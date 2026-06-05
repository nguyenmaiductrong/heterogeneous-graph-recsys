from __future__ import annotations

from dataclasses import dataclass
from collections.abc import Iterable
from numbers import Integral
import torch
from torch import Tensor

EMBED_DIM: int = 128
LOW_RANK: int = 16  # rank r cho A_phi @ B_beta^T (CrossComboWeightSpec)


def configure_dims(embed_dim: int) -> None:
    """Sync EMBED_DIM with config before any validation runs."""
    global EMBED_DIM
    EMBED_DIM = embed_dim
NODE_TYPES: list[str] = ["user", "product", "category", "brand"]
BEHAVIOR_TYPES: list[str] = ["view", "cart", "purchase"]

RELATION_TYPES: list[tuple[str, str, str]] = [
    ("user", "view", "product"),
    ("user", "cart", "product"),
    ("user", "purchase", "product"),
    ("product", "rev_view", "user"),
    ("product", "rev_cart", "user"),
    ("product", "rev_purchase", "user"),
    ("product", "belongs_to", "category"),
    ("category", "contains", "product"),
    ("product", "producedBy", "brand"),
    ("brand", "brands", "product"),
]

BEHAVIOR_TO_ID: dict[str, int] = {"view": 0, "cart": 1, "purchase": 2}


@dataclass
class SampledSubgraph:
    # {node_type: Tensor(num_nodes_of_type, EMBED_DIM)}
    node_features: dict[str, Tensor]

    # {(src_type, edge_type, dst_type): Tensor(2, num_edges)}
    edge_index: dict[tuple[str, str, str], Tensor]

    # {(src_type, edge_type, dst_type): Tensor(num_edges,)}
    # values in {0=view, 1=cart, 2=purchase}
    edge_behavior_origin: dict[tuple[str, str, str], Tensor]

    # Indices into node_features["user"] for this batch
    # shape: (batch_size,)
    target_user_indices: Tensor

    node_id_map: dict[str, Tensor]

    def validate(self) -> None:
        for ntype, feat in self.node_features.items():
            assert ntype in NODE_TYPES, f"Unknown node type: {ntype}"
            assert feat.dim() == 2 and feat.size(1) == EMBED_DIM, (
                f"node_features[{ntype}] shape {feat.shape}, expected (*, {EMBED_DIM})"
            )
        for rel, idx in self.edge_index.items():
            assert idx.dim() == 2 and idx.size(0) == 2, (
                f"edge_index[{rel}] must be (2, E), got {idx.shape}"
            )
            if rel in self.edge_behavior_origin:
                E = idx.size(1)
                orig = self.edge_behavior_origin[rel]
                assert orig.shape == (E,), f"origin shape {orig.shape} != ({E},)"


@dataclass
class GNNOutput:
    # BEFORE hierarchy gating — per-behavior
    # {behavior: {"user": (B, d), "product": (B, d)}}
    per_behavior_emb: dict[str, dict[str, Tensor]]

    # AFTER multi-order concat + projection
    final_user_emb: Tensor  # (num_users_in_batch, d)
    final_item_emb: Tensor  # (num_items_in_batch, d)

    def validate(self) -> None:
        for beh in BEHAVIOR_TYPES:
            assert beh in self.per_behavior_emb
            for nt in ["user", "product"]:
                e = self.per_behavior_emb[beh][nt]
                assert e.dim() == 2 and e.size(1) == EMBED_DIM
        assert self.final_user_emb.size(1) == EMBED_DIM
        assert self.final_item_emb.size(1) == EMBED_DIM


@dataclass
class GatedOutput:
    gated_user_emb: Tensor  # (batch_users, d)
    gated_item_emb: Tensor  # (batch_items, d)
    cl_loss: Tensor  # scalar

    def validate(self) -> None:
        assert self.gated_user_emb.size(1) == EMBED_DIM
        assert self.gated_item_emb.size(1) == EMBED_DIM
        assert self.cl_loss.dim() == 0


@dataclass
class LossInput:
    """Consolidated input for multi-task BPR + CL loss.

    Assembled by: P4 from GatedOutput + neg sampling
    """

    user_emb: Tensor  # (B, d)
    pos_item_emb: Tensor  # (B, d)
    neg_item_emb: Tensor  # (B, num_neg, d)
    behavior_ids: Tensor  # (B,) in {0,1,2}
    cl_loss: Tensor  # scalar from P3

    def validate(self) -> None:
        B = self.user_emb.size(0)
        assert self.user_emb.shape == (B, EMBED_DIM)
        assert self.pos_item_emb.shape == (B, EMBED_DIM)
        assert self.neg_item_emb.dim() == 3
        assert self.neg_item_emb.size(2) == EMBED_DIM
        assert self.behavior_ids.shape == (B,)


