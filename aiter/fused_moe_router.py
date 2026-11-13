# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#
# Stage-level router for fused_moe: picks a backend plan for a normalized
# problem, then executes it.
#
# Design:
#   * Tuned tables are read only through aiter.moe's _try_get_{asm,moe_c,ck}_config,
#     the same functions aiter_moe uses. They are imported inside functions, so
#     importing this module stays light.
#   * FusedMoePlan has separate stage1/stage2 backend fields, so mixed plans
#     (e.g. asm stage1 + ck stage2) fit the same dispatch loop.
#   * Each backend is one registry entry (match/lookup/execute); adding a
#     backend does not touch the core. Execute functions import torch/aiter
#     lazily, so the routing core stays torch-free.
#   * The only host-module imports are the MOE_C entry `moe_c_fused_experts`
#     and the aiter.moe lookup functions, both called lazily.

import functools
import logging
import os
from dataclasses import dataclass, field, replace
from typing import Any, Callable

# Pure-python constants module (no torch): safe to import eagerly, unlike the
# aiter package __init__ which pulls torch + pybind.
from aiter.fused_moe_types import SUPPORTED_ACTIVATIONS

# Resolved locally (env override first) instead of importing aiter.jit.core,
# which would pull in the whole aiter package (torch + pybind) and make this
# module depend on torch.
_AITER_ROOT_DIR_ENV = os.environ.get("AITER_ROOT_DIR", "")
AITER_ROOT_DIR = (
    _AITER_ROOT_DIR_ENV
    if _AITER_ROOT_DIR_ENV
    else os.path.dirname(os.path.dirname(os.path.abspath(__file__)))
)

# ---------------------------------------------------------------------------
# Problem / plan containers
# ---------------------------------------------------------------------------


@dataclass(frozen=True)
class FusedMoeProblem:
    """Normalized routing input (all scalars/strings, torch-free).

    Dtype strings: 'fp16' | 'bf16' for native dtypes; quant dtypes use
    'none' | 'fp8' | 'int8' | 'int4'. ``quant_kind`` is the quantization
    family resolved by the caller (see fused_moe._normalize_problem):
      none | w8a8 | w8a8_block | w4a8 | a8w4 | w4a16 | w8a16
    """

    arch: str
    M: int
    topk: int
    E: int
    model_dim: int
    inter_dim: int
    dtype: str  # activation dtype: 'fp16' | 'bf16'
    q_dtype_a: str  # 'none' | 'fp8' | 'int8'
    q_dtype_w: str  # 'none' | 'fp8' | 'int8' | 'int4'
    quant_kind: str
    quant_type: str = "no"  # raw QuantType name: no/per_Tensor/per_Token/...
    block_shape: tuple | None = None
    g1u1: bool = True
    activation: str = "silu"
    doweight_stage1: bool = False
    use_shuffle: int = 0
    is_ep: bool = False
    splitk: int = 0
    block_size_M: int | None = None  # user override, ck MPerBlock hint
    local_E: int = 0  # experts held on this rank (EP); 0 = same as E
    weight_layout: str = "raw"  # raw | marlin | asm_shuffle; set by
                                # _normalize_problem from the prepared-weight marker
    has_zp: bool = False  # True when w1_zp and w2_zp were both provided (gptq)


@dataclass
class FusedMoePlan:
    """Stage-level dispatch result.

    stage1_backend / stage2_backend name the per-stage backends ("asm"|"ck");
    both are None when a whole-chain backend is selected, in which case
    ``chained_backend`` carries the name ("moe_c"|"triton") and ``extra``
    holds its keyword arguments.
    """

    stage1_backend: str | None = None
    stage2_backend: str | None = None
    chained_backend: str | None = None
    block_m: int = 32
    act_op: int = 0  # ck: 1 = SiLU fused inside stage1, 0 = external activation
    sol_id1: Any = None  # asm: int "A" part; ck: int
    sol_id2: Any = None
    mode: int = 0  # asm: 0=w16a16, 2=w4a16-fp16, 3=w4a16-bf16, 4=w4a16-bf16-group32
    use_shuffle: int = 0
    flat: bool = False
    extra: dict = field(default_factory=dict)


@dataclass
class FusedMoeExecContext:
    """Runtime tensors handed to a backend execute(). Fields are opaque here."""

    hidden_states: Any = None
    w1: Any = None
    w2: Any = None
    topk_weight: Any = None
    topk_ids: Any = None
    expert_mask: Any = None
    activation: Any = None  # aiter ActivationType enum
    quant_type: Any = None  # aiter QuantType enum
    dtype: Any = None  # output dtype (torch.dtype) or None
    output: Any = None
    w1_scale: Any = None
    w2_scale: Any = None
    a1_scale: Any = None
    a2_scale: Any = None
    w1_zp: Any = None
    w2_zp: Any = None
    # Output scaling and stage1 activation hyper-params (aiter_moe contract).
    # routed_scaling_factor is normalized to 1.0 upstream.
    routed_scaling_factor: Any = 1.0
    gemm1_alpha: Any = None
    gemm1_limit: Any = None
    num_local_tokens: Any = None
    plan: FusedMoePlan | None = None
    problem: FusedMoeProblem | None = None


@dataclass(frozen=True)
class BackendEntry:
    name: str
    match: Callable[[FusedMoeProblem], bool]
    # None = matched, but no tuned config for this shape (try the next candidate)
    lookup: Callable[[FusedMoeProblem], dict | None]
    execute: Callable[[FusedMoeExecContext], Any]


# ---------------------------------------------------------------------------
# Backend match / lookup helpers
# ---------------------------------------------------------------------------


def _to_moe_quant_type(problem: FusedMoeProblem):
    """quant_kind -> aiter.moe.MoeQuantType. Returns None for the fp4 families
    (no routable lookup yet)."""
    from aiter.moe import MoeQuantType

    kind = problem.quant_kind
    if kind == "none":
        return MoeQuantType.W16A16
    if kind == "w8a16":
        return MoeQuantType.INT8_W8A16
    if kind in ("w8a8", "w8a8_block"):
        return (
            MoeQuantType.FP8_W8A8 if problem.q_dtype_a == "fp8" else MoeQuantType.W8A8
        )
    if kind == "w4a16":
        return MoeQuantType.W4A16
    if kind == "w4a8":
        return MoeQuantType.W4A8
    if kind == "wfp4a16":
        return MoeQuantType.WFP4A16
    if kind == "wfp4a8":
        return MoeQuantType.WFP4A8
    return None


def _moe_block_size(problem: FusedMoeProblem) -> int:
    """block_size argument for the aiter.moe lookups: the K group size for
    w8a8_block (128), 0 for everything else."""
    if problem.quant_kind == "w8a8_block" and problem.block_shape:
        return int(problem.block_shape[1])
    return 0


def _torch_dtype(problem: FusedMoeProblem):
    """dtype string -> torch.dtype."""
    import torch

    return torch.float16 if problem.dtype == "fp16" else torch.bfloat16


# Per-backend activation capability faces, matched to each host implementation:
#   * asm: the boltops moe_activation path supports silu/gelu/swigluoai/
#     swiglustep/gelu_tanh (gated) and relu2 (non-gated); situ refuses without
#     activation_situ_beta, which fused_moe does not carry -> excluded.
#   * moe_c: silu fast path + situ special case (moe_c_situ_glu, beta
#     hardcoded 4.0/25.0) + _apply_activation (gelu/gelu_tanh/swigluoai/
#     swiglustep/relu2) = the full SUPPORTED_ACTIVATIONS set.
#   * triton: the boltops host normalizes through the same
#     normalize_moe_activation layer, so situ is moe_c-only here too.
#   * ck: _get_ck_activation_type accepts three strings (gelu_tanh maps to the
#     Gelu enum, tanh approximation lost).
_BOLTOPS_ACTIVATIONS = (
    "silu", "gelu", "gelu_tanh", "swigluoai", "swiglustep", "relu2",
)
_BACKEND_ACTIVATIONS = {
    "asm": _BOLTOPS_ACTIVATIONS,
    "moe_c": SUPPORTED_ACTIVATIONS,
    "triton": _BOLTOPS_ACTIVATIONS,
    "ck": ("silu", "gelu", "gelu_tanh"),
}


def _activation_ok(problem: FusedMoeProblem, backend: str) -> bool:
    return problem.activation in _BACKEND_ACTIVATIONS[backend]


def _looks_like_mxfp(problem: FusedMoeProblem) -> bool:
    # per_1x32 normalizes into the wfp4a16/wfp4a8 families; only the
    # blockwise fp8 mxfp variants stay rejected here.
    return problem.quant_type in ("per_256x128", "per_1024x128")


# ---------------------------------------------------------------------------
# Backend execute paths (torch/aiter imported lazily)
# ---------------------------------------------------------------------------


