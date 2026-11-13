# Copyright (c) 2026 by FlashInfer team.
# SPDX-License-Identifier: Apache-2.0
"""The DeepSeekFp8 x DeepSeekFp8 pair of the batch-invariant fp8-block MoE backend of the unified MoE layer
(``BatchInvariantFp8BlockConfig`` under ``QuantConfig(DeepSeekFp8, DeepSeekFp8)`` -> ``BatchInvariantFp8BlockRunner`` ->
``BatchInvariantDeepSeekFp8Runner``, the pair's runner): the DeepSeek-style block-scale classes ``moe.e4m3bs.<act>`` (128-wide
blocks) and ``moe.e4m3bs32.<act>`` (32-wide) on SM100 / SM103 / SM107.

The surface is TRTLLM-Gen's block-fp8 one under the DeepSeek pair: e4m3 activations with their fp32 block scales
(``hidden_states_scale [H / block, T]``, as ``TrtllmFp8BlockConfig.prepare_activations`` hands them; the ``[T, H / block]``
layout is taken too), the weights prepared from the bf16 experts per block (or FlashInfer's DeepSeek weight view taken as
given), every routing input mode and every typed activation of the layer through the shared flow of
:class:`.runner.BatchInvariantMoeRunnerBase` (the pack, the fused route + plan launch, the launch). The class is the prepared
weights' block size, read off the view at the pack. The tactics are the ranked block-scale record pairs in both
requantization spellings (any tactic gives the same bits); the combine is the slot-order fp32 fold (``do_finalize=True``
only); an unsupported configuration raises :class:`flashinfer.batch_invariant.BatchInvariantUnsupportedError` instead of
falling back.
"""

from __future__ import annotations

from typing import Any, List, Optional, Tuple

import torch

from ...batch_invariant.support import unsupported
from ..api import MoEActivationPack, MoEWeightPack
from .runner import _TACTIC_FIELDS, MOE_BF16_ARCHS, _configs_from_tactic, _tactic
from .runner_fp8_block import PAIR_DEEPSEEK_FP8, BatchInvariantFp8BlockRunner
from .spec_fp8bs import BLOCK as QBLOCK
from .spec_fp8bs import CLASS, CLASS_OF

#: The compute capabilities the classes are stated for (the dense block-scale GEMM class's parts).
MOE_FP8BS_ARCHS: Tuple[Tuple[int, int], ...] = MOE_BF16_ARCHS
#: Positions of the packed inputs: the e4m3 activations, their block scales, the expert ids, the routing weights, the two
#: quantized weights with their block scales and the output.
_X, _SX, _IDS, _W, _W1, _W1SF, _W2, _W2SF, _OUT = range(9)


def _tactic_bs(c1, c2, fused: bool) -> tuple:
    """A pair of records (each with its swapped flag: the grouped or the swapped body) and the requantization spelling as a flat
    tuple of scalars (the autotuner's cache round-trips every knob the records carry; the swizzle and the grid are the class's
    constants)."""
    return _tactic(c1, c2) + (int(bool(fused)),)


def MoEWeightsE4M3BS_block_of(inputs: List[torch.Tensor]) -> int:
    """The scale block size of the packed inputs' weights (``w1`` and its scales)."""
    from .api_fp8bs import MoEWeightsE4M3BS

    return MoEWeightsE4M3BS.block_of(inputs[_W1], inputs[_W1SF])


def _configs_from_tactic_bs(t: tuple):
    n = 2 * _TACTIC_FIELDS
    c1, c2 = _configs_from_tactic(tuple(t[:n]))
    return c1, c2, bool(t[n])


