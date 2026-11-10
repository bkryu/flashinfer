# Copyright (c) 2026 by FlashInfer team.
# SPDX-License-Identifier: Apache-2.0
"""The NVFP4 MoE classes' grouped-GEMM dispatcher: the dense 4-bit GEMM class's ranking heuristic at the grouped launch's
shape, as the bf16 classes' (:mod:`.schedule`, whose terms this module reuses).

The grouped block-scaled GEMM is the dense NVFP4 class under a different scheduler (one segment of rows per expert, whole
128-row scale-factor atoms per segment), so its records are ranked by the dense dispatcher's model
(:func:`flashinfer.gemm.batch_invariant.heuristic.estimate_cycles` at the instruction class ``in_fmt``: the part's roofline
with nominal constants, no measured tables) at the dense shape whose tiles, M tail and operand bytes are the grouped
launch's: ``M`` = the rows of one active expert, ``N`` = the active experts' weight rows side by side (every group's tiles
count, and the weights are read once per group). Two record spaces are ranked together, as the bf16 classes' dispatcher
ranks them: the grouped records (the dense records at swizzle 1: no in-cluster split, no operand swap, no B-reuse tile, no
in-CTA chunk fold) and the swapped records (:mod:`.blocks.swap_nvfp4`: the weights on the MMA's M side, 128 rows per CTA, the
group's tokens a narrow N tile of 8 / 16 / 32 rows), which the dense model prices as a swapped decode record. The grouped
launch's own terms on the dense estimate are the bf16 dispatcher's: the pair term (the cluster tile's dummy share), the
swapped records' spill factor (the Poisson expectation of token tiles per active expert), the last tile's exposed epilogue
chain (this class's chain term: the W4A4 gated chain, or the static class's chain plus its share of the block quantization;
four epilogue warpgroups) and the token box's zero-fill past the group's rows at the packed fp4 element width, rounded to three
significant digits so records the estimate cannot separate fall through to the structural raster and the enumeration order.
Every record of either space is filtered by its body's acceptance. Numerics-neutral: every record of either space is
canonical (the same bits), so the dispatcher may depend on anything; the ranked list is what the autotuner profiles under
``batch_invariant``.
"""

from __future__ import annotations

from typing import List, Optional, Tuple

from ...gemm.batch_invariant.generator import (
    CLUSTERS,
    TILES_M_BLOCKSCALED,
    TILES_N_BLOCKSCALED,
    TILES_N_NARROW,
    Knobs,
    knob_product,
)
from .blocks.epilogue_nvfp4 import W4A4Chain
from .schedule import (  # noqa: F401  (re-exported)
    TOP_K,
    active_experts,
    exposed_epilogue_cycles,
    pair_term,
    raster_for,
    rows_per_expert,
    tiles_term,
    zero_fill_cycles,
)

#: Epilogue warpgroups of the grouped block-scaled body (:data:`.blocks.kernel_nvfp4.EPI_WARPGROUPS_NVFP4`): the exposed
#: epilogue term splits a tile's chains between them.
_EPI_WARPGROUPS_NVFP4 = 4

GROUP_ALIGN = (
    128  # the padded group alignment the dispatcher ranks at (one scale-factor atom)
)


def grouped_knobs_blockscaled(clusters=None) -> List[Knobs]:
    """The grouped block-scaled space: the dense records of the nvfp4 knob product at swizzle 1 (no in-cluster split, no
    operand swap, no B-reuse tile, no in-CTA chunk fold: the group scheduler has none of them), the same records for both
    instruction classes (the step is the class)."""
    return [
        k
        for k in knob_product(
            swizzles=(1,),
            clusters=CLUSTERS if clusters is None else clusters,
            in_fmt="nvfp4",
        )
        if k.cluster_k == 1 and not k.swap_ab and not k.b_reuse and not k.cta_chunks
    ]


