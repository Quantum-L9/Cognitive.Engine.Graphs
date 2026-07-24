<!-- L9_META
l9_schema: 2
origin: engine-specific
engine: graph
layer: [docs]
tags: [governance]
status: active
/L9_META -->

# Stage 5: Predictive Memory Warming System

**Perplexity Deep Research Output**
**Generated: 2026-01-15**
**Component ID: STAGE-5-PREDICTIVE-WARMING**

---

## Overview

Production-Grade Predictive Memory Warming System for LLM Agents achieving ~40% reduction in retrieval latency through:
- Knowledge gap detection via attention entropy analysis
- Intelligent cache warming with Redis
- Neo4j one-degree graph traversal
- Action-Think-Memory-Refine reasoning loop integration
- Prometheus metrics and comprehensive observability

## Core Components

| Component | Purpose | L9 Target Location |
|-----------|---------|-------------------|
| `GapDetector` | Detect knowledge gaps via attention + entity analysis | `memory/gap_detector.py` |
| `PredictiveCache` | Redis-backed cache with sliding TTL | `memory/predictive_cache.py` |
| `ReasoningLoop` | Action-Think-Memory-Refine cycle | `memory/reasoning_loop.py` |
| `MemoryWarmingService` | Production service orchestration | `memory/warming_service.py` |

## Data Models (Pydantic v2)

### Gap Detection Models

```python
class GapSeverity(str, Enum):
    """Enumeration of knowledge gap severity levels."""
    LOW = "low"
    MEDIUM = "medium"
    HIGH = "high"
    CRITICAL = "critical"


@dataclass
class KnowledgeGap:
    """Represents a detected knowledge gap with metadata for prioritization."""
    gap_id: str
    gap_type: str  # "entity_missing", "relationship_missing", "attention_uncertainty"
    severity: GapSeverity
    entity_ids: list[str]
    attention_entropy: Optional[float] = None
    confidence_score: float = 0.0
    related_layer: Optional[int] = None
    related_head: Optional[int] = None
    timestamp_detected_ms: float = 0


class AttentionConfig(BaseModel):
    """Configuration for attention-based gap detection."""
    entropy_threshold_low: float = Field(0.5, ge=0.0, le=2.0)
    entropy_threshold_high: float = Field(1.5, ge=0.0, le=2.0)
    min_attention_span_tokens: int = Field(3, ge=1)
    max_entropy_history_len: int = Field(100, ge=10)
    entropy_percentile_for_gap: float = Field(75.0, ge=50.0, le=99.0)
```

### Cache Models

```python
class SubgraphEntry(BaseModel):
    """Represents a cached subgraph entry."""
    entity_id: str
    neighbors: dict[str, dict[str, Any]]  # neighbor_id -> properties
    relationship_types: dict[str, list[str]]  # rel_type -> [neighbor_ids]
    cached_at_ms: float
    accessed_count: int = 0


class CacheMetrics(BaseModel):
    """Metrics tracking cache performance."""
    cache_hits: int = 0
    cache_misses: int = 0
    total_warming_calls: int = 0
    avg_warming_latency_ms: float = 0.0
    current_cache_size: int = 0
    evicted_entries: int = 0

    @property
    def cache_hit_ratio(self) -> float:
        total = self.cache_hits + self.cache_misses
        return self.cache_hits / total if total > 0 else 0.0
```

### Reasoning Loop Models

```python
class ReasoningPhase(str, Enum):
    """Phases of the reasoning cycle."""
    ACTION = "action"
    THINK = "think"
    MEMORY = "memory"
    REFINE = "refine"


@dataclass
class ActionProposal:
    """Proposed action with rationale."""
    action_description: str
    action_params: dict[str, Any]
    confidence_score: float  # 0.0 to 1.0
    rationale: str
    dependencies: list[str] = field(default_factory=list)
    required_entities: list[str] = field(default_factory=list)


@dataclass
class ThinkingOutput:
    """Output from thinking phase."""
    goal_progress_assessment: str
    moves_toward_goal: bool
    identified_gaps: list[str]
    uncertainty_level: float  # 0.0 to 1.0
    required_memory_entities: list[str]
    attention_entropy: Optional[float] = None


@dataclass
class MemoryContext:
    """Retrieved and warmed memory context."""
    retrieved_entities: dict[str, Any]
    entity_relationships: dict[str, set[str]]
    cache_hit_ratio: float
    warming_latency_ms: float
```

## GapDetector Implementation

Three detection strategies:

### 1. Attention Entropy Analysis

