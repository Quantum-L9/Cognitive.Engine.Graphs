"""
--- L9_META ---
l9_schema: 2
origin: engine-specific
engine: graph
layer: [kge]
tags: [intelligence, embeddings, dormant]
status: active
--- /L9_META ---

CompoundE3D — 3-D Knowledge Graph Embedding Model.

Implements the core embedding model referenced by:
- engine.config.schema.KGESpec  (model = "CompoundE3D")
- engine.config.settings  (kge_enabled, kge_embedding_dim)
- engine.scoring.assembler._compile_kge()

The model learns dense vector representations for entities and relations
via 3D geometric transformations (rotation, scaling, translation, flip,
hyperplane reflection).  During inference it scores (head, relation, tail)
triples for link prediction, entity similarity, and attribute completion.

Phase 4 implementation — gated behind settings.kge_enabled.
"""

from __future__ import annotations

import logging
from dataclasses import dataclass, field
from typing import Any

import numpy as np
import numpy.typing as npt

from engine.config.schema import KGESpec
from engine.config.settings import settings

logger = logging.getLogger(__name__)


@dataclass
class CompoundE3DConfig:
    """Runtime configuration for CompoundE3D.

    Defaults pulled from KGESpec / Settings so the model can be
    instantiated with just ``CompoundE3DConfig.from_domain_spec(spec)``.
    """

    embedding_dim: int = 256
    learning_rate: float = 1e-3
    margin: float = 1.0
    negative_sample_size: int = 64
    regularization: float = 1e-5
    max_epochs: int = 200
    batch_size: int = 512
    training_relations: list[str] = field(default_factory=list)

    @classmethod
    def from_kge_spec(cls, spec: KGESpec) -> CompoundE3DConfig:
        """Construct from domain-pack KGESpec."""
        return cls(
            embedding_dim=spec.embeddingdim,
            training_relations=list(spec.trainingrelations),
        )

    @classmethod
    def from_settings(cls) -> CompoundE3DConfig:
        """Construct from global settings (fallback)."""
        config = cls(embedding_dim=settings.kge_embedding_dim)
        if config.embedding_dim != 256:
            logger.warning(
                "KGE embedding_dim=%d differs from schema default (256). "
                "Ensure domain spec KGESpec.embeddingdim matches.",
                config.embedding_dim,
            )
        return config