def swapped_knobs_blockscaled() -> List[Knobs]:
    """The swapped decode space of the grouped block-scaled classes (:mod:`.blocks.swap_nvfp4`): the dense class's swapped 1-CTA
    records at the narrow token tiles (128 weight rows x 8 / 16 / 32 tokens), one per tile, no cluster, swizzle 1. Disjoint from
    the grouped space; the body reads the dense packing."""
    return [
        Knobs((128, tn), (1, 1), False, True, "m", 1, swap_ab=True)
        for tn in TILES_N_NARROW
    ]


#: The average rows per active expert fill at most three quarters of the swapped token tile (an empirical margin).
SWAP_TILE_FILL = (3, 4)
#: The narrowest swapped tile: the structural rule's pick (the bench's reference point; the ranking decides the dispatch).
SWAP_TILES_DEFAULT = (8,)


def token_tile_default(rows: int) -> Optional[int]:
    """The structural rule of the first campaign (kept as the benches' reference point, not the dispatch): the narrowest swapped
    tile of ``SWAP_TILES_DEFAULT`` the average rows per active expert fill to at most ``SWAP_TILE_FILL``, ``None`` otherwise. The
    dispatch ranks the swapped records with the grouped ones (:func:`rank_grouped_nvfp4`)."""
    num, den = SWAP_TILE_FILL
    for tn in SWAP_TILES_DEFAULT:
        if rows * den <= tn * num:
            return tn
    return None