class BatchInvariantDeepSeekFp8Runner(BatchInvariantFp8BlockRunner):
    """The fp8-block backend's runner for the DeepSeekFp8 x DeepSeekFp8 pair: the batch-invariant block-scale fp8 MoE
    classes."""

    supported_quant_variants = (PAIR_DEEPSEEK_FP8,)

    CLASS = CLASS
    ARCHS = MOE_FP8BS_ARCHS
    X_DTYPE = torch.float8_e4m3fn
    ROW_ALIGN = QBLOCK
    X_RULE = "an e4m3 [num_tokens, hidden_size] with its fp32 block scales (the DeepSeek pair)"
    ROW_RULE = f"a positive multiple of {QBLOCK} (whole smem stages of scale blocks of the intermediate and of both weights)"
    SCALE_RULE = f"the fp32 block scales [hidden_size / {QBLOCK}, num_tokens] of the activations (/ 32 for the 32-wide class)"
    TACTIC_TAG = CLASS + "-v1"  # the block's class joins the cache key at the pack (`_cache_key_extras`)
    N_ACT_TENSORS = 2
    N_WEIGHT_TENSORS = 4

    def __init__(self, config, device) -> None:
        super().__init__(config, device)
        self._block: int = QBLOCK
        self._fused: bool = False

    # ---- inputs ----------------------------------------------------------------------------------------------------
    def _accepts_shape(self, act: MoEActivationPack) -> bool:
        x = act.hidden_states_q
        return (
            x.ndim == 2
            and x.dtype == torch.float8_e4m3fn
            and x.shape[1] % QBLOCK == 0
            and act.hidden_states_scale is not None
        )

    def pack_inputs(
        self, act: MoEActivationPack, weights: MoEWeightPack
    ) -> List[torch.Tensor]:
        self._require_built()
        self._validate_pack_contract(act)
        # the class is the prepared weights' block size: the activation scales are checked against it in `_act_tensors`
        self._block = self._weights_from_view(weights.get_view(self.backend_key)).block
        return super().pack_inputs(act, weights)

    def _act_tensors(self, act: MoEActivationPack) -> List[torch.Tensor]:
        """The pair's activation pack: the e4m3 rows and their fp32 block scales in the kernel's ``[H / block, T]`` layout
        (the ``[T, H / block]`` layout taken too), and the class's shape rule on the configuration at this hidden size."""
        from .api_fp8bs import check_shape_fp8bs, scale_mn_view

        x = act.hidden_states_q
        if x.dtype != self.X_DTYPE or x.ndim != 2:
            raise unsupported(
                self.CLASS, f"hidden_states_q {x.dtype} of rank {x.ndim}", self.X_RULE
            )
        if act.hidden_states_scale is None:
            raise unsupported(self.CLASS, "no hidden_states_scale", self.SCALE_RULE)
        x = x.contiguous()
        T, H = x.shape
        if H % QBLOCK:
            raise unsupported(self.CLASS, f"hidden size {H}", self.ROW_RULE)
        cfg = self.config
        check_shape_fp8bs(
            H,
            cfg.experts.intermediate_size,
            cfg.routing.num_experts,
            cfg.routing.top_k,
            self._block,
        )
        sx = (
            scale_mn_view(
                act.hidden_states_scale,
                H // self._block,
                T,
                "hidden_states_scale",
                self._block,
            )
            .t()
            .contiguous()
        )
        return [x, sx]

    # ---- the weight view -------------------------------------------------------------------------------------------
    def _weights_from_view(self, view):
        from .api_fp8bs import MoEWeightsE4M3BS

        return MoEWeightsE4M3BS.from_view(view)

    def _weight_tensors(self, w) -> List[torch.Tensor]:
        return [w.w1, w.w1_sf, w.w2, w.w2_sf]

    def _weights_from_tensors(self, a, tensors: List[torch.Tensor]):
        from .api_fp8bs import MoEWeightsE4M3BS

        w1, w1_sf, w2, w2_sf = tensors
        self._block = MoEWeightsE4M3BS.block_of(w1, w1_sf)
        return MoEWeightsE4M3BS(
            w1, w1_sf, w2, w2_sf, a.gated, a.act, a.params, self._block
        )

    # ---- tactics ---------------------------------------------------------------------------------------------------
    def _ranked(self, T: int, fused: Optional[bool] = None) -> Tuple[list, list]:
        """The ranked records of both GEMMs over both record spaces at ``T`` tokens for the requantization spelling ``fused``
        (the default spelling's at this token count when None), memoised (`schedule_fp8bs.rank_grouped_fp8bs`)."""
        from .blocks.fp8bs_compile import GEMM2_CHAIN
        from .schedule import TOP_K, active_experts, rows_per_expert
        from .schedule_fp8bs import gemm1_chain, rank_grouped_fp8bs

        cfg = self.config
        E, k, I = (
            cfg.routing.num_experts,
            cfg.routing.top_k,
            cfg.experts.intermediate_size,
        )
        H = self._hidden
        if fused is None:
            fused = self._fused_default(T)
        rows, n_act = rows_per_expert(T, k, E), active_experts(T, k, E)
        a = self._activation()
        sm_count, family = self._part if self._part is not None else (None, None)
        n1 = 2 * I if a.gated else I
        return (
            rank_grouped_fp8bs(
                rows,
                n1,
                H,
                E,
                gemm1_chain(a.act, a.params, a.gated, fused),
                sm_count,
                family,
                TOP_K,
                n_active=n_act,
                block=self._block,
            ),
            rank_grouped_fp8bs(
                rows,
                H,
                I,
                E,
                GEMM2_CHAIN,
                sm_count,
                family,
                TOP_K,
                n_active=n_act,
                block=self._block,
            ),
        )

    def _fused_default(self, T: int) -> bool:
        from .schedule_fp8bs import fused_quant_default

        cfg = self.config
        return fused_quant_default(
            T, cfg.routing.top_k, cfg.routing.num_experts, self._block
        )

    def _default(self, T: int):
        """``(c1, c2, fused)``: the dispatcher's records and spelling at ``T`` tokens."""
        fused = self._fused_default(T)
        r1, r2 = self._ranked(T, fused)
        return r1[0], r2[0], fused

    def _pick(self, T: int) -> Tuple[Any, Any]:
        c1, c2, self._fused = self._default(T)
        return c1, c2

    def _configs_of_tactic(self, tactic: Any) -> Tuple[Any, Any]:
        c1, c2, self._fused = _configs_from_tactic_bs(tuple(tactic))
        return c1, c2

    def get_valid_tactics(self, inputs: List[torch.Tensor], profile) -> List[Any]:
        """The ranked record pairs of both requantization spellings, the dispatcher's spelling first (every tactic computes
        the class)."""
        self._require_built()
        self._hidden = int(inputs[_X].shape[1])
        self._block = MoEWeightsE4M3BS_block_of(inputs)
        T = int(inputs[_X].shape[0])
        default_fused = self._fused_default(T)
        out: List[Any] = []
        # both requantization spellings at the 128-wide class; the 32-wide class has the standalone pass only
        spellings = (
            (default_fused, not default_fused) if self._block == QBLOCK else (False,)
        )
        for fused in spellings:
            r1, r2 = self._ranked(T, fused)
            out += [_tactic_bs(c1, c2, fused) for c1 in r1 for c2 in r2]
        return out

    def _cache_key_extras(self) -> tuple:
        return super()._cache_key_extras() + (CLASS_OF[self._block] + "-v1",)

    # ---- launch ----------------------------------------------------------------------------------------------------
    def _launch(self, x, ids, wts, w, out, c1, c2, plan, inputs):
        from .api_fp8bs import fused_moe_fp8bs

        xq, sx = x
        fused_moe_fp8bs(
            xq,
            sx,
            ids,
            wts,
            w,
            out=out,
            config1=c1,
            config2=c2,
            fuse_quant=self._fused,
            plan=plan,
            w_round=getattr(inputs, "w_round", False),
        )
        return out


__all__ = ["MOE_FP8BS_ARCHS", "BatchInvariantDeepSeekFp8Runner"]