@dataclass
class LossOutput:
    total_loss: Tensor  # scalar — call .backward() on this
    bpr_loss: Tensor  # scalar
    cl_loss: Tensor  # scalar
    reg_loss: Tensor  # scalar

    def validate(self) -> None:
        for name in ["total_loss", "bpr_loss", "cl_loss", "reg_loss"]:
            assert getattr(self, name).dim() == 0


@dataclass
class EvalInput:
    user_embeddings: Tensor  # (num_eval_users, d)
    item_embeddings: Tensor  # (num_items, d)
    eval_user_ids: Tensor  # (num_eval_users,)
    ground_truth: dict[int, int | list[int] | tuple[int, ...] | set[int]]
    exclude_items: dict[int, list[int]]  # {user_id: [train_pos_items]}

    @staticmethod
    def _as_item_list(items: int | Iterable[int]) -> list[int]:
        if isinstance(items, Integral):
            return [int(items)]
        return [int(x) for x in items]

    def validate(self, total_num_users: int | None = None) -> None:
        """Validate EvalInput tensor shapes and index bounds.

        Parameters
        ----------
        total_num_users:
            The authoritative total user count from ``node_counts.json``
            (i.e. ``SplitResult.num_users``).  Pass this to enable a strict
            bounds check on ``eval_user_ids``, which holds *global* user
            indices in ``[0, total_num_users)`` — NOT positions into
            ``user_embeddings`` (which has size ``N_eval_users``).
            When omitted the global-ID bounds check is skipped.
        """
        n_eval_users = self.user_embeddings.size(0)
        num_items = self.item_embeddings.size(0)

        assert self.user_embeddings.size(1) == EMBED_DIM, (
            f"user_embeddings dim1={self.user_embeddings.size(1)}, expected {EMBED_DIM}"
        )
        assert self.item_embeddings.size(1) == EMBED_DIM, (
            f"item_embeddings dim1={self.item_embeddings.size(1)}, expected {EMBED_DIM}"
        )

        # user_embeddings is ordered by POSITION in eval_user_ids, not by
        # global user index.  Check the positional pairing, not a value bound.
        assert n_eval_users == self.eval_user_ids.size(0), (
            f"user_embeddings has {n_eval_users} rows but "
            f"eval_user_ids has {self.eval_user_ids.size(0)} entries — "
            "they must have the same length (embeddings are ordered by eval_user_ids position)"
        )
        assert len(self.ground_truth) == self.eval_user_ids.size(0), (
            f"ground_truth has {len(self.ground_truth)} entries but "
            f"eval_user_ids has {self.eval_user_ids.size(0)}"
        )

        # eval_user_ids holds GLOBAL user indices; check against total vocab size
        # when the authoritative count is provided.
        if total_num_users is not None:
            uid_max = int(self.eval_user_ids.max().item())
            assert uid_max < total_num_users, (
                f"eval_user_ids contains global index {uid_max} >= "
                f"total_num_users {total_num_users}.  "
                "This is a vocabulary mismatch between the saved mapping and "
                "the node counts passed to the model."
            )

        # Item bounds: ground_truth values are global item indices into item_embeddings.
        # The primary protocol uses multi-positive ground truth:
        # {user_idx: [all new purchase item_idx]}.
        missing_users = [
            int(u) for u in self.eval_user_ids.tolist() if int(u) not in self.ground_truth
        ]
        assert not missing_users, (
            f"ground_truth is missing {len(missing_users)} eval users, first={missing_users[:5]}"
        )

        gt_items: list[int] = []
        for user_items in self.ground_truth.values():
            items = self._as_item_list(user_items)
            assert items, "ground_truth contains an eval user with no positive items"
            gt_items.extend(items)

        item_min = min(gt_items)
        item_max = max(gt_items)
        assert item_min >= 0, f"ground_truth contains negative item index {item_min}"
        assert item_max < num_items, (
            f"ground_truth contains item index {item_max} >= "
            f"item_embeddings.size(0) {num_items}.  "
            "This will cause a CUDA OOB during evaluator scoring."
        )