def chain_nodes_nvfp4(chain: W4A4Chain) -> int:
    """The node count of the chain's term per output element (the exposed epilogue's cost unit): the W4A4 gated / ungated chain on the
    row-scaled accumulators (``glu_scaled_elem`` / ``act_scaled_elem``), GEMM2's scaled conversion, or the static class's GEMM1 -- the
    fp32 gated value plus its share of the block's quantization (the block's scale and codes over its 16 outputs)."""
    from . import mterm as term
    from . import spec_nvfp4 as Q

    alg = term.TermAlgebra()
    s = Q.w4a4_row_scale(alg, alg.leaf("alpha", 0), alg.leaf("pts"))
    g, u = alg.leaf("g", 0, 0), alg.leaf("u", 0, 0)
    if chain.static_quant:
        gs = alg.leaf("gs2", 0)
        if chain.pair:
            vals = [
                Q.glu_scaled_pre(
                    alg,
                    alg.leaf("g", 0, j),
                    alg.leaf("u", 0, j),
                    s,
                    chain.act,
                    chain.params,
                )
                for j in range(Q.NVFP4_BLOCK)
            ]
        else:
            vals = [
                Q.act_scaled_pre(alg, alg.leaf("u", 0, j), s, chain.act, chain.params)
                for j in range(Q.NVFP4_BLOCK)
            ]
        sf_d, codes = Q.static_block(alg, vals, gs)
        total = term.sexpr(sf_d).count("(") + sum(
            term.sexpr(c).count("(") for c in codes
        )
        return max(1, total // Q.NVFP4_BLOCK)
    if chain.pair:
        t = Q.glu_scaled_elem(alg, g, u, s, chain.act, chain.out_fmt, chain.params)
    elif chain.kind == "act":
        t = Q.act_scaled_elem(alg, u, s, chain.act, chain.out_fmt, chain.params)
    else:
        t = Q.scaled_out_elem(alg, u, s, chain.out_fmt)
    return term.sexpr(t).count("(")


def _grouped(cfg: Knobs) -> Knobs:
    """A dense block-scaled record as a grouped one: swizzle 1, no grid cap, the tile clamped into the grouped space (a
    swapped decode record's narrow token tile -> the narrowest grouped N tile; a B-reuse tile -> the 2-CTA tile; an
    in-cluster split or an in-CTA chunk fold -> the plain record of the same tile and cluster)."""
    tm = (
        cfg.tile_m
        if cfg.tile_m in TILES_M_BLOCKSCALED[cfg.use_2cta_instrs]
        else TILES_M_BLOCKSCALED[cfg.use_2cta_instrs][0]
    )
    tn = cfg.tile_n if cfg.tile_n in TILES_N_BLOCKSCALED else TILES_N_BLOCKSCALED[0]
    return Knobs(
        (tm, tn), cfg.cluster_shape_mn, cfg.use_2cta_instrs, True, cfg.raster_along, 1
    )


def all_valid_configs_nvfp4(
    N: int, K: int, E: int, chain: W4A4Chain, in_fmt: str = "nvfp4", clusters=None
) -> List[Knobs]:
    """The configuration space the grouped guarantee is claimed over, for an expert weight shape, a chain and an
    instruction class."""
    from .blocks.compile_nvfp4 import can_implement_grouped_nvfp4

    return [
        k
        for k in grouped_knobs_blockscaled(clusters)
        if can_implement_grouped_nvfp4(k, N, K, E, chain, in_fmt)
    ]


def all_valid_configs_nvfp4_swapped(
    N: int, K: int, E: int, chain: W4A4Chain, in_fmt: str = "nvfp4"
) -> List[Knobs]:
    """The swapped decode records the swapped body accepts for an expert weight shape, a chain and an instruction class (the
    dense packing); the guarantee is claimed over this space and the grouped space together."""
    from .blocks.compile_nvfp4 import can_implement_swapped_nvfp4

    return [
        k
        for k in swapped_knobs_blockscaled()
        if can_implement_swapped_nvfp4(k, N, K, E, chain, in_fmt)
    ]


def padded_rows(rows: int) -> int:
    """The rows per active expert rounded up to whole scale-factor atoms (the grouped kernel's tile fit)."""
    return -(-max(1, rows) // GROUP_ALIGN) * GROUP_ALIGN


def rank_grouped_nvfp4(
    rows: int,
    N: int,
    K: int,
    E: int,
    chain: W4A4Chain,
    in_fmt: str,
    sm_count: Optional[int] = None,
    family: Optional[str] = None,
    k: int = TOP_K,
    nominal: bool = False,
    n_active: Optional[int] = None,
    swap: Optional[bool] = None,
) -> List[Knobs]:
    """The ranked records for one GEMM over both record spaces (the bf16 dispatcher's form, :func:`.schedule.rank_grouped`): the
    grouped records the grouped body accepts for the weight shape, the chain and the instruction class (at a decode-sized ``rows``
    the dense dispatcher's structural guard, `heuristic.decode_sane`, selects the candidates; a record whose M tile is taller than
    the group's padded rows is excluded: the group scheduler's tiles never span groups) and the swapped records the swapped body
    accepts (``swap``: None ranks them with the rest, True keeps only them, False excludes them), ordered by the dense class's
    estimate at ``(M = rows, N = n_active * N, K)`` at the instruction class times the pair term and the swapped records' spill
    factor, plus the last tile's exposed epilogue chain (this class's chain term over four epilogue warpgroups), the token
    box's zero-fill at the packed fp4 width (a swapped record's at its exposed share) and the body's fixed cost per wave
    (`schedule.fixed_cycles`, off until the part is measured), rounded to three significant digits; the grouped scheduler's structural raster first
    among twins, ties in the spaces' enumeration order (the grouped records before the swapped ones, the narrower token tile
    first). Each of the best ceil(k/2) records is followed by its raster twin, then the rank order fills the list: distinct
    records, at most ``k``, never empty for an implementable shape."""
    import dataclasses

    from ...gemm.batch_invariant.heuristic import (
        PART_TABLE,
        decode_sane,
        estimate_cycles,
    )
    from .blocks.compile_nvfp4 import (
        can_implement_grouped_nvfp4,
        can_implement_swapped_nvfp4,
    )
    from .schedule import fixed_cycles

    fam = family or "sm_107"
    sms = sm_count or PART_TABLE.get(fam, PART_TABLE["sm_107"]).sm_count
    dense_n = (n_active or E) * N
    m_fit = padded_rows(rows)
    dense = (
        []
        if swap is True
        else [
            c
            for c in grouped_knobs_blockscaled()
            if c.tile_m <= m_fit
            and can_implement_grouped_nvfp4(c, N, K, E, chain, in_fmt)
        ]
    )
    swapped = (
        []
        if swap is False
        else [
            c
            for c in swapped_knobs_blockscaled()
            if can_implement_swapped_nvfp4(c, N, K, E, chain, in_fmt)
        ]
    )
    space = dense + swapped
    guarded = [c for c in dense if decode_sane(c, rows, False)] or dense
    nodes = chain_nodes_nvfp4(chain)

    def key(i, c):
        canon = dataclasses.replace(c, raster_along="m")
        est = estimate_cycles(
            canon, rows, dense_n, K, 1, "k", in_fmt, fam, sm_count, nominal=nominal
        )
        est = (
            est * pair_term(c, rows) * tiles_term(c, rows)
            + exposed_epilogue_cycles_nvfp4(c, rows, nodes)
            + zero_fill_cycles(c, rows, K, fam, in_fmt)
            + fixed_cycles(c, rows, n_active or E, N, fam, sms)
        )
        return (
            float(f"{est:.3g}"),
            0 if (c.swap_ab or c.raster_along == raster_for(c, rows)) else 1,
            i,
        )

    ranked = [
        c for _k, c in sorted((key(i, c), c) for i, c in enumerate(guarded + swapped))
    ]
    members = set(space)
    out: List[Knobs] = []
    seen = set()
    for rec in ranked[: -(-k // 2)]:
        twin = dataclasses.replace(
            rec, raster_along="n" if rec.raster_along == "m" else "m"
        )
        for cand in (rec, twin):
            if cand not in seen and (cand is rec or cand in members):
                out.append(cand)
                seen.add(cand)
    for rec in ranked:
        if len(out) >= k:
            break
        if rec not in seen:
            out.append(rec)
            seen.add(rec)
    return out[:k]


def exposed_epilogue_cycles_nvfp4(cfg: Knobs, rows: int, nodes: int) -> float:
    """The bf16 dispatcher's exposed-epilogue term with this body's epilogue warpgroups: the grouped body splits a tile's columns
    between four warpgroups, the swapped body computes the live token columns of a weight row per thread."""
    from .schedule import CHAIN_NODE_CYCLES

    if cfg.swap_ab:
        chains = min(rows, cfg.tile_n)
    else:
        chains = cfg.tile_n / _EPI_WARPGROUPS_NVFP4
    return chains * nodes * CHAIN_NODE_CYCLES


def default_configs_nvfp4(
    T: int,
    k: int,
    H: int,
    I: int,
    E: int,
    in_fmts: Tuple[str, str],
    chain1: W4A4Chain,
    chain2: W4A4Chain,
    sm_count: Optional[int] = None,
    family: Optional[str] = None,
    nominal: bool = False,
    swap: Optional[bool] = None,
) -> Tuple[Knobs, Knobs]:
    """``(config for GEMM1 (N = 2I or I, K = H), config for GEMM2 (N = H, K = I))``: the first record of each ranked list
    (``swap``: the swapped decode body by the structural rule (None), forced (True) or forbidden (False))."""
    rows, n_act = rows_per_expert(T, k, E), active_experts(T, k, E)
    n1 = 2 * I if chain1.pair else I
    c1 = rank_grouped_nvfp4(
        rows, n1, H, E, chain1, in_fmts[0], sm_count, family, 1, nominal, n_act, swap
    )
    c2 = rank_grouped_nvfp4(
        rows, H, I, E, chain2, in_fmts[1], sm_count, family, 1, nominal, n_act, swap
    )
    if not c1 or not c2:
        raise ValueError(
            f"no grouped block-scaled record implements (H={H}, I={I}, E={E}, {in_fmts})"
        )
    return c1[0], c2[0]