```python
async def _detect_attention_gaps(
    self,
    attention_weights: np.ndarray,
    layer_idx: Optional[int],
    head_idx: Optional[int]
) -> list[KnowledgeGap]:
    """
    Detect gaps based on attention entropy analysis.

    High entropy = distributed attention = uncertainty
    Low entropy = concentrated attention = confidence
    """
    for head_i, head_weights in enumerate(attention_weights):
        entropy = -np.sum(head_weights * np.log(head_weights))

        # Dynamic threshold based on percentile of history
        if len(self._entropy_history) > 10:
            percentile_value = np.percentile(
                self._entropy_history,
                self.config.attention_config.entropy_percentile_for_gap
            )

        if entropy > percentile_value:
            gap_severity = GapSeverity.CRITICAL if entropy > 2.0 else GapSeverity.HIGH
            # Create KnowledgeGap...
```

### 2. Entity Mention Tracking

```python
async def _detect_entity_gaps(
    self,
    mentioned_entities: list[str],
    entity_memory_graph: dict[str, set[str]]
) -> list[KnowledgeGap]:
    """
    Detect gaps based on missing or incomplete entity references.

    - Missing entity: CRITICAL/HIGH severity
    - Isolated entity (no relationships): MEDIUM severity
    """
```

### 3. Relationship Inference

```python
async def _detect_relationship_gaps(
    self,
    mentioned_entities: list[str],
    entity_memory_graph: dict[str, set[str]]
) -> list[KnowledgeGap]:
    """
    Detect missing relationships between mentioned entities.

    If entities A and B are mentioned together but have no
    relationship in the graph, flag as MEDIUM severity gap.
    """
```

## PredictiveCache Implementation

Redis-backed cache with:
- Sliding window TTL (5 minutes default)
- LRU eviction policy
- One-degree Neo4j traversal for warming
- Concurrent warming with semaphore control

### Warming Pipeline

```
1. Check if entity already cached → refresh TTL if hit
2. If miss, fetch one-degree neighbors from Neo4j
3. Build SubgraphEntry with neighbors + relationship types
4. Store in Redis with TTL
5. Track metrics (hits, misses, latency)
```

### Cache Configuration

```python
class PredictiveCacheConfig(BaseModel):
    redis_url: str = "redis://localhost:6379/0"
    cache_ttl_seconds: int = Field(300, ge=10, le=3600)
    max_subgraph_neighbors: int = Field(20, ge=5, le=100)
    max_cache_entries: int = Field(1000, ge=100, le=100000)
    max_connection_pool_size: int = Field(10, ge=1, le=50)
    enable_metrics_tracking: bool = True
    refresh_ttl_on_hit: bool = True
```

## ReasoningLoop Implementation

Four-phase cycle based on ReMem architecture:

```
ACTION → THINK → MEMORY → REFINE
   ↓        ↓        ↓        ↓
Generate  Evaluate  Warm    Adjust
proposal  vs goal   cache   action
```

### Phase Details

1. **ACTION**: Generate proposed action toward goal
2. **THINK**: Evaluate if action moves toward goal, identify gaps
3. **MEMORY**: Detect gaps, warm caches, retrieve context
4. **REFINE**: Adjust action based on retrieved memory

## Production Observability

### Prometheus Metrics

```python
self.gap_detection_count = Counter(
    'gap_detection_count', 'Total gaps detected', ['gap_type']
)
self.attention_entropy_histogram = Histogram(
    'attention_entropy_values', 'Attention entropy measurements',
    buckets=[0.0, 0.25, 0.5, 0.75, 1.0, 1.25, 1.5, 2.0]
)
self.gap_detector_latency = Histogram(
    'gap_detector_latency_ms', 'Time to detect gaps'
)
```

### Target Metrics

| Metric | Target |
|--------|--------|
| Memory warming latency (p99) | < 200ms |
| Cache hit ratio (warm) | > 0.70 |
| Rounds to reasoning convergence | 5-7 |

## L9 Adaptation Notes

### Integration Points

1. **Redis**: Use existing L9 Redis client infrastructure
2. **Neo4j**: Use existing graph adapter
3. **Metrics**: Integrate with L9 telemetry system
4. **Logging**: Use structlog with L9 patterns

### Required Changes for L9

- Replace raw Redis with L9's Redis client wrapper
- Integrate with existing graph traversal utilities
- Add PacketEnvelope logging for audit trail
- Wire into existing memory retrieval pipeline

## Research Foundations

- **Evo-Memory benchmark** (DeepMind): Self-evolving agent memory
- **ReMem architecture**: Action-think-memory-refine pipeline
- **Attention entropy**: Information-theoretic uncertainty estimation
- **Graph-based RAG**: Neo4j for structured memory retrieval

---

*Research source: Perplexity deep_research tool, 2026-01-15*