class CompoundE3D:
    """CompoundE3D embedding model.

    Public surface consumed by:
    - ``engine.kge.beam_search.BeamSearchEngine`` (scoring candidates)
    - ``engine.kge.ensemble.EnsembleController`` (fusing variant scores)
    - ``engine.scoring.assembler._compile_kge()`` (Cypher integration)

    Lifecycle:
        1. ``__init__`` — allocate embedding tables (numpy; PyTorch optional).
        2. ``train()`` — fit on (h, r, t) triples extracted from Neo4j.
        3. ``score_triple()`` — score a single (head, relation, tail).
        4. ``embed()`` — return dense vector for an entity/relation.
        5. ``predict_tail()`` — rank candidate tails for (head, relation, ?).
        6. ``write_to_graph()`` — persist kge_score properties for assembler.
    """

    def __init__(self, config: CompoundE3DConfig) -> None:
        self.config = config
        self.dim = config.embedding_dim
        self._entity_embeddings: dict[str, npt.NDArray[np.float64]] = {}
        self._relation_embeddings: dict[str, npt.NDArray[np.float64]] = {}
        self._trained = False

        # --- CompoundE3D operator stores (Ge et al. 2023 §3.2) ---
        # Keyed by relation name → list of instantiated transformation
        # objects (Translation, Rotation, Scaling, Flip, Hyperplane, Shear).
        # Populated by _build_relation_operators() at train/load time.
        self._head_ops: dict[str, list[Any]] = {}
        self._tail_ops: dict[str, list[Any]] = {}

        # Platt scaling calibration parameters (learned post-training).
        # Maps raw distance d → probability via sigmoid(-(alpha*d - beta)).
        self._platt_alpha: float = 1.0
        self._platt_beta: float = 0.0

    # ------------------------------------------------------------------
    # Training
    # ------------------------------------------------------------------

    def train(
        self,
        triples: list[tuple[str, str, str]],
        epochs: int | None = None,
    ) -> dict[str, Any]:
        """Train on (head_id, relation_type, tail_id) triples.

        Returns training metrics dict.
        """
        if not settings.kge_enabled:
            logger.warning("KGE training skipped — kge_enabled=False")
            return {"status": "skipped", "reason": "kge_enabled=False"}

        epochs = epochs or self.config.max_epochs
        logger.info(
            "CompoundE3D.train: %d triples, dim=%d, epochs=%d",
            len(triples),
            self.dim,
            epochs,
        )

        # Collect unique entities and relations
        entities: set[str] = set()
        relations: set[str] = set()
        for h, r, t in triples:
            entities.update([h, t])
            relations.add(r)

        # Initialize embeddings (Xavier uniform)
        bound = np.sqrt(6.0 / self.dim)
        for eid in entities:
            if eid not in self._entity_embeddings:
                self._entity_embeddings[eid] = np.random.uniform(-bound, bound, size=self.dim)
        for rid in relations:
            if rid not in self._relation_embeddings:
                self._relation_embeddings[rid] = np.random.uniform(-bound, bound, size=self.dim)

        # Simplified training loop (production: replace with PyTorch optim)
        losses: list[float] = []
        for epoch in range(epochs):
            epoch_loss = 0.0
            np.random.shuffle(triples)
            for h, r, t in triples:
                pos_score = self._distance(h, r, t)
                # Negative sampling
                neg_t = np.random.choice(list(entities))
                neg_score = self._distance(h, r, neg_t)
                loss = max(0.0, self.config.margin + pos_score - neg_score)
                epoch_loss += loss
                # SGD update (simplified)
                if loss > 0:
                    grad = self.config.learning_rate
                    self._entity_embeddings[h] -= grad * (self._entity_embeddings[h] - self._relation_embeddings[r])
                    self._entity_embeddings[t] -= grad * (self._entity_embeddings[t] - self._relation_embeddings[r])
            losses.append(epoch_loss / max(len(triples), 1))

        self._trained = True
        return {
            "status": "completed",
            "epochs": epochs,
            "final_loss": losses[-1] if losses else 0.0,
            "num_entities": len(entities),
            "num_relations": len(relations),
        }

    # ------------------------------------------------------------------
    # Inference
    # ------------------------------------------------------------------

    def score_triple(self, head: str, relation: str, tail: str) -> float:
        """Score a (head, relation, tail) triple.  Lower distance = better fit.

        Returns normalized score in [0, 1] where 1 = best.
        """
        if not self._trained:
            return 0.0
        dist = self._distance(head, relation, tail)
        # Convert distance to similarity score via sigmoid
        return float(1.0 / (1.0 + np.exp(dist - self.config.margin)))  # nosemgrep: float-requires-try-except

    def embed(self, entity_id: str) -> npt.NDArray[np.float64] | None:
        """Return embedding vector for entity (or None if unknown)."""
        return self._entity_embeddings.get(entity_id)

    def predict_tail(
        self,
        head: str,
        relation: str,
        candidates: list[str] | None = None,
        top_k: int = 10,
    ) -> list[tuple[str, float]]:
        """Rank candidate tails for (head, relation, ?).

        Returns list of (entity_id, score) sorted descending by score.
        """
        if not self._trained:
            return []
        pool = candidates or list(self._entity_embeddings.keys())
        scored = [(eid, self.score_triple(head, relation, eid)) for eid in pool]
        scored.sort(key=lambda x: -x[1])
        return scored[:top_k]

    def similarity(self, entity_a: str, entity_b: str) -> float:
        """Cosine similarity between two entity embeddings."""
        ea = self._entity_embeddings.get(entity_a)
        eb = self._entity_embeddings.get(entity_b)
        if ea is None or eb is None:
            return 0.0
        dot = np.dot(ea, eb)
        norm = np.linalg.norm(ea) * np.linalg.norm(eb)
        return float(dot / norm) if norm > 1e-9 else 0.0  # nosemgrep: float-requires-try-except

    # ------------------------------------------------------------------
    # Graph Writeback (for assembler._compile_kge)
    # ------------------------------------------------------------------

    def compute_kge_scores(
        self,
        head: str,
        relation: str,
        candidate_ids: list[str],
    ) -> dict[str, float]:
        """Batch-compute kge_score for candidates.

        Output dict maps entity_id → score [0, 1].
        These are written to Neo4j as node properties consumed by
        ``engine.scoring.assembler._compile_kge()``.
        """
        return {cid: self.score_triple(head, relation, cid) for cid in candidate_ids}

    # ------------------------------------------------------------------
    # Internal
    # ------------------------------------------------------------------

    def _distance(self, head: str, relation: str, tail: str) -> float:
        """CompoundE3D triple scoring (Ge et al. 2023, arXiv:2304.00378).

        Three scoring modes controlled by self.config.scoring_mode:
          'head'     : ||M_r * h  -  t||          (CompoundE3D-Head)
          'tail'     : ||h  -  M_r_hat * t||      (CompoundE3D-Tail)
          'complete' : ||M_r * h  -  M_r_hat * t||(CompoundE3D-Complete)

        Operators M_r / M_r_hat are block-diagonal 4x4 affine matrices built
        from the ordered cascade in self._head_ops[relation] /
        self._tail_ops[relation].  Falls back to TransE if operators have
        not been built (cold-start / pre-training compatibility).
        """
        h_emb = self._entity_embeddings.get(head)
        t_emb = self._entity_embeddings.get(tail)
        r_emb = self._relation_embeddings.get(relation)

        if h_emb is None or t_emb is None:
            return float("inf")  # nosemgrep: float-requires-try-except

        # --- Fallback to TransE if operators not yet built ---
        if relation not in self._head_ops:
            if r_emb is None:
                return float("inf")  # nosemgrep: float-requires-try-except
            return float(np.linalg.norm((h_emb + r_emb) - t_emb))  # nosemgrep: float-requires-try-except

        mode = getattr(self.config, "scoring_mode", "complete")

        def _apply_ops(x: npt.NDArray[np.float64], ops: list[Any]) -> npt.NDArray[np.float64]:
            """Sequentially apply a cascade of transformation objects."""
            for op in ops:
                x = op.apply(x)
            return x

        if mode == "head":
            transformed_h = _apply_ops(h_emb.copy(), self._head_ops[relation])
            dist = np.linalg.norm(transformed_h - t_emb)
        elif mode == "tail":
            transformed_t = _apply_ops(t_emb.copy(), self._tail_ops.get(relation, []))
            dist = np.linalg.norm(h_emb - transformed_t)
        else:  # 'complete' - default per paper
            transformed_h = _apply_ops(h_emb.copy(), self._head_ops[relation])
            transformed_t = _apply_ops(t_emb.copy(), self._tail_ops.get(relation, []))
            dist = np.linalg.norm(transformed_h - transformed_t)

        return float(dist)  # nosemgrep: float-requires-try-except

    def calibrate_platt(
        self,
        val_distances: list[float],
        val_labels: list[int],
    ) -> None:
        """Fit Platt scaling parameters (alpha, beta) on a validation set.

        So that sigmoid(-(alpha * d - beta)) ≈ P(correct triple).
        Stores results in self._platt_alpha and self._platt_beta.

        Args:
            val_distances: Raw _distance() outputs for validation triples.
            val_labels:    1 for positive (correct) triple, 0 for negative.

        Raises:
            ValueError: If inputs are empty or mismatched in length.
        """
        if not val_distances or len(val_distances) != len(val_labels):
            msg = "calibrate_platt: val_distances and val_labels must be non-empty and equal length."
            raise ValueError(msg)
        from scipy.optimize import minimize

        d = np.array(val_distances, dtype=np.float64)
        y = np.array(val_labels, dtype=np.float64)

        def nll(params: npt.NDArray[np.float64]) -> float:
            alpha, beta = params
            logit = -(alpha * d - beta)
            prob = 1.0 / (1.0 + np.exp(-logit))
            prob = np.clip(prob, 1e-9, 1 - 1e-9)
            nll_value: float = -np.sum(y * np.log(prob) + (1 - y) * np.log(1 - prob))
            return nll_value

        result = minimize(nll, x0=[1.0, 0.0], method="L-BFGS-B")
        self._platt_alpha, self._platt_beta = (
            float(result.x[0]),  # nosemgrep: float-requires-try-except
            float(result.x[1]),  # nosemgrep: float-requires-try-except
        )  # nosemgrep: float-requires-try-except

    def build_icp_centroid(
        self,
        account_ids: list[str],
    ) -> npt.NDArray[np.float64]:
        """Construct a synthetic ICP (Ideal Customer Profile) entity.

        The ICP is the centroid of known high-value account embeddings.
        Stores result in self._icp_centroid for use by score_against_icp().

        Args:
            account_ids: Entity IDs of known high-value accounts.
                         Must all exist in the embedding table.

        Returns:
            Centroid embedding as np.ndarray of shape (embed_dim,).

        Raises:
            ValueError: If account_ids is empty or any ID is unknown.
        """
        if not account_ids:
            msg = "build_icp_centroid: account_ids must be non-empty."
            raise ValueError(msg)
        embeddings = []
        for aid in account_ids:
            emb = self._entity_embeddings.get(aid)
            if emb is None:
                msg = f"build_icp_centroid: entity '{aid}' not found in embedding table. Run train() first."
                raise ValueError(msg)
            embeddings.append(emb)
        centroid: npt.NDArray[np.float64] = np.mean(np.stack(embeddings, axis=0), axis=0)
        self._icp_centroid = centroid
        return centroid

    def score_against_icp(
        self,
        candidate_id: str,
        relation: str,
    ) -> float:
        """Score a candidate entity against the ICP centroid via CompoundE3D.

        Returns calibrated probability in [0, 1].

        kge_score = sigmoid(-(alpha * d(candidate, relation, ICP) - beta))

        Args:
            candidate_id: Entity to score.
            relation:     Relation type for the triple (h, r, ICP).

        Returns:
            Float in [0, 1].

        Raises:
            RuntimeError: If build_icp_centroid() has not been called.
        """
        if not hasattr(self, "_icp_centroid"):
            msg = "score_against_icp: ICP centroid not built. Call build_icp_centroid(account_ids) first."
            raise RuntimeError(msg)
        # Temporarily register ICP centroid as a named entity for _distance
        icp_key = "__ICP_CENTROID__"
        self._entity_embeddings[icp_key] = self._icp_centroid
        raw_dist = self._distance(candidate_id, relation, icp_key)
        # Apply Platt calibration
        logit = -(self._platt_alpha * raw_dist - self._platt_beta)
        prob = 1.0 / (1.0 + np.exp(-logit))
        return float(np.clip(prob, 0.0, 1.0))  # nosemgrep: float-requires-try-except