def _asm_execute(ctx: FusedMoeExecContext):
    """Run the asm path by forwarding to fused_moe_asm_wna16.fused_experts_asm_impl.

    This is the same entry aiter_moe uses. The tuned solution ("SOL1+SOL2",
    PADDED_K, USE_SHUFFLE) comes from aiter.moe._try_get_asm_config via
    moe_cfg. The forwarded function handles quantization, K padding, weight
    shuffle tables, sorting, activation and moe_sum itself, and launches only
    solutions whose block size matches the blob's launch bounds.
    """
    from aiter.fused_moe_asm_wna16 import fused_experts_asm_impl

    plan, problem = ctx.plan, ctx.problem
    cfg = plan.extra.get("moe_cfg") or {}
    if "SOL_ID1" not in cfg or "SOL_ID2" not in cfg:
        return None  # no usable solution in the config: do not launch
    out_dtype = ctx.dtype or ctx.hidden_states.dtype
    is_w8a8 = problem.quant_kind in ("w8a8", "w8a8_block")
    use_shuffle = int(cfg.get("USE_SHUFFLE", problem.use_shuffle) or 0)
    padded_k = cfg.get("PADDED_K")
    w1, w2 = ctx.w1, ctx.w2
    if use_shuffle and problem.weight_layout != "asm_shuffle":
        raise AssertionError(
            "fused_moe: asm solution requires the asm_shuffle layout but got "
            f"{problem.weight_layout!r}; call fused_moe_prepare_weights and pass "
            "the returned prepared")
    # w2_scale 的第 1 维必须与补 K 后的权重一致（与 aiter_moe 的行为一致）。
    # 这是形状修正，不是重排，因此不放进准备函数（调用方不需要换 scale）。
    w2_scale = ctx.w2_scale
    if padded_k is not None and w2_scale is not None:
        from aiter.moe import _pad_tensor_dim
        w2_scale = _pad_tensor_dim(w2_scale, 1, int(padded_k))
    return fused_experts_asm_impl(
        ctx.hidden_states, w1, w2, ctx.topk_weight, ctx.topk_ids,
        dtype=out_dtype,
        activation=problem.activation,
        # Pass is_gated explicitly (same as the triton executor): inferring it
        # from the activation misreads g1u0 weights (w1 N == inter_dim, EP
        # shapes) as gated and the result is silently wrong.
        is_gated=problem.g1u1,
        use_fp8_w8a8=is_w8a8 and problem.q_dtype_a == "fp8",
        use_int8_w8a8=is_w8a8 and problem.q_dtype_a == "int8",
        use_int4_w4a16=problem.quant_kind == "w4a16",
        w1_zp=ctx.w1_zp,
        w2_zp=ctx.w2_zp,
        # Scaling/alpha passthrough with transparent degradation: if the asm
        # kernels ignore alpha/limit, a one-shot WARNING records it; the match
        # is not revoked.
        routed_scaling_factor=ctx.routed_scaling_factor,
        gemm1_alpha=ctx.gemm1_alpha,
        gemm1_limit=ctx.gemm1_limit,
        per_channel_quant=problem.block_shape is None,
        global_num_experts=problem.E,
        expert_map=_expert_mask_to_map(ctx.expert_mask),
        w1_scale=ctx.w1_scale,
        w2_scale=w2_scale,
        a1_scale=ctx.a1_scale,
        a2_scale=ctx.a2_scale,
        block_shape=list(problem.block_shape) if problem.block_shape else None,
        use_shuffle=use_shuffle,
        solution_id=f"{cfg['SOL_ID1']}+{cfg['SOL_ID2']}",
        padded_k=padded_k,
    )


def _ck_execute(ctx: FusedMoeExecContext):
    """CK execution: forward to fused_moe_ck.run_fused_experts_ck_impl,
    the same entry aiter_moe uses (module_moe / ck_tile). Requires
    module_moe.so (checked by _ck_module_ready; the lookup abstains otherwise).

    The host dispatches 1stage/2stage internally by the solution_id bit30
    (fused_moe_ck.py); sol_id=0 (no table row) runs the 1stage path.
    """
    from aiter.fused_moe_ck import run_fused_experts_ck_impl

    plan, problem = ctx.plan, ctx.problem
    out_dtype = ctx.dtype or ctx.hidden_states.dtype
    is_w8a8 = problem.quant_kind == "w8a8"
    return run_fused_experts_ck_impl(
        ctx.hidden_states,
        ctx.w1,
        ctx.w2,
        ctx.topk_weight,
        ctx.topk_ids,
        odtype=out_dtype,
        inplace=False,
        activation=problem.activation,
        use_fp8_w8a8=is_w8a8 and problem.q_dtype_a == "fp8",
        use_int8_w8a8=is_w8a8 and problem.q_dtype_a == "int8",
        per_channel_quant=problem.block_shape is None,
        global_num_experts=problem.E,
        block_m=plan.block_m,
        expert_map=_expert_mask_to_map(ctx.expert_mask),
        w1_scale=ctx.w1_scale,
        w2_scale=ctx.w2_scale,
        w1_zp=ctx.w1_zp,
        w2_zp=ctx.w2_zp,
        a1_scale=ctx.a1_scale,
        a2_scale=ctx.a2_scale,
        block_shape=list(problem.block_shape) if problem.block_shape else None,
        use_shuffle=int(problem.use_shuffle),
        routed_scaling_factor=ctx.routed_scaling_factor,
        solution_id=plan.extra.get("sol_id"),
    )


def _expert_mask_to_map(expert_mask):
    """Convert expert_mask (global 0/1 mask) to expert_map (global id -> local id,
    -1 = not on this rank).

    The triton and moe_c entry points take an expert_map and recover the 0/1
    mask themselves with ``expert_map >= 0``; handing them the raw mask would
    mark every expert local (0 >= 0) and index past the rank's weights. Local
    ids follow the same cumulative numbering as torch_moe / moe_sorting.
    """
    if expert_mask is None:
        return None
    import torch

    local_id = expert_mask.cumsum(0, dtype=torch.int32) - 1
    return torch.where(expert_mask != 0, local_id, torch.full_like(local_id, -1))


def _moe_c_execute(ctx: FusedMoeExecContext):
    """MOE_C whole-chain execution: forward to moe_c_fused_experts.

    执行层不做任何权重重排：权重必须是准备函数给出的 marlin 布局
    （wfp4a16 例外，原样消费）；raw 权重在这里直接报错。"""
    from aiter.fused_moe_c import moe_c_fused_experts

    problem, plan = ctx.problem, ctx.plan
    w1, w2 = ctx.w1, ctx.w2
    # moe_c 只接受准备函数给出的 marlin 权重；raw 权重在这里必须报错，
    # 绝不现场重排：raw 直接进 marlin 内核会静默算错。
    if problem.quant_kind in ("w8a16", "w8a8", "w4a8", "wfp4a8"):
        if problem.weight_layout != "marlin":
            raise AssertionError(
                "fused_moe: moe_c requires the marlin layout but got "
                f"{problem.weight_layout!r}; call fused_moe_prepare_weights and "
                "pass the returned prepared")
    extra = plan.extra
    w1_zp, w2_zp = ctx.w1_zp, ctx.w2_zp
    # w4a16 在匹配层被拒绝（见 _moe_c_match），其 scale 重排分支不可达；
    # 其余家族的 scale 原样透传（w8a8/w8a16/w4a8/wfp4a8 均如此）。
    w1_scale, w2_scale = ctx.w1_scale, ctx.w2_scale
    block_shape = list(problem.block_shape) if problem.block_shape else None
    out = moe_c_fused_experts(
        ctx.hidden_states,
        w1,
        w2,
        ctx.topk_weight,
        ctx.topk_ids,
        # inplace=True would overwrite hidden_states; the caller copies the
        # result into `output` instead.
        inplace=False,
        activation=problem.activation,
        use_fp8_w8a8=extra.get("use_fp8_w8a8", False),
        use_int8_w8a8=extra.get("use_int8_w8a8", False),
        use_int8_w8a16=extra.get("use_int8_w8a16", False),
        use_int4_w4a16=extra.get("use_int4_w4a16", False),
        use_int8_w4a8=extra.get("use_int8_w4a8", False),
        use_fp4_w4a16=extra.get("use_fp4_w4a16", False),
        use_fp4_w4a8=extra.get("use_fp4_w4a8", False),
        global_num_experts=problem.E,
        expert_map=_expert_mask_to_map(ctx.expert_mask),
        w1_scale=w1_scale,
        w2_scale=w2_scale,
        w1_zp=w1_zp,
        w2_zp=w2_zp,
        a1_scale=ctx.a1_scale,
        a2_scale=ctx.a2_scale,
        block_shape=block_shape,
        is_gated=problem.g1u1,
        # Forward the scaling/alpha trio (moe_c consumes alpha/limit in
        # _apply_activation); compute_dtype intentionally NOT passed -- the
        # host defaults to the hidden dtype for computation and the output
        # dtype is guaranteed by the caller-side cast.
        routed_scaling_factor=ctx.routed_scaling_factor,
        gemm1_alpha=ctx.gemm1_alpha,
        gemm1_limit=ctx.gemm1_limit,
    )
    return out