@dataclass
class CrossComboWeightSpec:
    """Low-rank relation-behavior transform: W_{ρ,β} = W_ρ + A_ρ · diag(z_β) · B_ρᵀ"""

    w_rho: tuple[int, int] = (EMBED_DIM, EMBED_DIM)  # per-relation base: |R| × (d, d)
    a_rho: tuple[int, int] = (EMBED_DIM, LOW_RANK)  # per-relation: |R| × (d, r)
    b_rho: tuple[int, int] = (EMBED_DIM, LOW_RANK)  # per-relation: |R| × (d, r)
    z_beta: tuple[int,] = (LOW_RANK,)  # per-behavior: |B| × (r,)

    @property
    def total_params(self) -> int:
        d, r = EMBED_DIM, LOW_RANK
        nR, nB = len(RELATION_TYPES), len(BEHAVIOR_TYPES)
        # W_ρ: nR×d×d, A_ρ: nR×d×r, B_ρ: nR×d×r, z_β: nB×r
        return nR * d * d + nR * d * r + nR * d * r + nB * r


def _self_test() -> None:
    print("=" * 55)
    print("contracts.py self-test")
    print("=" * 55)

    B, Nu, Ni, Nc, Nb = 64, 200, 500, 30, 20

    # 1. SampledSubgraph
    sg = SampledSubgraph(
        node_features={
            "user": torch.randn(Nu, EMBED_DIM),
            "product": torch.randn(Ni, EMBED_DIM),
            "category": torch.randn(Nc, EMBED_DIM),
            "brand": torch.randn(Nb, EMBED_DIM),
        },
        edge_index={
            ("user", "view", "product"): torch.randint(0, Nu, (2, 1000)),
            ("user", "cart", "product"): torch.randint(0, Nu, (2, 300)),
            ("user", "purchase", "product"): torch.randint(0, Nu, (2, 100)),
            ("product", "belongs_to", "category"): torch.randint(0, Ni, (2, 500)),
            ("product", "producedBy", "brand"): torch.randint(0, Ni, (2, 500)),
        },
        edge_behavior_origin={
            ("user", "view", "product"): torch.zeros(1000, dtype=torch.long),
            ("user", "cart", "product"): torch.ones(300, dtype=torch.long),
            ("user", "purchase", "product"): torch.full((100,), 2, dtype=torch.long),
            ("product", "belongs_to", "category"): torch.randint(0, 3, (500,)),
            ("product", "producedBy", "brand"): torch.randint(0, 3, (500,)),
        },
        target_user_indices=torch.randint(0, Nu, (B,)),
        node_id_map={
            t: torch.arange(n)
            for t, n in [("user", Nu), ("product", Ni), ("category", Nc), ("brand", Nb)]
        },
    )
    sg.validate()
    print("[PASS] SampledSubgraph")

    # 2. GNNOutput
    gnn = GNNOutput(
        per_behavior_emb={
            b: {"user": torch.randn(B, EMBED_DIM), "product": torch.randn(B, EMBED_DIM)}
            for b in BEHAVIOR_TYPES
        },
        final_user_emb=torch.randn(B, EMBED_DIM),
        final_item_emb=torch.randn(B, EMBED_DIM),
    )
    gnn.validate()
    print("[PASS] GNNOutput")

    # 3. GatedOutput
    gated = GatedOutput(torch.randn(B, EMBED_DIM), torch.randn(B, EMBED_DIM), torch.tensor(0.5))
    gated.validate()
    print("[PASS] GatedOutput")

    # 4. LossInput / LossOutput
    li = LossInput(
        torch.randn(B, EMBED_DIM),
        torch.randn(B, EMBED_DIM),
        torch.randn(B, 4, EMBED_DIM),
        torch.randint(0, 3, (B,)),
        torch.tensor(0.5),
    )
    li.validate()
    print("[PASS] LossInput")

    lo = LossOutput(*(torch.tensor(x) for x in [1.2, 0.8, 0.3, 0.1]))
    lo.validate()
    print("[PASS] LossOutput")

    # 6. EvalInput
    Ne = 100
    ei = EvalInput(
        torch.randn(Ne, EMBED_DIM),
        torch.randn(Ni, EMBED_DIM),
        torch.arange(Ne),
        {i: i % Ni for i in range(Ne)},
        {i: [i % Ni] for i in range(Ne)},
    )
    ei.validate()
    print("[PASS] EvalInput")

    # 7. Param count
    spec = CrossComboWeightSpec()
    print(f"\n  Cross-combo params: {spec.total_params:,} ({spec.total_params / 1e6:.2f}M)")

    print("\n" + "=" * 55)
    print("ALL CONTRACTS PASSED")
    print("=" * 55)


if __name__ == "__main__":
    _self_test()
