"""The flat LSA design in plain torch - pool, Ward, bucket, score, pick, expand.

Vendored from Prefrontal-AI/latent-sparse-attention @
97b82d695b74ca341965a16bbc2a951c8b0c567a (src/lsa/core/reference.py),
Apache-2.0, with the SM70 port's changes. See PROVENANCE.md.

This is the oracle the kernels are tested against. `build_buckets` turns the
closed cluster blocks of a cache's index keys into buckets, and `read` scores the
buckets a query may see, takes its top-p, and expands them to its top-k beside
the sink and the window.

The reference's bucket shapes are not ported: the target design scores the
centroid, and `bucket_shape` is None. See PROVENANCE.md.
"""

from __future__ import annotations

from typing import NamedTuple

import torch

from .budget import EarlyBudget, budget_at
from .constants import PAD
from .ward import members_from_labels, pool_keys, ward_merge

# Unit rows to within what the dtype can hold.
NORM_TOLERANCE = {torch.float32: 1e-4, torch.bfloat16: 2e-2}
# How a cluster block's pools become buckets - Ward, or runs of consecutive keys.
CLUSTER_ALGORITHMS = ("ward", "position")


class Buckets(NamedTuple):
    """The buckets of a cache's closed cluster blocks, block after block."""

    # Normalized key sum of each bucket [rows, index_dim] fp32.
    bucket_centroids: torch.Tensor
    # Positions of each bucket's keys [rows, bucket_cap] int32, -1 padded.
    bucket_members: torch.Tensor
    # Keys in each bucket [rows] int32.
    bucket_sizes: torch.Tensor
    # Buckets a cluster block ends with.
    block_bucket_count: int
    # Keys in a cluster block.
    cluster_block_size: int


def check_unit_rows(name: str, vectors: torch.Tensor) -> None:
    """Refuse vectors that are not a float matrix of unit rows."""
    if vectors.dim() != 2:
        raise ValueError(f"{name} must be [N, index_dim] - got shape {tuple(vectors.shape)}")
    if vectors.dtype not in NORM_TOLERANCE:
        raise ValueError(f"{name} must be float32 or bfloat16 - got {vectors.dtype}")
    if not vectors.isfinite().all():
        raise ValueError(f"{name} holds a non-finite value")
    off = (
        (vectors.float().norm(dim=1) - 1).abs().max() if vectors.numel() else vectors.new_zeros(())
    )
    if off > NORM_TOLERANCE[vectors.dtype]:
        raise ValueError(f"{name} must be unit rows - a row is {off:.3g} off unit length")


def check_sizes(pool_size: int, bucket_size: int, bucket_cap: int, cluster_block_size: int) -> None:
    """Refuse sizes that do not nest, or a cap under twice the bucket size."""
    if min(pool_size, bucket_size, bucket_cap, cluster_block_size) < 1:
        raise ValueError(
            "pool_size, bucket_size, bucket_cap and cluster_block_size must be positive"
        )
    if bucket_size % pool_size or cluster_block_size % bucket_size:
        raise ValueError(
            f"pool_size {pool_size} must divide bucket_size {bucket_size}, which must divide "
            f"cluster_block_size {cluster_block_size}"
        )
    if bucket_cap < 2 * bucket_size:
        raise ValueError(
            f"bucket_cap must be at least twice bucket_size {bucket_size} - got {bucket_cap}"
        )


def build_buckets(
    index_keys: torch.Tensor,
    pool_size: int,
    bucket_size: int,
    bucket_cap: int,
    cluster_block_size: int,
    cluster_algorithm: str = "ward",
) -> Buckets:
    """Cluster every closed cluster block of the index keys into buckets with Ward.

    A trailing partial block is still open - its keys are in no bucket, and a
    read takes them from the window. Under `cluster_algorithm` `position` each
    bucket is instead `bucket_size` consecutive keys.

    Args:
        index_keys: The cache's index keys [T, index_dim] fp32 or bf16, unit rows.
        pool_size: Keys in a pool, a pool never split across buckets.
        bucket_size: Average keys in a bucket.
        bucket_cap: Most keys in a bucket, at least twice `bucket_size`.
        cluster_block_size: Keys in a cluster block.
        cluster_algorithm: `ward`, the design's, or `position`.

    Returns:
        The buckets of the `T // cluster_block_size` closed blocks.

    Raises:
        ValueError: If the keys are not unit rows, the sizes do not nest, or the
            cluster algorithm is unknown.
    """
    check_unit_rows("index_keys", index_keys)
    check_sizes(pool_size, bucket_size, bucket_cap, cluster_block_size)
    if cluster_algorithm not in CLUSTER_ALGORITHMS:
        raise ValueError(
            f"cluster_algorithm must be one of {CLUSTER_ALGORITHMS} - got {cluster_algorithm!r}"
        )
    keys = index_keys.float()
    block_count = keys.shape[0] // cluster_block_size
    block_bucket_count = cluster_block_size // bucket_size
    index_dim = keys.shape[1]
    blocks = keys[: block_count * cluster_block_size].view(
        block_count, cluster_block_size, index_dim
    )
    pools = pool_keys(blocks, pool_size)
    pool_sizes = torch.full(pools.shape[:2], float(pool_size), device=keys.device)
    if cluster_algorithm == "position":
        labels = (
            torch.arange(pools.shape[1], device=keys.device) // (bucket_size // pool_size)
        ).expand(block_count, -1)
    else:
        labels = ward_merge(pools, pool_sizes, block_bucket_count, bucket_cap)
    key_labels = labels.repeat_interleave(pool_size, dim=1)
    # Bucket of each key across the whole cache, numbered block after block.
    block_ids = torch.arange(block_count, device=keys.device)[:, None]
    bucket_of_key = key_labels + block_bucket_count * block_ids
    key_sums = torch.zeros(block_count * block_bucket_count, index_dim, device=keys.device)
    key_sums.index_add_(0, bucket_of_key.flatten(), blocks.reshape(-1, index_dim))
    bucket_centroids = key_sums / key_sums.norm(dim=1, keepdim=True).clamp_min(1e-30)
    members = torch.empty(
        block_count * block_bucket_count, bucket_cap, dtype=torch.int32, device=keys.device
    )
    for block in range(block_count):
        local = members_from_labels(key_labels[block], block_bucket_count, bucket_cap)
        rows = slice(block * block_bucket_count, (block + 1) * block_bucket_count)
        # Block-local positions made absolute, the padding left at -1.
        members[rows] = torch.where(local >= 0, local + block * cluster_block_size, -1)
    bucket_sizes = (members >= 0).sum(1).to(torch.int32)
    return Buckets(bucket_centroids, members, bucket_sizes, block_bucket_count, cluster_block_size)