def _triton_execute(ctx: FusedMoeExecContext):
    """Triton whole-chain execution through boltops fused_experts_impl.

    Uses the same entry and keyword mapping as the TRITON branch of aiter_moe.
    fused_experts_impl looks up the installed ``triton_<capability>`` JSON
    configs itself, so no config object is passed in.
    """
    from boltops.fused_moe.triton.fused_moe import fused_experts_impl

    problem, plan = ctx.problem, ctx.plan
    extra = plan.extra
    use_fp8_w8a8 = extra.get("use_fp8_w8a8", False)
    use_int8_w8a8 = extra.get("use_int8_w8a8", False)
    use_int8_w8a16 = extra.get("use_int8_w8a16", False)
    use_int4_w4a8 = extra.get("use_int4_w4a8", False)
    block_shape = extra.get("block_shape", problem.block_shape)
    # Same as aiter_moe: per-channel only for channelwise quant without block_shape
    # (blockwise w8a8_block passes its 2-D group scales through block_shape).
    per_channel_quant = (
        (use_int8_w8a8 or use_fp8_w8a8 or use_int8_w8a16 or use_int4_w4a8)
        and block_shape is None
    )
    return fused_experts_impl(
        ctx.hidden_states,
        ctx.w1,
        ctx.w2,
        ctx.topk_weight,
        ctx.topk_ids,
        output_dtype=ctx.dtype or ctx.hidden_states.dtype,
        inplace=False,
        activation=problem.activation,
        # Pass is_gated explicitly. Inferring it from the activation is wrong
        # for g1u0 weights (w1 N == inter_dim, used by EP tests): "silu" would
        # be treated as gated, the width misread, and the result silently wrong.
        is_gated=problem.g1u1,
        use_fp8_w8a8=use_fp8_w8a8,
        use_int8_w8a8=use_int8_w8a8,
        use_int8_w8a16=use_int8_w8a16,
        use_int4_w4a16=extra.get("use_int4_w4a16", False),
        use_int4_w4a8=use_int4_w4a8,
        per_channel_quant=per_channel_quant,
        global_num_experts=problem.E,
        expert_map=_expert_mask_to_map(ctx.expert_mask),
        w1_scale=ctx.w1_scale,
        w2_scale=ctx.w2_scale,
        w1_zp=ctx.w1_zp,
        w2_zp=ctx.w2_zp,
        a1_scale=ctx.a1_scale,
        a2_scale=ctx.a2_scale,
        block_shape=list(block_shape) if block_shape is not None else None,
        routed_scaling_factor=ctx.routed_scaling_factor,
        gemm1_alpha=ctx.gemm1_alpha,
        gemm1_limit=ctx.gemm1_limit,
    )


# ---------------------------------------------------------------------------
# Backend registry + planning
# ---------------------------------------------------------------------------

BACKEND_REGISTRY: dict[str, BackendEntry] = {}

# asm is admitted by quant_kind alone (see _asm_match). int4 families are
# rejected at the start of plan(). none, w8a8 and w8a8_block run through the
# host forwarder, whose tuned solutions match the blobs' launch bounds.


def _asm_match(problem: FusedMoeProblem) -> bool:
    if problem.is_ep or problem.doweight_stage1 or problem.splitk:
        return False
    if not _activation_ok(problem, "asm"):
        return False
    if _looks_like_mxfp(problem):
        return False
    if problem.quant_kind == "w4a16":
        # fp16 w4a16 hits a mode2 blob VMFault (sol 10000/11000 families);
        # only bf16 may enter asm, and _asm_lookup additionally whitelists the
        # gw32 safe solutions.
        return problem.dtype == "bf16"
    # w8a8_block is handled by fused_experts_asm_impl too (blockwise scales,
    # K padding, shuffle tables, PADDED_K), so the router does not repeat them.
    # Shapes without a tuned row return None in _asm_lookup and fall through
    # to the next candidate.
    return problem.quant_kind in ("none", "w8a8", "w8a8_block")


def _asm_lookup(problem: FusedMoeProblem) -> dict | None:
    """Read the asm tuned table through aiter.moe._try_get_asm_config, the same
    function aiter_moe uses (K padding, forced USE_SHUFFLE and PADDED_K are
    handled there). SOL_ID1/SOL_ID2/BLOCK_SIZE_M are copied flat into the
    result and the full config is kept in plan.extra["moe_cfg"].
    Returns None if there is no tuned config."""
    from aiter.moe import MoeQuantType, _try_get_asm_config

    qt = _to_moe_quant_type(problem)
    if qt is None:
        return None
    _bs = _moe_block_size(problem)
    if problem.quant_kind == "w4a16" and problem.block_shape:
        _bs = int(problem.block_shape[1])  # group32 → 触发 moe.py gw32 特判
    cfg = _try_get_asm_config(
        qt,
        problem.M,
        problem.E,
        problem.inter_dim,
        problem.model_dim,
        problem.topk,
        _bs,
        use_shuffle=1 if problem.weight_layout == "asm_shuffle" else 0,
    )
    if cfg is None:
        return None
    if qt == MoeQuantType.W4A16 and (
        (cfg.get("SOL_ID1"), cfg.get("SOL_ID2")) != (50032, 60032)
    ):
        return None  # 非 gw32 安全解一律弃权（落 moe_c/triton）
    # 配置要求重排（model_dim 不是 64 的倍数时被迫查重排表）但布局不是
    # asm_shuffle 时，asm 不能直接消费；w4a16 的解与布局无关，asm_shuffle 无效。
    if problem.weight_layout == RAW_LAYOUT:
        if (int(cfg.get("USE_SHUFFLE", 0) or 0) == 1
                or cfg.get("PADDED_K") is not None):
            return None
    elif problem.weight_layout == ASM_SHUFFLE_LAYOUT:
        if problem.quant_kind == "w4a16":
            return None
    else:
        return None  # marlin 权重不能进 asm
    return {**cfg, "moe_cfg": cfg, "persist1": 0, "persist2": 0}


def _ck_match(problem: FusedMoeProblem) -> bool:
    if problem.doweight_stage1 or problem.splitk:
        return False
    if not _activation_ok(problem, "ck"):
        return False
    if _looks_like_mxfp(problem):
        return False
    # Aligned with _try_get_ck_config's mapping (W16A16/W8A8/FP8_W8A8 only).
    # a8w4 has no CK entry and w8a8_block has no CK face -- both stay excluded.
    return problem.quant_kind in ("none", "w8a8")


def _ck_module_ready() -> bool:
    """Whether the CK module (module_moe / ck_tile) is built.

    The CK executor forwards to run_fused_experts_ck_impl, whose kernels live
    in module_moe.so. While it is absent the ck entry yields to later
    candidates instead of triggering a JIT build failure at call time.
    """
    return os.path.exists(
        os.path.join(AITER_ROOT_DIR, "aiter", "jit", "module_moe.so")
    )


def _ck_lookup(problem: FusedMoeProblem) -> dict | None:
    # Return None while module_moe.so is missing, even if the
    # table has rows for this shape.
    if not _ck_module_ready():
        return None
    from aiter.moe import _try_get_ck_config

    qt = _to_moe_quant_type(problem)
    if qt is None:
        return None
    cfg = _try_get_ck_config(qt, problem.M, problem.E, problem.inter_dim,
                             problem.model_dim, problem.topk,
                             list(problem.block_shape) if problem.block_shape else None)
    if cfg is None:
        return None
    # get_moe_ck_solution_id returns 0 as its "no matching pattern" sentinel
    # (moe.py wraps it as {"solution_id": 0}, a NON-None config). On gfx938
    # the ck tuned tables have zero gfx938 rows and the sol-0 kernel instance
    # SIGFPE-crashes the process (rc=136, signal death). Abstain on the
    # sentinel so ck only executes with a real tuned solution; a future gfx938
    # table with real sol ids re-enables the backend without code changes.
    if not cfg.get("solution_id"):
        return None
    return {
        "ck_cfg": cfg,
        "sol_id": cfg.get("solution_id", 0),
        "block_m": problem.block_size_M or 32,
    }


def _moe_c_match(problem: FusedMoeProblem) -> bool:
    if problem.doweight_stage1 or problem.splitk:
        return False
    if problem.is_ep:
        # moe_c remaps expert ids through expert_map, so blocks of non-local
        # experts reach the marlin kernels with expert id -1. The w8a16 kernels
        # do not skip -1 and hit a VMFault (E_local=128 of 256, N=768), so EP
        # is left to triton.
        return False
    if not _activation_ok(problem, "moe_c"):
        return False
    if _looks_like_mxfp(problem):
        return False
    # w8a8 candidate order follows aiter_moe (asm > moe_c > triton). moe_c
    # w8a8 per-token has a known numeric error (cos ~0.01-10); the same
    # error occurs when calling the host op directly.
    # w4a16/w4a8 are excluded from moe_c: the marlin int4 path shows
    # long-standing host-side semantic gaps (w4a16: cos ~0 / NaN on 37.5% of
    # cases; w4a8: cos 0.41-0.69 + astronomic need_atol even with the Char
    # container fix, and the host aiter_moe_shfl_weight path fails the same
    # way). Host defects belong in a host change request, not router
    # workarounds, so both families abstain at match level and are served by
    # triton (w4a16 group32 has_zp cos 1.0; w4a8 channelwise cos 0.9998).
    # Re-admission = re-add the kind here once the host fix lands.
    # wfp4a16/wfp4a8 are moe_c-exclusive: fp4 weights have no boltops
    # path, and the e8m0 scale contract is consumed by the host directly.
    # moe_c 的权重必须是 marlin 布局（准备函数给出），执行层不再现场重排。
    return problem.quant_kind in ("w8a16", "w8a8", "wfp4a16", "wfp4a8")


def _moe_c_lookup(problem: FusedMoeProblem) -> dict | None:
    """Check for a tuned marlin config through aiter.moe._try_get_moe_c_config.

    moe_c re-reads the config itself at execute time, so this call only decides
    whether moe_c is a candidate: None means no tuned config. The returned
    flags are consumed by _moe_c_execute.
    """
    from aiter.moe import _try_get_moe_c_config

    # wfp4 block-shape precheck: the host asserts these at :59-70/:77-88;
    # front-loaded here so unsupported shapes abstain instead of reaching the
    # marlin op.
    if problem.quant_kind == "wfp4a16" and problem.block_shape != (0, 32):
        return None
    if problem.quant_kind == "wfp4a8" and problem.block_shape not in (None, (0, 32)):
        return None
    qt = _to_moe_quant_type(problem)
    if qt is None:
        return None
    cfg = _try_get_moe_c_config(
        qt,
        problem.M,
        problem.E,
        problem.inter_dim,
        _moe_block_size(problem),
        k=problem.model_dim,
        top_k=problem.topk,
        indtype=str(_torch_dtype(problem)),
    )
    if cfg is None:
        return None
    # 需要 marlin 却拿到 raw 权重时，moe_c 会把它直接送进 marlin 内核，
    # 因此必须在查表内弃权。
    if problem.quant_kind in _MARLIN_REQUIRED_KINDS:
        if problem.weight_layout != MARLIN_LAYOUT:
            return None
    elif problem.weight_layout != RAW_LAYOUT:
        return None
    # moe_c 的 w8a8_fp8 在 model_dim 不是 64 的倍数时要补 K，kernel侧补 K 的数值
    # 错误（cos 0.085），因此布局即便补好也不放行
    if (problem.quant_kind == "w8a8" and problem.q_dtype_a == "fp8"
            and cfg.get("PADDED_K") is not None):
        return None
    return {
        "use_int4_w4a16": problem.quant_kind == "w4a16",
        "use_int8_w8a16": problem.quant_kind == "w8a16",
        "use_fp8_w8a8": problem.quant_kind == "w8a8" and problem.q_dtype_a == "fp8",
        "use_int8_w8a8": problem.quant_kind == "w8a8" and problem.q_dtype_a == "int8",
        "use_int8_w4a8": problem.quant_kind == "w4a8",
        "use_fp4_w4a16": problem.quant_kind == "wfp4a16",
        "use_fp4_w4a8": problem.quant_kind == "wfp4a8",
        "use_shuffle": problem.use_shuffle,
        "tuned_config": cfg,
    }


def _triton_match(problem: FusedMoeProblem) -> bool:
    # Last-resort backend. The gptq kernel is only verified with has_zp=True
    # + group-32 scales; wfp4 families have no boltops surface.
    if _looks_like_mxfp(problem):
        return False
    # Routing-level activation gate: the boltops host refuses out-of-face
    # activations (situ without beta) only mid-execution; a routing-level
    # reject keeps the "no backend covers" raise honest.
    if not _activation_ok(problem, "triton"):
        return False
    if problem.is_ep and problem.quant_kind in ("w4a16", "w4a8"):
        return False  # EP int4 无验证面，留给后续 raise 指引（见 _supported_order）
    return problem.quant_kind in ("none", "w8a8", "w8a8_block", "w8a16",
                                  "w4a16", "w4a8")


def _triton_lookup(problem: FusedMoeProblem) -> dict | None:
    """Check for a tuned Triton config through aiter.moe._try_get_triton_config.

    W16A16 always returns {} (non-None). Other families return None when no
    triton_<capability> JSON covers the shape, so the next candidate is tried.
    The config is returned as plan.extra["triton_cfg"].
    """
    from aiter.moe import _try_get_triton_config

    qt = _to_moe_quant_type(problem)
    if qt is None:
        return None
    # Use the same key as the boltops executor: local expert count, inter_dim,
    # model_dim and topk.
    cfg = _try_get_triton_config(
        qt, problem.M, problem.local_E or problem.E, problem.inter_dim,
        _moe_block_size(problem), k=problem.model_dim, top_k=problem.topk)
    if cfg is None:
        return None
    return {**_triton_flags(problem), "triton_cfg": cfg}


def _triton_flags(problem: FusedMoeProblem) -> dict:
    """Executor flags for the boltops triton chain. Shared by _triton_lookup and
    the untuned fallback so both build identical arguments."""
    is_w8a8 = problem.quant_kind in ("w8a8", "w8a8_block")
    return {
        "use_fp8_w8a8": is_w8a8 and problem.q_dtype_a == "fp8",
        "use_int8_w8a8": is_w8a8 and problem.q_dtype_a == "int8",
        "use_int4_w4a8": problem.quant_kind == "w4a8",
        "use_int4_w4a16": problem.quant_kind == "w4a16",
        "use_int8_w8a16": problem.quant_kind == "w8a16",
        "per_channel_quant": problem.quant_kind in ("w8a8", "w4a8"),
        "block_shape": problem.block_shape,
    }


BACKEND_REGISTRY["asm"] = BackendEntry("asm", _asm_match, _asm_lookup, _asm_execute)
# ck is registered but not in any _CANDIDATE_ORDER row: the lookup abstains
# unless module_moe.so is built AND the tuned table returns a real solution id
# (see _ck_module_ready / _ck_lookup), so it is only selectable via an explicit
# route-table row. Add it to the per-family rows once tuned tables land.
BACKEND_REGISTRY["ck"] = BackendEntry("ck", _ck_match, _ck_lookup, _ck_execute)
BACKEND_REGISTRY["moe_c"] = BackendEntry("moe_c", _moe_c_match, _moe_c_lookup, _moe_c_execute)
BACKEND_REGISTRY["triton"] = BackendEntry("triton", _triton_match, _triton_lookup, _triton_execute)

# Candidate backends per quant family, highest priority first.
_CANDIDATE_ORDER = {
    # moe_c 从 none 行移除：w16a16 在 moe_c 侧缺 is_bottom=True 的配置，永远不可达
    "none": ("asm", "triton"),
    "w8a8": ("asm", "moe_c", "triton"),
    "w8a8_block": ("asm", "triton"),
    "w8a16": ("moe_c", "triton"),
    # w4a16: asm first for bf16 gw32 (gw32 safe solutions; fp16 skips asm via
    # the _asm_match bf16 gate); moe_c abstains on int4 (host semantic gaps),
    # triton last.
    "w4a16": ("asm", "moe_c", "triton"),
    "w4a8": ("moe_c", "triton"),
    # wfp4 families are moe_c-exclusive: no triton/asm fallback.
    "wfp4a16": ("moe_c",),
    "wfp4a8": ("moe_c",),
}

# 后端「无需重排即可直接消费」的布局，按 quant_kind 区分，见
# _layout_directly_usable。


# ---------------------------------------------------------------------------
# 布局词汇
#
# 合法布局只有三种；量化家族词汇见 FusedMoeProblem.quant_kind。
# 这三个常量在模块顶层定义，供绑定表与决策函数共用。
# ---------------------------------------------------------------------------

RAW_LAYOUT = "raw"
MARLIN_LAYOUT = "marlin"
ASM_SHUFFLE_LAYOUT = "asm_shuffle"


# 布局 -> 后端绑定表。
#
# 重排布局与后端是一对一关系：marlin 只有 moe_c 能直接消费，asm_shuffle 只有
# asm 能直接消费。`_layout_directly_usable` 与 `plan()` 的短路分支都引用这张表，
# 防止绑定关系在两处分叉。
_LAYOUT_BACKEND_BINDING = {
    MARLIN_LAYOUT: "moe_c",
    ASM_SHUFFLE_LAYOUT: "asm",
}

# 只接 raw 的家族：绑定到 marlin 时对这些家族无效（它们本来也不该出现 marlin）
_RAW_ONLY_KINDS = ("w4a16", "w4a8", "wfp4a16", "none")