def read(
    index_queries: torch.Tensor,
    positions: torch.Tensor,
    buckets: Buckets,
    top_p: int,
    top_k: int,
    sink_size: int,
    window_size: int,
    early_budget: EarlyBudget | None = None,
) -> tuple[torch.Tensor, torch.Tensor]:
    """Select the keys each query reads - the buckets scored, picked and expanded.

    A query scores every bucket of the cluster blocks closed before its own,
    picks the `top_p` best (a tie to the lower bucket), and reads their keys best
    bucket first until `top_k` keys are held. A key in the sinks or the window is
    not counted, because the read takes them anyway, and the last bucket is cut
    short.

    Args:
        index_queries: One index query a row [Tq, index_dim] fp32 or bf16, unit rows.
        positions: Each query's position [Tq] int32 or int64.
        buckets: The buckets of the cache, from `build_buckets`.
        top_p: Buckets a query picks.
        top_k: Long-range keys a query reads at most.
        sink_size: First positions always read.
        window_size: Recent positions always read, the query's own included.
        early_budget: The budget of queries before its position, or None.

    Returns:
        Selected key ids [Tq, top_k + window_size + sink_size] int32 - the
        expansion, then the window, then the sinks, -1 padded.
        Keys each row holds [Tq] int32.

    Raises:
        ValueError: If the queries are not unit rows of the buckets' index dim,
            the positions are not a non-negative integer vector one a query, a
            size is not positive, or the early budget is over `top_p` or `top_k`.
    """
    check_unit_rows("index_queries", index_queries)
    if index_queries.shape[1] != buckets.bucket_centroids.shape[1]:
        raise ValueError(
            f"index_queries have {index_queries.shape[1]} dims and the buckets "
            f"{buckets.bucket_centroids.shape[1]}"
        )
    if positions.dtype not in (torch.int32, torch.int64) or positions.shape != (
        index_queries.shape[0],
    ):
        raise ValueError("positions must be an int32 or int64 vector, one a query")
    if positions.numel() and positions.min() < 0:
        raise ValueError("positions must be non-negative")
    if min(top_p, top_k, window_size) < 1 or sink_size < 0:
        raise ValueError("top_p, top_k and window_size must be positive and sink_size non-negative")
    if early_budget is not None and (early_budget.top_p > top_p or early_budget.top_k > top_k):
        raise ValueError(
            f"the early budget is at most top_p {top_p} and top_k {top_k} - "
            f"got top_p {early_budget.top_p} and top_k {early_budget.top_k}"
        )
    width = top_k + window_size + sink_size
    selected = torch.full((index_queries.shape[0], width), PAD, dtype=torch.int32)
    lengths = torch.zeros(index_queries.shape[0], dtype=torch.int32)
    scores_all = index_queries.float() @ buckets.bucket_centroids.T
    for row, position in enumerate(positions.tolist()):
        row_top_k, row_top_p = budget_at(position, top_k, top_p, early_budget)
        keys = _read_row(
            scores_all[row], position, buckets, row_top_p, row_top_k, sink_size, window_size
        )
        selected[row, : keys.numel()] = keys
        lengths[row] = keys.numel()
    return selected, lengths


def _read_row(
    scores: torch.Tensor,
    position: int,
    buckets: Buckets,
    top_p: int,
    top_k: int,
    sink_size: int,
    window_size: int,
) -> torch.Tensor:
    """Select one query's keys from its scores of every bucket."""
    visible = min(
        position // buckets.cluster_block_size * buckets.block_bucket_count, scores.shape[0]
    )
    # Best score first, a tie to the lower bucket.
    picked = torch.argsort(scores[:visible], descending=True, stable=True)[:top_p]
    return expand_buckets(picked, position, buckets, top_k, sink_size, window_size)


def expand_buckets(
    picked: torch.Tensor,
    position: int,
    buckets: Buckets,
    top_k: int,
    sink_size: int,
    window_size: int,
) -> torch.Tensor:
    """Expand one query's picked buckets to its keys, beside its window and sinks.

    Returns:
        Its key ids [n] int32 - the expansion, the window, then the sinks.
    """
    window_start = max(0, position + 1 - window_size)
    members = buckets.bucket_members[picked].flatten().long()
    members = members[(members >= sink_size) & (members < window_start)][:top_k]
    window = torch.arange(window_start, position + 1)
    sinks = torch.arange(min(sink_size, window_start, position + 1))
    return torch.cat([members, window, sinks]).to(torch.int32)