def _layout_directly_usable(problem: FusedMoeProblem, backend: str, params) -> bool:
    """该后端能否**不再shuffle**直接消费当前权重布局（唯一判定入口）。

    路由表推荐路径与候选链路径都必须走这里，禁止各写一份。
    """
    layout = problem.weight_layout
    if params is None:
        return False
    bound = _LAYOUT_BACKEND_BINDING.get(layout)
    if bound is not None:
        if backend != bound:
            return False
        if layout == ASM_SHUFFLE_LAYOUT:
            # w4a16 的 gw32 解与布局无关，asm_shuffle 对它没有意义
            return problem.quant_kind != "w4a16"
        # marlin：只接 raw 的家族不能出现 marlin 布局
        return problem.quant_kind not in _RAW_ONLY_KINDS
    # ---- raw ----
    if backend == "asm":
        padded_k = params.get("PADDED_K")
        if problem.quant_kind == "w4a16":
            # gw32 解只要求 K 对齐，与拼图布局无关
            return padded_k is None
        return int(params.get("USE_SHUFFLE", 0) or 0) == 0 and padded_k is None
    if backend == "moe_c":
        return problem.quant_kind not in _MARLIN_REQUIRED_KINDS
    return True  # triton / ck 只接 raw


# ---------------------------------------------------------------------------
# Untuned-shape fallback
#
# When no backend has a tuned config for a shape, run boltops triton with its
# own default config and log one warning per shape. Set
# AITER_FMOE_TRITON_FALLBACK=strict to raise NotImplementedError instead. The
# variable is read at import time, so set it before `import aiter`.
#
# boltops fused_experts_impl falls back to its default config on a table miss
# by itself and gives correct results on an EP int8 per-token shape. The
# in-tree aiter.ops.triton path does not (cos 0.975 on the same shape), so it
# is not used here.
# ---------------------------------------------------------------------------

logger = logging.getLogger(__name__)

_TRITON_FALLBACK_MODE = os.environ.get(
    "AITER_FMOE_TRITON_FALLBACK", "warn").strip().lower()
_FALLBACK_STRICT = _TRITON_FALLBACK_MODE in ("strict", "raise", "off", "0")
if not _FALLBACK_STRICT and _TRITON_FALLBACK_MODE != "warn":
    logger.warning(
        "AITER_FMOE_TRITON_FALLBACK=%r is not recognized; using 'warn'. "
        "Use 'strict' to raise on untuned shapes.", _TRITON_FALLBACK_MODE)
# Shapes already warned about in this process. Test runners count fallbacks by
# grepping the log for "fused_moe fallback:".
_fallback_seen: set[tuple] = set()


def _fallback_allowed(problem: FusedMoeProblem) -> bool:
    if _FALLBACK_STRICT:
        return False
    if problem.quant_kind not in _CANDIDATE_ORDER:
        return False  # no candidate order for this family
    if problem.quant_kind in ("wfp4a16", "wfp4a8"):
        return False  # moe_c 独占：禁 triton 兜底（fp4 权重无 boltops 路径）
    if _looks_like_mxfp(problem):
        return False
    if problem.weight_layout != RAW_LAYOUT:
        return False  # triton 只接 raw 权重
    # The fallback runs the boltops triton host, so the activation must be
    # inside the triton face too -- out-of-face activations (situ without
    # beta) must raise at routing, not fail mid-execution with a confusing
    # boltops error.
    if not _activation_ok(problem, "triton"):
        return False
    return True


def _triton_fallback_params(problem: FusedMoeProblem) -> dict | None:
    """Same flags as _triton_lookup, but without a tuned config.

    triton_cfg=None is fine: boltops looks up its own configs at execute time
    and uses its default on a miss. The "fallback" flag in plan.extra lets
    route logs count fallback uses.
    """
    if _to_moe_quant_type(problem) is None:
        return None
    return {**_triton_flags(problem), "triton_cfg": None, "fallback": True}


def _warn_triton_fallback(problem: FusedMoeProblem) -> None:
    key = (
        problem.quant_kind, problem.E, problem.local_E, problem.inter_dim,
        problem.model_dim, problem.topk, problem.q_dtype_a, problem.dtype,
        problem.is_ep,
    )
    if key in _fallback_seen:
        return
    _fallback_seen.add(key)
    local_e = problem.local_E or problem.E  # local_E == 0 means "same as E"
    logger.warning(
        "fused_moe fallback: no tuned triton config for this shape -- running "
        "boltops triton DEFAULT config (performance NOT tuned; tune it or set "
        "AITER_FMOE_TRITON_FALLBACK=strict to raise instead): "
        "E_global=%d E_local=%d N=%d K=%d topk=%d M=%d quant_kind=%s "
        "q_dtype_a=%s dtype=%s act=%s is_ep=%s (executor JSON key space: "
        "triton_3_6/E=%d,N=%d,K=%d,topk=%d,arch=%s,dtype=...)",
        problem.E, local_e, problem.inter_dim, problem.model_dim,
        problem.topk, problem.M, problem.quant_kind, problem.q_dtype_a,
        problem.dtype, problem.activation, problem.is_ep,
        local_e, problem.inter_dim, problem.model_dim, problem.topk,
        problem.arch,
    )

# ---------------------------------------------------------------------------
# Backend route table
#
# Maps a problem shape and token count to the fastest backend found by tuning.
# Written by moe_tune/unified_tune/route_table.py; the column layout must stay
# in sync with it. A missing file or unparsable rows mean no entries, and
# plan() then uses _CANDIDATE_ORDER. Set FMOE_ROUTE_LOG=1 to print which
# route was used.
# ---------------------------------------------------------------------------

_ROUTE_GROUP = ("arch", "quant_type", "indtype", "inter_dim", "model_dim",
                "expert", "topk", "q_size_n", "q_size_k")


def _route_csv_path() -> str:
    return os.path.join(AITER_ROOT_DIR, "aiter", "configs", "tuned_fused_moe_route.csv")


def _route_quant_key(problem: FusedMoeProblem) -> str | None:
    """Map quant_kind and q_dtype_a to the quant_type name used in the route CSV
    (tune_spec.QUANTS). int4 families never get here."""
    kind = problem.quant_kind
    if kind == "none":
        return "no_quant"
    if kind == "w8a16":
        return "int8_w8a16"
    if kind == "w8a8":
        return "f8_w8a8_channel" if problem.q_dtype_a == "fp8" else "int8_w8a8_channel"
    if kind == "w8a8_block":
        return "f8_w8a8_block" if problem.q_dtype_a == "fp8" else "int8_w8a8_block"
    return None


@functools.lru_cache(maxsize=2)
def _load_route_table(path: str):
    """Read the route CSV into {group key: (sorted tokens, backends, times)};
    None if the file is missing or has no valid rows."""
    import csv
    if not os.path.exists(path):
        return None
    groups = {}
    with open(path, newline="") as fh:
        for row in csv.DictReader(fh):
            try:
                key = tuple(str(row[c]).strip() for c in _ROUTE_GROUP)
                token = int(row["token"])
                backend = str(row["backend"]).strip()
            except (KeyError, TypeError, ValueError):
                continue
            if backend not in BACKEND_REGISTRY:
                continue
            entry = groups.setdefault(key, ([], [], []))
            entry[0].append(token)
            entry[1].append(backend)
            entry[2].append(row.get("time_us", ""))
    if not groups:
        return None
    for entry in groups.values():
        order = sorted(range(len(entry[0])), key=lambda i: entry[0][i])
        entry[0][:] = [entry[0][i] for i in order]
        entry[1][:] = [entry[1][i] for i in order]
        entry[2][:] = [entry[2][i] for i in order]
    return groups


def _lookup_route_table(problem: FusedMoeProblem) -> tuple | None:
    """Return (backend, time_us) for the nearest tuned token count, or None.
    On a tie the smaller token count wins."""
    index = _load_route_table(_route_csv_path())
    if not index:
        return None
    quant = _route_quant_key(problem)
    if quant is None:
        return None
    block = problem.block_shape or (0, 0)
    key = (problem.arch, quant,
           "torch.float16" if problem.dtype == "fp16" else "torch.bfloat16",
           str(problem.inter_dim), str(problem.model_dim), str(problem.E),
           str(problem.topk), str(int(block[0])), str(int(block[1])))
    entry = index.get(key)
    if not entry:
        return None
    tokens, backends, times = entry
    token = int(problem.M)
    if token <= tokens[0]:
        idx = 0
    elif token >= tokens[-1]:
        idx = len(tokens) - 1
    else:
        from bisect import bisect_left
        pos = bisect_left(tokens, token)
        if tokens[pos] == token:
            idx = pos
        else:
            left, right = pos - 1, pos
            idx = left if token - tokens[left] <= tokens[right] - token else right
    return backends[idx], times[idx]


_STAGE_BACKENDS = ("asm", "ck")
_CHAIN_BACKENDS = ("moe_c", "triton")


_INT4_UNSUPPORTED_MSG = (
    "fused_moe: int4-weight families currently have no routable "
    "backend -- asm .co blobs fault on this arch (launch bounds), "
    "moe_c marlin requires explicit zero points, which fused_moe has "
    "no argument for, and the triton gptq kernel is only verified "
    "with has_zp=True group-32 scales. Use aiter_moe for these "
    "families."
)


def _supported_order(problem: FusedMoeProblem) -> tuple:
    """Return the candidate backends for the problem's quant family, highest
    priority first. Raise NotImplementedError for problems fused_moe rejects."""
    # EP with int4/fp4 families has no verified backend (gptq+EP is untested);
    # fail early with an explicit pointer instead of silently degrading.
    if problem.is_ep and problem.quant_kind in ("w4a16", "w4a8", "wfp4a16", "wfp4a8"):
        raise NotImplementedError(
            f"fused_moe: EP with {problem.quant_kind} has no verified backend "
            "(gptq+EP is untested); use aiter_moe with an explicit expert_map")
    # a8w4 (fp8 activation + int4 weight) has no backend on either interface.
    if problem.quant_kind == "a8w4":
        raise NotImplementedError(_INT4_UNSUPPORTED_MSG)
    if problem.doweight_stage1:
        raise NotImplementedError(
            "fused_moe: doweight_stage1=True is not supported because the "
            "1-stage kernel backends are not available"
        )
    order = _CANDIDATE_ORDER.get(problem.quant_kind)
    if order is None:
        raise NotImplementedError(
            f"fused_moe routing: unsupported quantization family "
            f"{problem.quant_kind!r} (quant_type={problem.quant_type!r}, "
            f"q_dtype_a={problem.q_dtype_a!r}, q_dtype_w={problem.q_dtype_w!r})"
        )
    return order


# ---------------------------------------------------------------------------
# 布局决策
#
# 三个入口：
#   feasible_layouts(problem)  哪些布局下至少有一个后端「无需重排即可服务」
#   decide_layout(problem)     按双表耗时与家族约束给出唯一布局（加载期一次性）
#   LayoutDecision             决策结果 + 理由 + 补 K 需求
#
# 关键语义：这里的「可用」= 后端拿到该布局的权重可以直接执行，不需要现场重排。
# 执行层不再重排，因此这里的判断必须与 plan() 的判定一致。
# ---------------------------------------------------------------------------

_ASM_QUANT_NAME = {
    ("none", "none"): "no_quant",
    ("w8a8", "int8"): "int8_w8a8_channel",
    ("w8a8", "fp8"): "f8_w8a8_channel",
    ("w8a8_block", "int8"): "int8_w8a8_block",
    ("w8a8_block", "fp8"): "f8_w8a8_block",
}

_MARLIN_REQUIRED_KINDS = ("w8a16", "w8a8", "w4a8", "wfp4a8")


@dataclass(frozen=True)
class LayoutDecision:
    """加载期布局决策结果（可序列化，可写日志）。"""

    layout: str
    family: str | None = None          # 期望承载后端：asm / moe_c / triton / None
    reason: str = ""
    padded_k: int | None = None        # 需要补到的 K（None = 不补）
    original_k: int | None = None
    feasible: frozenset = frozenset()  # 运行期复核用的可行布局集合
    weighted_gain: float | None = None  # 双表加权收益（asm 族）


def _with_layout(problem: FusedMoeProblem, layout: str) -> FusedMoeProblem:
    return replace(problem, weight_layout=layout,
                   use_shuffle=1 if layout == ASM_SHUFFLE_LAYOUT else 0)


def _asm_usable(problem: FusedMoeProblem, layout: str):
    """asm 在该布局下能否**不再shuffle**直接执行。返回 (ok, cfg)。

    注意：asm 配置里通常**没有** USE_SHUFFLE 键（decode_sol_0 不写它），
    是否重排由「查的是哪张表」决定。因此这里以查表参数为准：
      * raw          —— 查普通表命中且没有被迫补 K（PADDED_K is None）
      * asm_shuffle  —— 查重排表命中（权重会被补 K 到 PADDED_K）
    """
    if not _asm_match(problem):
        return False, None
    cfg = _asm_lookup(_with_layout(problem, layout))
    if cfg is None:
        return False, None
    use_shuffle = int(cfg.get("USE_SHUFFLE", 0) or 0)
    padded_k = cfg.get("PADDED_K")
    if layout == RAW_LAYOUT:
        # K 不是 64 倍数时 _try_get_asm_config 会强制改查重排表并记录 PADDED_K
        ok = use_shuffle == 0 and padded_k is None
    else:
        # w4a16 的 gw32 解与布局无关，asm_shuffle 对它没有意义
        if problem.quant_kind == "w4a16":
            return False, cfg
        ok = True
    return ok, cfg


def _moe_c_usable(problem: FusedMoeProblem, layout: str):
    """moe_c 在该布局下能否**不再shuffle**直接执行。返回 (ok, params)。"""
    if not _moe_c_match(problem):
        return False, None
    kind = problem.quant_kind
    if kind in _MARLIN_REQUIRED_KINDS and layout != MARLIN_LAYOUT:
        return False, None
    if kind in ("w4a16", "wfp4a16") and layout != RAW_LAYOUT:
        return False, None
    params = _moe_c_lookup(_with_layout(problem, layout))
    if params is None:
        return False, None
    cfg = params.get("tuned_config") or {}
    # moe_c 的 w8a8_fp8 在 model_dim 不是 64 的倍数时要补 K，kernel侧补 K 的路径
    # 数值错误（cos 0.085），因此降级 raw，不放行 marlin。
    if kind == "w8a8" and problem.q_dtype_a == "fp8" and cfg.get("PADDED_K") is not None:
        return False, params
    return True, params


def _triton_usable(problem: FusedMoeProblem, layout: str):
    if layout != RAW_LAYOUT or not _triton_match(problem):
        return False, None
    cfg = _triton_lookup(problem)
    if cfg is not None:
        return True, cfg
    return _fallback_allowed(problem), None


def _ck_usable(problem: FusedMoeProblem, layout: str):
    if layout != RAW_LAYOUT or not _ck_match(problem):
        return False, None
    cfg = _ck_lookup(problem)
    return (cfg is not None), cfg


@functools.lru_cache(maxsize=1024)
def _feasible_layouts_keyed(problem: FusedMoeProblem) -> frozenset:
    # 可用性与 M 无关，键里先归一 M，提升命中率
    problem = replace(problem, M=1)
    _supported_order(problem)  # 不支持的家族在这里抛出既有错误
    layouts = set()
    for layout in (RAW_LAYOUT, ASM_SHUFFLE_LAYOUT):
        if _asm_usable(problem, layout)[0]:
            layouts.add(layout)
    for layout in (RAW_LAYOUT, MARLIN_LAYOUT):
        if _moe_c_usable(problem, layout)[0]:
            layouts.add(layout)
    if _triton_usable(problem, RAW_LAYOUT)[0]:
        layouts.add(RAW_LAYOUT)
    if _ck_usable(problem, RAW_LAYOUT)[0]:
        layouts.add(RAW_LAYOUT)
    return frozenset(layouts)


def feasible_layouts(problem: FusedMoeProblem) -> frozenset:
    """哪些布局下至少有一个后端无需重排即可服务这个形状（不含 M）。"""
    return _feasible_layouts_keyed(replace(problem, M=1))


# ---- asm 双表耗时 ----


def _asm_timing_table(problem: FusedMoeProblem, shuffled: bool):
    """取 asm 某张表的分组 -> [(token, time_us)]，没有该分组时返回 None。"""
    from aiter.fused_moe_asm_wna16 import (
        _cached_data_by_quant, load_and_cache_csv_for_quant)

    qname = _ASM_QUANT_NAME.get(
        (problem.quant_kind, "none" if problem.quant_kind == "none" else problem.q_dtype_a))
    if qname is None:
        return None
    model_dim = problem.model_dim
    if problem.quant_kind in ("w8a8", "w8a8_block") and model_dim % 64 != 0:
        # model_dim 不是 64 的倍数时强制查重排表，并使用补 K 后的 model_dim
        model_dim = ((model_dim + 63) // 64) * 64
        shuffled = True
    if not load_and_cache_csv_for_quant(qname, 1 if shuffled else 0):
        return None
    groups = _cached_data_by_quant.get(qname + ("_s" if shuffled else ""))
    if not groups:
        return None
    key = (str(problem.arch), int(problem.inter_dim), int(model_dim),
           int(problem.E), int(problem.topk), qname)
    entry = groups.get(key)
    if entry is None:
        return None
    tokens, _sol_ids, df = entry
    return list(zip(tokens.tolist(), df["time_us"].tolist()))


def _nearest_time(rows, token):
    tokens = [r[0] for r in rows]
    if token <= tokens[0]:
        return rows[0][1]
    if token >= tokens[-1]:
        return rows[-1][1]
    from bisect import bisect_left
    pos = bisect_left(tokens, token)
    if tokens[pos] == token:
        return rows[pos][1]
    left, right = pos - 1, pos
    return rows[left][1] if token - tokens[left] <= tokens[right] - token else rows[right][1]


def _asm_two_table_gain(problem: FusedMoeProblem, max_num_tokens=None):
    """asm 双表的加权收益：token 档位并集、逐档取最近行、等权求和。

    返回 (gain, n_tokens)；任一张表缺分组时返回 (None, 0) 表示无数据可比。
    """
    raw = _asm_timing_table(problem, shuffled=False)
    shf = _asm_timing_table(problem, shuffled=True)
    if raw is None or shf is None:
        return None, 0
    tokens = sorted({t for t, _ in raw} | {t for t, _ in shf})
    if max_num_tokens is not None:
        tokens = [t for t in tokens if t <= int(max_num_tokens)]
    if not tokens:
        return None, 0
    t_raw = sum(_nearest_time(raw, t) for t in tokens)
    t_shf = sum(_nearest_time(shf, t) for t in tokens)
    if not t_raw:
        return None, len(tokens)
    return (t_raw - t_shf) / t_raw, len(tokens)


def _asm_choice(problem: FusedMoeProblem, max_num_tokens=None):
    """asm 内部 raw / asm_shuffle 的选择（双表收益 + 家族例外）。

    返回 (layout, padded_k, reason, gain) 或 None。
    """
    raw_ok, _raw_cfg = _asm_usable(problem, RAW_LAYOUT)
    shf_ok, shf_cfg = _asm_usable(problem, ASM_SHUFFLE_LAYOUT)
    padded_k = int(shf_cfg["PADDED_K"]) if shf_cfg and shf_cfg.get("PADDED_K") else None
    if problem.quant_kind == "w4a16":
        # gw32 解与布局无关，权重重排没有意义
        return (RAW_LAYOUT, None, "w4a16 gw32 解与布局无关", None) if raw_ok else None
    if raw_ok and shf_ok:
        gain, n = _asm_two_table_gain(problem, max_num_tokens)
        if gain is None:
            return (ASM_SHUFFLE_LAYOUT, padded_k,
                    "双表无耗时数据可比，按候选顺序选重排表", None)
        verdict = "≥5%" if gain >= 0.05 else "<5%"
        layout = ASM_SHUFFLE_LAYOUT if gain >= 0.05 else RAW_LAYOUT
        return (layout, padded_k if layout == ASM_SHUFFLE_LAYOUT else None,
                f"双表加权收益 {gain * 100:.1f}% {verdict}（{n} 个 token 档位）",
                gain)
    if shf_ok:
        why = ("model_dim 不是 64 的倍数，asm 强制重排表" if padded_k
               else "仅重排表覆盖该形状")
        return ASM_SHUFFLE_LAYOUT, padded_k, why, None
    if raw_ok:
        return RAW_LAYOUT, None, "仅普通表覆盖该形状", None
    return None


def decide_layout(problem: FusedMoeProblem, backend="auto",
                  max_num_tokens=None) -> LayoutDecision:
    """一次性决定权重布局（加载期调用；不做任何重排）。"""
    _supported_order(problem)  # 不支持的家族在这里抛出
    feasible = feasible_layouts(problem)
    kind = problem.quant_kind
    orig_k = int(problem.model_dim)

    if backend != "auto" and backend not in BACKEND_REGISTRY:
        raise ValueError(
            f"decide_layout: unknown backend preference {backend!r} "
            f"(supported: 'auto', {sorted(BACKEND_REGISTRY)})")

    # is_ep / doweight_stage1 / splitk：只可能落到 triton（或直接无解）
    if problem.is_ep or problem.doweight_stage1 or problem.splitk:
        if _triton_usable(problem, RAW_LAYOUT)[0] and backend in ("auto", "triton"):
            return LayoutDecision(RAW_LAYOUT, "triton",
                                  "is_ep/doweight_stage1/splitk 仅 triton 可服务",
                                  feasible=feasible)
        raise NotImplementedError(
            f"decide_layout: no backend serves {kind} with "
            f"is_ep={problem.is_ep} doweight_stage1={problem.doweight_stage1} "
            f"splitk={problem.splitk}")

    # 不需要权重重排的家族
    if kind in ("w4a16", "w4a8"):
        if backend not in ("auto", "asm", "triton"):
            raise ValueError(f"decide_layout: {backend} cannot serve {kind}")
        family = None
        if backend in ("auto", "asm") and _asm_usable(problem, RAW_LAYOUT)[0]:
            family = "asm"
        elif _triton_usable(problem, RAW_LAYOUT)[0]:
            family = "triton"
        return LayoutDecision(RAW_LAYOUT, family, f"{kind} 权重不再shuffle",
                              original_k=orig_k, feasible=feasible)

    if kind == "wfp4a16":
        if backend not in ("auto", "moe_c"):
            raise ValueError(f"decide_layout: {backend} cannot serve {kind}")
        return LayoutDecision(RAW_LAYOUT, "moe_c", "moe_c 独占，fp4x2 原样消费",
                              original_k=orig_k, feasible=feasible)

    if kind == "wfp4a8":
        if backend not in ("auto", "moe_c"):
            raise ValueError(f"decide_layout: {backend} cannot serve {kind}")
        return LayoutDecision(MARLIN_LAYOUT, "moe_c", "moe_c 独占，逐专家布局重排",
                              original_k=orig_k, feasible=feasible)

    if kind == "w8a16":
        ok, _ = _moe_c_usable(problem, MARLIN_LAYOUT)
        if ok and backend in ("auto", "moe_c"):
            return LayoutDecision(MARLIN_LAYOUT, "moe_c", "moe_c 配置存在",
                                  original_k=orig_k, feasible=feasible)
        if backend == "moe_c":
            raise ValueError("decide_layout: backend=moe_c but no moe_c config "
                             f"for this {kind} shape")
        return LayoutDecision(RAW_LAYOUT, "triton", "moe_c 无配置，走 triton",
                              original_k=orig_k, feasible=feasible)

    # none / w8a8 / w8a8_block：先定 asm 内部布局
    asm_pick = _asm_choice(problem, max_num_tokens)
    asm_dec = None
    if asm_pick is not None and backend in ("auto", "asm"):
        layout, padded_k, reason, gain = asm_pick
        asm_dec = LayoutDecision(layout, "asm", reason, padded_k, orig_k,
                                 feasible, gain)

    if kind in ("none", "w8a8_block"):
        if backend == "asm" and asm_dec is None:
            raise ValueError(f"decide_layout: backend=asm cannot serve this {kind} shape")
        if backend == "moe_c":
            raise ValueError(f"decide_layout: backend=moe_c cannot serve {kind}")
        if asm_dec is not None:
            return asm_dec
        return LayoutDecision(RAW_LAYOUT, "triton",
                              "asm 无可直接消费的布局，走 triton",
                              original_k=orig_k, feasible=feasible)

    # w8a8：asm 内部选择后与 moe_c 比较（有耗时比耗时，否则按候选顺序 asm > moe_c）
    moe_c_ok, _ = _moe_c_usable(problem, MARLIN_LAYOUT)
    if backend == "moe_c" and not moe_c_ok:
        raise ValueError("decide_layout: backend=moe_c cannot serve this w8a8 shape "
                         "(no config, or fp8 with a non-64-aligned K)")
    if backend in ("auto", "moe_c") and moe_c_ok:
        if backend == "moe_c":
            return LayoutDecision(MARLIN_LAYOUT, "moe_c",
                                  "backend 偏好指定 moe_c",
                                  original_k=orig_k, feasible=feasible)
        if asm_dec is not None:
            asm_total, moe_total = _cross_backend_totals(
                problem, asm_dec.layout, max_num_tokens)
            if (asm_total is not None and moe_total is not None
                    and moe_total < asm_total):
                return LayoutDecision(MARLIN_LAYOUT, "moe_c",
                                      f"同档位总耗时 moe_c {moe_total:.1f} < "
                                      f"asm({asm_dec.layout}) {asm_total:.1f}",
                                      original_k=orig_k, feasible=feasible)
        else:
            return LayoutDecision(MARLIN_LAYOUT, "moe_c", "moe_c 配置存在",
                                  original_k=orig_k, feasible=feasible)
    if asm_dec is not None:
        return asm_dec
    if backend == "asm":
        raise ValueError("decide_layout: backend=asm cannot serve this w8a8 shape")
    return LayoutDecision(RAW_LAYOUT, "triton", "无 asm 配置，走 triton",
                          original_k=orig_k, feasible=feasible)


def _total_on_tokens(rows, tokens):
    return sum(_nearest_time(rows, t) for t in tokens)


_MOE_C_CHANNEL_CSV = {
    "int8": "tuned_moe_c_w8a8_int8_channel.csv",
    "fp8": "tuned_moe_c_w8a8_fp8_channel.csv",
}


def _moe_c_timing_rows(problem: FusedMoeProblem):
    """moe_c w8a8 通道 CSV 的同形状行 -> [(token, time_us)]（无则 None）。"""
    import csv

    name = _MOE_C_CHANNEL_CSV.get(problem.q_dtype_a)
    if name is None:
        return None
    path = os.path.join(AITER_ROOT_DIR, "aiter", "moe_c_configs", name)
    if not os.path.exists(path):
        return None
    quant = f"{problem.q_dtype_a}_w8a8_channel"
    indtype = ("torch.float16" if problem.dtype == "fp16" else "torch.bfloat16")
    rows = []
    with open(path, newline="") as fh:
        for row in csv.DictReader(fh):
            if (row["arch"] != problem.arch or row["quant_type"] != quant
                    or row["indtype"] != indtype
                    or int(row["inter_dim"]) != int(problem.inter_dim)
                    or int(row["model_dim"]) != int(problem.model_dim)
                    or int(row["expert"]) != int(problem.E)
                    or int(row["topk"] or 0) != int(problem.topk)):
                continue
            try:
                rows.append((int(row["token"]), float(row["time_us"])))
            except (TypeError, ValueError):
                continue
    if not rows:
        return None
    rows.sort()
    return rows


def _cross_backend_totals(problem: FusedMoeProblem, asm_layout: str,
                          max_num_tokens=None):
    """asm 选定布局与 moe_c 在**同一批 token 档位**上的总耗时。

    跨后端比较必须对齐档位集合：两表档位数不同时，直接比各自求和
    会被档位数差异带偏（实测 asm 178 档、moe_c 27 档）。
    """
    asm_rows = _asm_timing_table(problem, shuffled=(asm_layout == ASM_SHUFFLE_LAYOUT))
    moe_rows = _moe_c_timing_rows(problem)
    if asm_rows is None or moe_rows is None:
        return None, None
    tokens = sorted({t for t, _ in asm_rows} | {t for t, _ in moe_rows})
    if max_num_tokens is not None:
        tokens = [t for t in tokens if t <= int(max_num_tokens)]
    if not tokens:
        return None, None
    return _total_on_tokens(asm_rows, tokens), _total_on_tokens(moe_rows, tokens)


def _plan_from_route_table(problem: FusedMoeProblem) -> FusedMoePlan | None:
    """Use the backend recommended by the route table if it can run this
    problem. Return None if there is no table or row, the backend does not
    match, the weight layout is not directly usable, or it has no tuned config."""
    rec = _lookup_route_table(problem)
    if rec is None:
        return None
    name = rec[0]
    entry = BACKEND_REGISTRY.get(name)
    if entry is None or not entry.match(problem):
        return None
    params = entry.lookup(problem)
    if params is None:
        return None
    if not _layout_directly_usable(problem, name, params):
        return None
    routed = _build_plan(name, params, problem)
    if routed is not None and os.environ.get("FMOE_ROUTE_LOG"):
        print(f"ROUTE-TABLE use backend={name} token={problem.M} time_us={rec[1]}",
              flush=True)
    return routed


def _plan_from_candidates(problem: FusedMoeProblem, order: tuple) -> FusedMoePlan | None:
    """Return the first backend in `order` that matches, can consume the weight
    layout without shuffling, and has a tuned config."""
    for name in order:
        entry = BACKEND_REGISTRY[name]
        if not entry.match(problem):
            continue
        params = entry.lookup(problem)  # 查表内在布局不匹配时已弃权
        if params is None:
            continue  # matched, but no tuned config / layout not usable
        if not _layout_directly_usable(problem, name, params):
            continue
        routed = _build_plan(name, params, problem)
        if routed is not None:
            return routed
    return None


def _plan_from_fallback(problem: FusedMoeProblem) -> FusedMoePlan | None:
    """No tuned config anywhere: run triton with its default config and warn
    (see "Untuned-shape fallback" above). Return None if not allowed."""
    if not _fallback_allowed(problem):
        return None
    params = _triton_fallback_params(problem)
    if params is None:
        return None
    fallback = _build_plan("triton", params, problem)
    if fallback is None:
        return None
    _warn_triton_fallback(problem)
    if os.environ.get("FMOE_ROUTE_LOG"):
        print("ROUTE-FALLBACK use backend=triton(default-config)", flush=True)
    return fallback


def _no_backend_error(problem: FusedMoeProblem) -> NotImplementedError:
    message = (
        f"fused_moe routing: no backend covers this problem "
        f"(quant_kind={problem.quant_kind!r}, dtype={problem.dtype!r}, "
        f"q_dtype_a={problem.q_dtype_a!r}, q_dtype_w={problem.q_dtype_w!r}, "
        f"activation={problem.activation!r}, arch={problem.arch!r}, "
        f"weight_layout={problem.weight_layout!r})"
    )
    if problem.quant_kind == "a8w4":
        message += "\n" + _INT4_UNSUPPORTED_MSG
    elif problem.quant_kind in ("w4a16", "w4a8"):
        message += ("\nfused_moe: no tuned triton config for this int4 "
                    "shape and AITER_FMOE_TRITON_FALLBACK=strict is set")
    if problem.weight_layout == RAW_LAYOUT:
        try:
            feasible = feasible_layouts(problem)
        except NotImplementedError:
            feasible = frozenset()
        if any(lay != RAW_LAYOUT for lay in feasible):
            message += (
                "\nraw 权重不再有执行期重排兜底：请先调用 "
                "fused_moe_prepare_weights，由加载期一次性决定布局并完成重排，"
                "再把返回的 prepared 传给 fused_moe（prepared=...）。")
    if _FALLBACK_STRICT:
        message += (
            "\nAITER_FMOE_TRITON_FALLBACK=warn (the default) would run this "
            "shape on the boltops triton default config instead of raising."
        )
    return NotImplementedError(message)


def _bound_layout_error(problem: FusedMoeProblem, backend: str) -> NotImplementedError:
    """非 raw 布局短路后查不到绑定后端配置：报错，不换布局、不现场重排。"""
    return NotImplementedError(
        f"fused_moe routing: weight_layout={problem.weight_layout!r} is bound to "
        f"backend {backend!r}, which has no tuned config for this problem "
        f"(quant_kind={problem.quant_kind!r}, dtype={problem.dtype!r}, "
        f"q_dtype_a={problem.q_dtype_a!r}, activation={problem.activation!r}, "
        f"topk={problem.topk}, E={problem.E}, N={problem.inter_dim}, "
        f"K={problem.model_dim}, arch={problem.arch!r}). "
        "布局与调优配置不匹配：请检查准备时的 activation / topk / expert_mask / "
        "dtype 是否与运行期一致，或重新调用 fused_moe_prepare_weights。"
    )


def plan(problem: FusedMoeProblem) -> FusedMoePlan:
    """Route a normalized problem to a stage-level FusedMoePlan.

    Order: non-raw layout binding (short-circuit), route table recommendation,
    then the static candidate order, then the untuned-shape triton fallback.
    Raises NotImplementedError when no registered backend covers the problem
    (per_1x32 / MXFP families, a16w4, unsupported activations, ...).

    ``marlin`` / ``asm_shuffle`` 布局不进入路由表 / 候选链 / triton 兜底：
    绑定表命中时直接查绑定后端。查不到配置说明准备参数与运行参数不一致或
    配置数据损坏，报错优于静默换到别的后端；运行期可行布局复核在此之前已
    独立生效。
    """
    order = _supported_order(problem)
    bound = _LAYOUT_BACKEND_BINDING.get(problem.weight_layout)
    if bound is not None:
        entry = BACKEND_REGISTRY[bound]
        if entry.match(problem):
            params = entry.lookup(problem)
            if params is not None and _layout_directly_usable(problem, bound, params):
                routed = _build_plan(bound, params, problem)
                if routed is not None:
                    return routed
        raise _bound_layout_error(problem, bound)
    routed = _plan_from_route_table(problem)
    if routed is None:
        routed = _plan_from_candidates(problem, order)
    if routed is None:
        routed = _plan_from_fallback(problem)
    if routed is None:
        raise _no_backend_error(problem)
    return routed


def _build_plan(chosen: str, params: dict, problem: FusedMoeProblem) -> FusedMoePlan:
    if chosen in _STAGE_BACKENDS:
        return FusedMoePlan(
            stage1_backend=chosen,
            stage2_backend=chosen,
            block_m=int(params.get("BLOCK_SIZE_M", params.get("block_m", 32))),
            act_op=1 if problem.activation == "silu" else 0,
            sol_id1=params.get("SOL_ID1", params.get("sol_id")),
            sol_id2=params.get("SOL_ID2", params.get("sol_id")),
            mode=int(params.get("mode", 0)),
            use_shuffle=int(problem.use_shuffle),
            flat=False,
            extra=dict(params),
        )
    if chosen in _CHAIN_BACKENDS:
        chain_keys = (
            "use_int4_w4a16", "use_int8_w8a16", "use_fp8_w8a8", "use_int8_w8a8",
            "use_int4_w4a8", "use_int8_w4a8", "use_fp4_w4a16", "use_fp4_w4a8",
            "per_channel_quant", "block_shape", "tuned_config",
            "triton_cfg", "fallback",
        )
        return FusedMoePlan(
            stage1_backend=None,
            stage2_backend=None,
            chained_backend=chosen,
            act_op=1 if problem.activation == "silu" else 0,
            mode=0,
            use_shuffle=int(problem.use_shuffle),
            flat=False,
            extra={k: v for k, v in params.items() if k in chain_keys},
        )
    return None
