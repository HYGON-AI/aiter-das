# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
 
import torch
import torch.nn.functional as F
from einops import rearrange
import os
from typing import Optional
import functools
import aiter
from aiter import ActivationType, QuantType, dtypes

# from aiter import get_hip_quant as get_quant
# from aiter import get_torch_quant as get_quant
from aiter import get_triton_quant as get_quant
from aiter.jit.core import AITER_ROOT_DIR, PY, get_asm_dir, bd_dir, mp_lock
from aiter.jit.utils.chip_info import get_cu_num, get_gfx
from aiter.jit.utils.torch_guard import torch_compile_guard
from aiter import pertoken_quant, ck_moe
from aiter.fused_moe_router import (
    BACKEND_REGISTRY,
    FusedMoeExecContext,
    FusedMoeProblem,
    plan as _route_plan,
)
from aiter.fused_moe_layout import resolve_weight_layout
from aiter.fused_moe_types import GateMode, Stage2ScatterContext, SUPPORTED_ACTIVATIONS

BLOCK_SIZE_M = 32


def moe_sorting(
    topk_ids,
    topk_weights,
    num_experts,
    model_dim,
    moebuf_dtype,
    block_size=BLOCK_SIZE_M,
    expert_mask=None,
):
    device = topk_ids.device
    M, topk = topk_ids.shape
    max_num_tokens_padded = topk_ids.numel() + num_experts * block_size - topk
    max_num_m_blocks = int((max_num_tokens_padded + block_size - 1) // block_size)
    sorted_ids = torch.empty((max_num_tokens_padded,), dtype=dtypes.i32, device=device)
    sorted_weights = torch.empty(
        (max_num_tokens_padded,), dtype=dtypes.fp32, device=device
    )
    sorted_expert_ids = torch.empty(
        (max_num_m_blocks,), dtype=dtypes.i32, device=device
    )
    tokens_positions_per_expert = torch.empty(
        (num_experts*2,), dtype=dtypes.i32, device=device
    )
    num_valid_ids = torch.empty((1), dtype=dtypes.i32, device=device)
    moe_buf = torch.empty((M, model_dim), dtype=moebuf_dtype, device=device)

    # for now, moe_sorting_fwd only support int32 topk_ids
    if topk_ids.dtype != dtypes.i32:
        topk_ids = topk_ids.to(dtypes.i32)

    aiter.moe_sorting_fwd(
        topk_ids,
        topk_weights,
        sorted_ids,
        sorted_weights,
        sorted_expert_ids,
        tokens_positions_per_expert,
        num_valid_ids,
        moe_buf,
        num_experts,
        block_size,
        expert_mask,
    )
    return sorted_ids, sorted_weights, sorted_expert_ids, num_valid_ids, tokens_positions_per_expert, moe_buf


@functools.lru_cache(maxsize=1024)
def get_inter_dim(w1_shape, w2_shape):
    E, _, model_dim = w1_shape
    E, model_dim, inter_dim = w2_shape

    int4_war = model_dim // w1_shape[-1]
    inter_dim *= int4_war
    return E, model_dim, inter_dim


def _enum_name(value, enum_cls=None) -> str:
    """pybind11 enum / int / str -> lower-case name string.

    The torch.compile guard passes enum values through as plain ints (schema
    annotation), so int codes are mapped back through the pybind enum class
    (csrc/include/aiter_enum.h).
    """
    name = getattr(value, "name", None)
    if name is not None:
        return str(name).lower()
    if enum_cls is not None and isinstance(value, int):
        try:
            return str(enum_cls(value).name).lower()
        except Exception:
            return str(value).lower()
    return str(value).lower()


_DTYPE_KIND = {
    torch.bfloat16: "bf16",
    torch.float16: "fp16",
    torch.float32: "fp32",
    torch.float8_e4m3fn: "fp8",
    torch.float8_e5m2: "fp8",
    torch.int8: "int8",
    torch.uint8: "int4",  # int4 packed, 2 nibbles per byte (host w4a16 container)
    torch.uint32: "int4",  # int4 packed, 8 nibbles per word
    torch.int32: "int4",
}


def _infer_w4_group(w1_scale, model_dim):
    """w4 族 group size from a [E, N, K//group] scale tensor.
    Returns None when not inferable (no scale / non-3D / indivisible)."""
    if w1_scale is None or w1_scale.dim() != 3:
        return None
    last = int(w1_scale.shape[-1])
    if last <= 0 or model_dim % last != 0:
        return None
    return model_dim // last


# Quant families fused_moe routes. Everything else (a4w4 / a16w4 /
# MXFP8 / ...) is rejected and handled by aiter_moe.
_SUPPORTED_KINDS = ("none", "w8a8", "w8a8_block", "w4a8", "a8w4", "w4a16", "w8a16",
                    "wfp4a16", "wfp4a8")


def _normalize_problem(
    hidden_states,
    w1,
    w2,
    topk_ids,
    expert_mask,
    activation,
    quant_type,
    quant_type_a,
    quant_dtype_a,
    block_size_M,
    doweight_stage1,
    splitk,
    w1_scale=None,
    w2_scale=None,
    w1_zp=None,
    w2_zp=None,
    routed_scaling_factor=1.0,
    gemm1_alpha=None,
    gemm1_limit=None,
    *,
    model_dim=None,
    M=None,
    topk=None,
    dtype=None,
    weight_layout=None,
):
    """Normalize the fused_moe arguments into a torch-free routing problem.

    Stored-vs-real inter_dim handling mirrors the aiter_moe callers; the asm
    CSV lookup keys must match the per-branch conventions.

    Keyword-only ``model_dim`` / ``M`` / ``topk`` / ``dtype`` let the weight
    preparation API reuse this derivation without activation tensors.
    """
    if (w1_zp is None) != (w2_zp is None):
        raise ValueError(
            "fused_moe: w1_zp and w2_zp must be provided together "
            f"(got w1_zp={'None' if w1_zp is None else 'tensor'}, "
            f"w2_zp={'None' if w2_zp is None else 'tensor'})")
    act_dtype = dtype if dtype is not None else (
        hidden_states.dtype if hidden_states is not None else None)
    if act_dtype is None:
        raise ValueError(
            "fused_moe: dtype is required when hidden_states is not provided")
    dtype_str = _DTYPE_KIND.get(act_dtype)
    if dtype_str not in ("bf16", "fp16"):
        raise NotImplementedError(
            f"fused_moe: unsupported activation dtype {act_dtype}"
        )
    q_dtype_w_kind = _DTYPE_KIND.get(w1.dtype)  # raw: bf16/fp16/fp8/int8/int4
    if q_dtype_w_kind is None:
        raise NotImplementedError(
            f"fused_moe: unsupported weight dtype {w1.dtype}"
        )
    # router semantics: 'none' | 'fp8' | 'int8' | 'int4'
    q_dtype_w = q_dtype_w_kind if q_dtype_w_kind in ("fp8", "int8", "int4") else "none"
    q_dtype_a = q_dtype_w_kind if q_dtype_w_kind in ("fp8", "int8") else "none"
    if quant_dtype_a is not None:
        kind = _DTYPE_KIND.get(quant_dtype_a)
        if kind in ("fp8", "int8"):
            q_dtype_a = kind
        elif kind not in ("bf16", "fp16", None):
            raise NotImplementedError(
                f"fused_moe: unsupported quant_dtype_a {quant_dtype_a}"
            )

    quant_str = _enum_name(quant_type, QuantType)
    if quant_type_a is not None:
        # activation-side quant type override stays scheduling-level for now
        quant_str = _enum_name(quant_type_a, QuantType)

    # Read the weight layout marker before inferring the quant family.
    # Unmarked tensors are "raw". w1 and w2 must carry the same marker.
    # use_shuffle means the weights are already in the asm shuffle layout; the
    # router then skips backends that cannot use it and _asm_lookup picks the
    # shuffle CSV. An explicit ``weight_layout`` argument wins over the marker
    # and is cross-checked against it.
    weight_layout = resolve_weight_layout(w1, w2, weight_layout)
    # marlin uint8 tensors come in two flavors: w8a16 marlin is a pure reorder
    # (unpacked geometry, w1.shape[1] == 2 * w2.shape[2]) while w4a16/w4a8
    # marlin keeps the packed-int4 geometry (w1.shape[1] != 2 * w2.shape[2]).
    # Only the w8a16 flavor may be reinterpreted as int8 weights.
    _marlin_w8a16_geom = (weight_layout == "marlin"
                          and w1.shape[1] == 2 * w2.shape[2])
    # The w8a16 marlin packer returns its reordered output viewed as uint8,
    # which dtype inference would read as packed int4. For quant_type=No the
    # marker decides: marlin means int8 weights (w8a16). Marlin w8a8 keeps its
    # int8/fp8 dtypes, so it needs no override.
    if (_marlin_w8a16_geom and quant_str == "no" and q_dtype_w == "int4"):
        q_dtype_w_kind = "int8"
        q_dtype_w = "int8"

    if quant_str == "per_1x32":
        # fp4x2 packed weights arrive as uint8 (the dtype fallback maps them
        # there), the same container as int4 nibbles: per_1x32 is the only
        # discriminator.
        if q_dtype_w != "int4":
            raise NotImplementedError(
                f"fused_moe: per_1x32 requires fp4x2 packed weights, "
                f"got w1.dtype={w1.dtype}")
        quant_kind = "wfp4a8" if q_dtype_a in ("int8", "fp8") else "wfp4a16"
        q_dtype_w = "int4"  # 保持 router 侧 q_dtype_w 口径（int4 容器）

    elif quant_str == "no":
        if q_dtype_w == "none":
            quant_kind = "none"
        elif q_dtype_w == "int4":
            quant_kind, q_dtype_a = "w4a16", "none"
        elif q_dtype_w == "int8":
            quant_kind, q_dtype_a = "w8a16", "none"
        else:
            raise NotImplementedError(
                f"fused_moe: fp8 weights require an activation quant_type, "
                f"got quant_type=No with w1.dtype={w1.dtype}"
            )
    elif quant_str in ("per_tensor", "per_token"):
        if q_dtype_w in ("fp8", "int8"):
            quant_kind = "w8a8"
            if q_dtype_a == "none":
                q_dtype_a = q_dtype_w
        elif q_dtype_w == "int4":
            if q_dtype_a == "none":
                raise NotImplementedError(
                    "fused_moe: int4 weights with per_token/per_tensor require "
                    "quant_dtype_a=int8 (w4a8) or float8 (a8w4)"
                )
            quant_kind = "w4a8" if q_dtype_a == "int8" else "a8w4"
        else:
            raise NotImplementedError(
                f"fused_moe: unsupported combination quant_type={quant_str}, "
                f"w1.dtype={w1.dtype}"
            )
    elif quant_str in ("per_1x128", "per_128x128"):
        if q_dtype_w not in ("fp8", "int8"):
            raise NotImplementedError(
                f"fused_moe: blockwise quant requires fp8/int8 weights, "
                f"got {w1.dtype}"
            )
        quant_kind = "w8a8_block"
        q_dtype_a = q_dtype_w
    else:
        raise NotImplementedError(
            f"fused_moe: unsupported quant_type {quant_str} (a16w4 / MXFP8 and "
            f"other families are handled by aiter_moe)"
        )
    if quant_kind not in _SUPPORTED_KINDS:
        raise NotImplementedError(f"fused_moe: unsupported quant family {quant_kind}")

    act_str = _enum_name(activation, ActivationType)
    # Whitelist matches the aiter_moe activation set; per-backend acceptance
    # is narrowed further by the router (_activation_ok). Gated/non-gated
    # inference remains shape-based (problem.g1u1 below).
    if act_str not in SUPPORTED_ACTIVATIONS:
        raise NotImplementedError(
            f"fused_moe: unsupported activation {act_str} for the current backends"
        )

    if M is not None and topk is not None:
        M, topk = int(M), int(topk)
    else:
        M, topk = topk_ids.shape
    E = expert_mask.numel() if expert_mask is not None else w1.shape[0]
    explicit_model_dim = model_dim is not None
    if not explicit_model_dim:
        if hidden_states is None:
            model_dim = None  # 权重形状兜底（packed_mul 计算之后补）
        else:
            model_dim = hidden_states.shape[1]
    if w1.dtype == torch.uint8 and weight_layout == "marlin" and _marlin_w8a16_geom:
        packed_mul = 1  # marlin w8a16 uint8 view only reorders; element count
                        # and shapes are unchanged
    elif w1.dtype == torch.uint8:
        packed_mul = 2  # int4 packed, 2 nibbles per byte
    elif w1.dtype in (torch.uint32, torch.int32):
        packed_mul = 8  # int4 packed, 8 nibbles per word
    else:
        packed_mul = 1
    if model_dim is None:
        # 无激活张量时按权重形状推导真实 K（int4 容器按 packed_mul 还原）
        model_dim = int(w1.shape[2]) * packed_mul
    model_dim = int(model_dim)
    inter_dim = w2.shape[2] * packed_mul
    is_g1u1 = w1.shape[1] == 2 * w2.shape[2] * packed_mul or (
        w1.shape[1] * packed_mul == 2 * w2.shape[2]
    )
    # blockwise families (DeepSeek-style): 128x128 weight blocks / 1x128 activation
    # groups, whichever of the two enum names the caller used
    block_shape = (128, 128) if quant_str in ("per_1x128", "per_128x128") else None

    # w4 族 group 推断：per-channel scale [E,N,1] -> group == model_dim
    # -> channelwise (None)；groupwise scale [E,N,K//g] -> (0, g)。仅 int4/fp4 四族生效。
    if quant_kind in ("w4a16", "w4a8", "wfp4a16", "wfp4a8") and block_shape is None:
        _g = _infer_w4_group(w1_scale, model_dim)
        block_shape = None if _g is None or _g == model_dim else (0, _g)

    # Reject shapes no backend can serve, before routing.
    if quant_kind == "w4a16" and block_shape not in (None, (0, 32)):
        raise NotImplementedError(
            f"fused_moe: w4a16 supports group_size=32 only "
            f"(inferred group={block_shape[1]}); use aiter_moe for other groups")
    if quant_kind == "w4a8" and block_shape is not None:
        raise NotImplementedError(
            "fused_moe: w4a8 supports channelwise scales only "
            f"(inferred block_shape={block_shape}); use aiter_moe for groupwise w4a8")

    return FusedMoeProblem(
        arch=get_gfx(),
        M=int(M),
        topk=int(topk),
        E=int(E),
        model_dim=int(model_dim),
        inter_dim=int(inter_dim),
        dtype=dtype_str,
        q_dtype_a=q_dtype_a,
        q_dtype_w=q_dtype_w,
        quant_kind=quant_kind,
        quant_type=quant_str,
        block_shape=block_shape,
        g1u1=is_g1u1,
        activation=act_str,
        doweight_stage1=bool(doweight_stage1),
        use_shuffle=1 if weight_layout == "asm_shuffle" else 0,
        weight_layout=weight_layout,
        is_ep=expert_mask is not None,
        splitk=int(splitk or 0),
        block_size_M=int(block_size_M) if block_size_M else None,
        local_E=int(w1.shape[0]),
        has_zp=(w1_zp is not None and w2_zp is not None),
    )


def fused_moe(
    hidden_states,
    w1,  # [expert(local_expert:EP), inter_dim*2, dim] N,K
    w2,  # [expert(local_expert:EP), dim, inter_dim]
    topk_weight,
    topk_ids,
    expert_mask=None,  # EP
    activation=ActivationType.Silu,
    quant_type=QuantType.No,
    doweight_stage1=False,
    # following for quant
    w1_scale=None,  # [expert(local_expert:EP), inter_dim, 1]
    w2_scale=None,  # [expert(local_expert:EP), model_dim, 1]
    a1_scale=None,  # [expert(local_expert:EP), 1, model_dim]
    a2_scale=None,  # [expert(local_expert:EP), 1, inter_dim]
    # following for tuning
    block_size_M=None,
    num_local_tokens=None,
    moe_sorting_dispatch_policy=0,
    dtype=None,
    hidden_pad=0,
    intermediate_pad=0,
    bias1=None,
    bias2=None,
    splitk=0,
    swiglu_limit=None,
    beta=None,
    linear_beta=None,
    gate_mode=GateMode.SEPARATED,
    shared_w1=None,
    shared_w2=None,
    shared_w1_scale=None,
    shared_w2_scale=None,
    shared_expert_id=-1,
    stage2_scatter: Stage2ScatterContext | None = None,
    output=None,
    quant_type_a=None,
    quant_dtype_a=None,
    quant_dtype_a2=None,
    w1_zp=None,
    w2_zp=None,
    routed_scaling_factor=1.0,
    gemm1_alpha=None,
    gemm1_limit=None,
    weight_layout=None,
):
    """Public fused_moe entry. Dispatches to an aiter backend chosen by the
    stage-level router. Unsupported features raise NotImplementedError instead
    of silently degrading.

    ``weight_layout``: 准备函数返回的布局（raw / asm_shuffle / marlin）。
    为 None 时回退读取张量属性；两者都在时由 resolve_weight_layout 交叉校验。
    """
    if (
        any(
            t is not None
            for t in (shared_w1, shared_w2, shared_w1_scale, shared_w2_scale)
        )
        or shared_expert_id != -1
    ):
        raise NotImplementedError(
            "fused_moe: shared-expert fusion (shared_w1/shared_w2/...) is not "
            "supported; merge shared experts "
            "into the routed expert set in the caller, as the op_tests do"
        )
    if doweight_stage1:
        raise NotImplementedError(
            "fused_moe: doweight_stage1=True is not supported because the "
            "1-stage kernel backends are not available"
        )
    if gate_mode is not None and GateMode(gate_mode) != GateMode.SEPARATED:
        raise NotImplementedError(
            f"fused_moe: only GateMode.SEPARATED is supported, got {gate_mode!r}"
        )
    if stage2_scatter is not None:
        raise NotImplementedError(
            "fused_moe: stage2_scatter (EP arena scatter) has no aiter backend"
        )
    if hidden_pad or intermediate_pad:
        raise NotImplementedError("fused_moe: hidden_pad/intermediate_pad unsupported")
    if bias1 is not None or bias2 is not None:
        raise NotImplementedError("fused_moe: bias1/bias2 unsupported")
    if swiglu_limit is not None or beta is not None or linear_beta is not None:
        raise NotImplementedError(
            "fused_moe: swiglu_limit/beta/linear_beta unsupported by the "
            "current backends"
        )

    return fused_moe_(
        hidden_states=hidden_states,
        w1=w1,
        w2=w2,
        topk_weight=topk_weight,
        topk_ids=topk_ids,
        expert_mask=expert_mask,
        # The op schema binds activation as str (the 7-string aiter_moe path;
        # the 4-member ActivationType enum cannot represent gelu_tanh / situ /
        # swigluoai / swiglustep / relu2). _enum_name accepts the enum default,
        # int codes and plain strings alike.
        activation=_enum_name(activation, ActivationType),
        quant_type=quant_type.value if hasattr(quant_type, "value") else quant_type,
        doweight_stage1=doweight_stage1,
        w1_scale=w1_scale,
        w2_scale=w2_scale,
        a1_scale=a1_scale,
        a2_scale=a2_scale,
        block_size_M=block_size_M,
        num_local_tokens=num_local_tokens,
        moe_sorting_dispatch_policy=moe_sorting_dispatch_policy,
        dtype=dtype,
        hidden_pad=hidden_pad,
        intermediate_pad=intermediate_pad,
        bias1=bias1,
        bias2=bias2,
        splitk=splitk,
        swiglu_limit=swiglu_limit,
        beta=beta,
        linear_beta=linear_beta,
        gate_mode=(
            GateMode(gate_mode).value if gate_mode is not None else GateMode.SEPARATED.value
        ),
        shared_w1=shared_w1,
        shared_w2=shared_w2,
        shared_w1_scale=shared_w1_scale,
        shared_w2_scale=shared_w2_scale,
        shared_expert_id=shared_expert_id,
        output=output,
        quant_type_a=(
            quant_type_a.value if hasattr(quant_type_a, "value") else quant_type_a
        ),
        quant_dtype_a=quant_dtype_a,
        quant_dtype_a2=quant_dtype_a2,
        w1_zp=w1_zp,
        w2_zp=w2_zp,
        routed_scaling_factor=routed_scaling_factor,
        gemm1_alpha=gemm1_alpha,
        gemm1_limit=gemm1_limit,
        weight_layout=weight_layout,
    )


def _per_tensor_to_channel_scale(scale, E, N, name):
    """QuantType.per_Tensor carries ONE weight scale per expert ((E,), (E, 1) or
    (E, 1, 1) -- test_moe_2stage.py builds (E, 1)); every w8a8 backend reads a
    scale per output channel ([E, N, 1]). Handing the raw per-tensor scale to
    those kernels reads past the buffer (wrong results / VMFault), so broadcast
    it here once. A scale that is already per-channel passes through."""
    if scale is None:
        raise ValueError(f"fused_moe: quant_type=per_Tensor requires {name}")
    if scale.numel() == E * N:
        return scale.reshape(E, N, 1)
    if scale.numel() in (1, E):
        return scale.reshape(-1, 1, 1).expand(E, N, 1).contiguous()
    raise ValueError(
        f"fused_moe: {name} has {scale.numel()} elements, expected one per "
        f"expert ({E}) for per_Tensor or one per output channel ({E * N})"
    )


def _check_output(output, M, model_dim, out_dtype, device):
    """`output=` contract shared by the eager path and the torch.compile fake:
    a contiguous (M, model_dim) tensor of the output dtype on the activation
    device. Raising up front keeps eager and traced behavior identical."""
    if (
        tuple(output.shape) != (M, model_dim)
        or output.dtype != out_dtype
        or output.device != device
        or not output.is_contiguous()
    ):
        raise RuntimeError(
            f"output mismatch: got shape={tuple(output.shape)} "
            f"dtype={output.dtype} device={output.device} "
            f"contiguous={output.is_contiguous()}, expected a contiguous "
            f"{(M, model_dim)} {out_dtype} tensor on {device}"
        )


def fused_moe_fake(
    hidden_states: torch.Tensor,
    w1: torch.Tensor,
    w2: torch.Tensor,
    topk_weight: torch.Tensor,
    topk_ids: torch.Tensor,
    expert_mask: torch.Tensor | None = None,
    activation: str = "silu",
    quant_type: int = QuantType.No.value,
    doweight_stage1: bool = False,
    w1_scale: torch.Tensor | None = None,
    w2_scale: torch.Tensor | None = None,
    a1_scale: torch.Tensor | None = None,
    a2_scale: torch.Tensor | None = None,
    block_size_M: int | None = None,
    num_local_tokens: torch.Tensor | None = None,
    moe_sorting_dispatch_policy: int = 0,
    dtype: torch.dtype | None = None,
    hidden_pad: int = 0,
    intermediate_pad: int = 0,
    bias1: torch.Tensor | None = None,
    bias2: torch.Tensor | None = None,
    splitk: int = 0,
    swiglu_limit: float | None = None,
    beta: float | None = None,
    linear_beta: float | None = None,
    gate_mode: str = GateMode.SEPARATED.value,
    shared_w1: torch.Tensor | None = None,
    shared_w2: torch.Tensor | None = None,
    shared_w1_scale: torch.Tensor | None = None,
    shared_w2_scale: torch.Tensor | None = None,
    shared_expert_id: int = -1,
    output: torch.Tensor | None = None,
    quant_type_a: int | None = None,
    quant_dtype_a: torch.dtype | None = None,
    quant_dtype_a2: torch.dtype | None = None,
    w1_zp: torch.Tensor | None = None,
    w2_zp: torch.Tensor | None = None,
    routed_scaling_factor: float = 1.0,
    gemm1_alpha: float | None = None,
    gemm1_limit: float | None = None,
    weight_layout: str | None = None,
) -> torch.Tensor:
    M, _topk = topk_ids.shape
    out_dtype = dtype if dtype is not None else hidden_states.dtype
    model_dim = w2.shape[1]
    if output is not None:
        _check_output(output, M, model_dim, out_dtype, hidden_states.device)
        return output
    return torch.empty((M, model_dim), dtype=out_dtype, device=topk_ids.device)


@torch_compile_guard(gen_fake=fused_moe_fake)
def fused_moe_(
    hidden_states: torch.Tensor,
    w1: torch.Tensor,
    w2: torch.Tensor,
    topk_weight: torch.Tensor,
    topk_ids: torch.Tensor,
    expert_mask: torch.Tensor | None = None,
    activation: str = "silu",
    quant_type: int = QuantType.No.value,
    doweight_stage1: bool = False,
    w1_scale: torch.Tensor | None = None,
    w2_scale: torch.Tensor | None = None,
    a1_scale: torch.Tensor | None = None,
    a2_scale: torch.Tensor | None = None,
    block_size_M: int | None = None,
    num_local_tokens: torch.Tensor | None = None,
    moe_sorting_dispatch_policy: int = 0,
    dtype: torch.dtype | None = None,
    hidden_pad: int = 0,
    intermediate_pad: int = 0,
    bias1: torch.Tensor | None = None,
    bias2: torch.Tensor | None = None,
    splitk: int = 0,
    swiglu_limit: float | None = None,
    beta: float | None = None,
    linear_beta: float | None = None,
    gate_mode: str = GateMode.SEPARATED.value,
    shared_w1: torch.Tensor | None = None,
    shared_w2: torch.Tensor | None = None,
    shared_w1_scale: torch.Tensor | None = None,
    shared_w2_scale: torch.Tensor | None = None,
    shared_expert_id: int = -1,
    output: torch.Tensor | None = None,
    quant_type_a: int | None = None,
    quant_dtype_a: torch.dtype | None = None,
    quant_dtype_a2: torch.dtype | None = None,
    w1_zp: torch.Tensor | None = None,
    w2_zp: torch.Tensor | None = None,
    routed_scaling_factor: float = 1.0,
    gemm1_alpha: float | None = None,
    gemm1_limit: float | None = None,
    weight_layout: str | None = None,
) -> torch.Tensor:
    return _fused_moe_impl(
        hidden_states=hidden_states,
        w1=w1,
        w2=w2,
        topk_weight=topk_weight,
        topk_ids=topk_ids,
        expert_mask=expert_mask,
        activation=activation,
        quant_type=quant_type,
        doweight_stage1=doweight_stage1,
        w1_scale=w1_scale,
        w2_scale=w2_scale,
        a1_scale=a1_scale,
        a2_scale=a2_scale,
        block_size_M=block_size_M,
        num_local_tokens=num_local_tokens,
        moe_sorting_dispatch_policy=moe_sorting_dispatch_policy,
        dtype=dtype,
        hidden_pad=hidden_pad,
        intermediate_pad=intermediate_pad,
        bias1=bias1,
        bias2=bias2,
        splitk=splitk,
        swiglu_limit=swiglu_limit,
        beta=beta,
        linear_beta=linear_beta,
        gate_mode=gate_mode,
        shared_w1=shared_w1,
        shared_w2=shared_w2,
        shared_w1_scale=shared_w1_scale,
        shared_w2_scale=shared_w2_scale,
        shared_expert_id=shared_expert_id,
        output=output,
        quant_type_a=quant_type_a,
        quant_dtype_a=quant_dtype_a,
        quant_dtype_a2=quant_dtype_a2,
        w1_zp=w1_zp,
        w2_zp=w2_zp,
        routed_scaling_factor=routed_scaling_factor,
        gemm1_alpha=gemm1_alpha,
        gemm1_limit=gemm1_limit,
        weight_layout=weight_layout,
    )


# 运行期可行布局复核：传入布局不在可行集合内一律报错。
def _check_runtime_layout(problem) -> None:
    from aiter.fused_moe_router import feasible_layouts

    try:
        feasible = feasible_layouts(problem)
    except NotImplementedError:
        return  # 家族本身不可路由：交给 plan() 抛既有错误
    if problem.weight_layout in feasible:
        return
    raise ValueError(
        f"fused_moe: weight_layout={problem.weight_layout!r} is not directly "
        f"usable for this problem (quant_kind={problem.quant_kind!r}, "
        f"activation={problem.activation!r}, topk={problem.topk}, "
        f"E={problem.E}, N={problem.inter_dim}, K={problem.model_dim}, "
        f"dtype={problem.dtype!r}, is_ep={problem.is_ep}); "
        f"feasible layouts: {sorted(feasible)}. Check that activation / topk / "
        f"expert_mask / dtype match the values used at preparation time, or call "
        f"fused_moe_prepare_weights again."
    )


def _fused_moe_impl(
    hidden_states,
    w1,
    w2,
    topk_weight,
    topk_ids,
    expert_mask=None,
    activation=ActivationType.Silu.value,
    quant_type=QuantType.No.value,
    doweight_stage1=False,
    w1_scale=None,
    w2_scale=None,
    a1_scale=None,
    a2_scale=None,
    block_size_M=None,
    num_local_tokens=None,
    moe_sorting_dispatch_policy=0,
    dtype=None,
    hidden_pad=0,
    intermediate_pad=0,
    bias1=None,
    bias2=None,
    splitk=0,
    swiglu_limit=None,
    beta=None,
    linear_beta=None,
    gate_mode=GateMode.SEPARATED.value,
    shared_w1=None,
    shared_w2=None,
    shared_w1_scale=None,
    shared_w2_scale=None,
    shared_expert_id=-1,
    stage2_scatter=None,
    output=None,
    quant_type_a=None,
    quant_dtype_a=None,
    quant_dtype_a2=None,
    w1_zp=None,
    w2_zp=None,
    routed_scaling_factor=1.0,
    gemm1_alpha=None,
    gemm1_limit=None,
    weight_layout=None,
):
    """Core dispatch: normalize -> route -> execute. Backends are reached
    through BACKEND_REGISTRY entries, so there are no per-backend branches here."""
    out_dtype = dtype if dtype is not None else hidden_states.dtype
    if output is not None:
        _check_output(
            output, topk_ids.shape[0], w2.shape[1], out_dtype, hidden_states.device
        )
    problem = _normalize_problem(
        hidden_states=hidden_states,
        w1=w1,
        w2=w2,
        topk_ids=topk_ids,
        expert_mask=expert_mask,
        activation=activation,
        quant_type=quant_type,
        quant_type_a=quant_type_a,
        quant_dtype_a=quant_dtype_a,
        block_size_M=block_size_M,
        doweight_stage1=doweight_stage1,
        splitk=splitk,
        w1_scale=w1_scale,
        w2_scale=w2_scale,
        w1_zp=w1_zp,
        w2_zp=w2_zp,
        routed_scaling_factor=routed_scaling_factor,
        gemm1_alpha=gemm1_alpha,
        gemm1_limit=gemm1_limit,
        weight_layout=weight_layout,
    )
    _check_runtime_layout(problem)
    if problem.quant_kind == "w8a8" and problem.quant_type == "per_tensor":
        w1_scale = _per_tensor_to_channel_scale(w1_scale, w1.shape[0], w1.shape[1], "w1_scale")
        w2_scale = _per_tensor_to_channel_scale(w2_scale, w2.shape[0], w2.shape[1], "w2_scale")
    moe_plan = _route_plan(problem)
    if (
        moe_plan.stage1_backend is not None
        and moe_plan.stage1_backend != moe_plan.stage2_backend
    ):
        raise NotImplementedError(
            "fused_moe: heterogeneous stage mix "
            f"({moe_plan.stage1_backend}+{moe_plan.stage2_backend}) is "
            "expressible in the plan but has no executor yet"
        )
    entry = BACKEND_REGISTRY[moe_plan.chained_backend or moe_plan.stage1_backend]
    ctx = FusedMoeExecContext(
        hidden_states=hidden_states,
        w1=w1,
        w2=w2,
        topk_weight=topk_weight,
        topk_ids=topk_ids,
        expert_mask=expert_mask,
        activation=activation,
        quant_type=quant_type,
        dtype=dtype,
        output=output,
        w1_scale=w1_scale,
        w2_scale=w2_scale,
        a1_scale=a1_scale,
        a2_scale=a2_scale,
        w1_zp=w1_zp,
        w2_zp=w2_zp,
        # None normalizes to 1.0 (same as aiter_moe).
        routed_scaling_factor=(
            1.0 if routed_scaling_factor is None else routed_scaling_factor
        ),
        gemm1_alpha=gemm1_alpha,
        gemm1_limit=gemm1_limit,
        num_local_tokens=num_local_tokens,
        plan=moe_plan,
        problem=problem,
    )
    ret = entry.execute(ctx)

    if ret.dtype != out_dtype:
        ret = ret.to(out_dtype)
    if output is not None:
        return output.copy_(ret.view(output.shape))
    return ret


def fused_moe_1stage(
    hidden_states,
    w1,  # [expert(local_expert:EP), inter_dim*2, dim] N,K
    w2,  # [expert(local_expert:EP), dim, inter_dim]
    topk,
    sorted_ids,
    sorted_weights,
    sorted_expert_ids,
    num_valid_ids,
    moe_buf,
    isG1U1,
    block_size_M=32,
    activation=ActivationType.Silu,
    quant_type=QuantType.No,
    # following for quant
    q_dtype_a=None,
    q_dtype_w=None,
    w1_scale=None,  # [expert(local_expert:EP), inter_dim, 1]
    w2_scale=None,  # [expert(local_expert:EP), model_dim, 1]
    a1_scale=None,  # [expert(local_expert:EP), 1, model_dim]
    a2_scale=None,  # [expert(local_expert:EP), 1, inter_dim]
):
    raise NotImplementedError("The legacy fused_moe_1stage path is not implemented in this checkout")


@functools.lru_cache(maxsize=1024)
def get_block_size_M(token, topk, expert, inter_dim):
    cu_num = get_cu_num()
    tileN = 128
    tgN = (inter_dim + tileN - 1) // tileN
    support_list = [32, 64, 128]

    tmp = []
    for el in support_list:
        max_num_tokens = token * topk + expert * el - topk
        tg_num = tgN * (max_num_tokens + el - 1) // el
        rnd = (tg_num + cu_num - 1) // cu_num
        empty = cu_num - tg_num % cu_num
        tmp.append((rnd, empty, el))
    return sorted(tmp, key=lambda x: x[:2])[0][-1]


cfg_2stages = None


@functools.lru_cache(maxsize=1024)
def get_2stage_cfgs(
    token,
    model_dim,
    inter_dim,
    expert,
    topk,
    dtype,
    q_dtype_a,
    q_dtype_w,
    q_type,
    use_g1u1,
    activation,
    doweight_stage1,
):
    raise NotImplementedError("The legacy two-stage CK/ASM adapters are not implemented in this checkout")


@functools.lru_cache()
def get1tensor(device):
    return torch.tensor(1.0, dtype=torch.float, device=device)


# def fused_moe_2stages(
#     hidden_states,
#     w1,  # [expert(local_expert:EP), inter_dim*2, dim] N,K
#     w2,  # [expert(local_expert:EP), dim, inter_dim]
#     topk,
#     sorted_ids,
#     sorted_weights,
#     sorted_expert_ids,
#     num_valid_ids,
#     moe_out,
#     isG1U1,
#     block_size_M,
#     activation=ActivationType.Silu,
#     quant_type=QuantType.No,
#     doweight_stage1=False,
#     # following for quant
#     q_dtype_a=None,
#     q_dtype_w=None,
#     w1_scale=None,  # [expert(local_expert:EP), inter_dim, 1]
#     w2_scale=None,  # [expert(local_expert:EP), model_dim, 1]
#     a1_scale=None,  # [expert(local_expert:EP), 1, model_dim]
#     a2_scale=None,  # [expert(local_expert:EP), 1, inter_dim]
# ):

#     quant_func = get_quant(quant_type)

#     token_num, _ = hidden_states.shape
#     E, model_dim, inter_dim = get_inter_dim(w1.shape, w2.shape)
#     dtype = hidden_states.dtype
#     device = hidden_states.device

#     stage1, stage2, block_m, ksplit = get_2stage_cfgs(
#         token_num,
#         model_dim,
#         inter_dim,
#         E,
#         topk,
#         dtype,
#         q_dtype_a,
#         q_dtype_w,
#         quant_type,
#         isG1U1,
#         activation,
#         doweight_stage1,
#     )

#     a1, a1_scale = quant_func(hidden_states, scale=a1_scale, quant_dtype=q_dtype_a)
#     if quant_type != QuantType.per_128x128:
#         a2 = torch.empty(
#             (token_num, topk, inter_dim),
#             dtype=dtype,
#             device=device,
#         )
#     else:
#         ratio = a1_scale.element_size() // a1.element_size()
#         a2 = torch.empty(
#             (token_num + (token_num * ratio + 127) // 128, topk, inter_dim),
#             dtype=q_dtype_a,
#             device=device,
#         )

#     a2 = stage1(
#         a1,
#         w1,
#         w2,
#         sorted_ids,
#         sorted_expert_ids,
#         num_valid_ids,
#         a2,
#         block_m=block_m,
#         a1_scale=a1_scale,
#         w1_scale=w1_scale,
#         sorted_weights=sorted_weights if doweight_stage1 else None,
#     )

#     if quant_type != QuantType.per_128x128:
#         if quant_type == QuantType.per_Token:
#             a2 = a2.view(token_num, -1)
#         a2, a2_scale = quant_func(a2, scale=a2_scale, quant_dtype=q_dtype_a)
#         a2 = a2.view(token_num, topk, inter_dim)
#     else:
#         a2_v = a2[:token_num, :, :]
#         a2_scale = (
#             a2[token_num:, ...]
#             .view(-1)[: token_num * topk * inter_dim * ratio // 128]
#             .view(dtypes.fp32)
#             .view(token_num, -1)
#         )
#         a2 = a2_v

#     if quant_type == aiter.QuantType.No:
#         a2_scale = get1tensor(device)

#     stage2(
#         a2,
#         w1,
#         w2,
#         sorted_ids,
#         sorted_expert_ids,
#         num_valid_ids,
#         moe_out,
#         topk,
#         w2_scale,
#         a2_scale,
#         block_size_M,
#         sorted_weights=sorted_weights if not doweight_stage1 else None,
#     )

#     return moe_out


def torch_moe_act(act_input, torch_act, inter_dim):
    if act_input.shape[-1] == inter_dim:
        return torch_act(act_input)
    else:
        gate, up = act_input.split([inter_dim, inter_dim], dim=-1)
        return torch_act(gate) * up


# def asm_stage1(
#     input,
#     w1,
#     w2,
#     sorted_ids,
#     sorted_expert_ids,
#     num_valid_ids,
#     out,  # [token_num, topk, inter_dim]
#     block_m: int,
#     kernelName: str = "",
#     ksplit: int = 0,
#     activation=ActivationType.Silu,
#     quant_type=QuantType.No,
#     a1_scale=None,
#     w1_scale=None,
#     sorted_weights=None,
# ):
#     dtype = dtypes.bf16  # out.dtype, asm only support bf16
#     if quant_type != QuantType.per_128x128:
#         out = out.view(dtype)
#     device = out.device
#     token_num, topk, _ = out.shape
#     E, model_dim, inter_dim = get_inter_dim(w1.shape, w2.shape)

#     if quant_type == QuantType.per_Tensor:
#         a1_scale = a1_scale.view(1, 1).repeat(token_num, 1)
#         w1_scale = w1_scale.view(E, 1).repeat(1, w1.shape[1])
#         quant_type = QuantType.per_Token

#     tmp_out = out
#     if ksplit > 0:
#         tmp_out = torch.zeros(
#             (token_num, topk, w1.shape[1]),
#             dtype=dtypes.fp32,
#             device=device,
#         ).view(dtype)

#     aiter.moe_stage1_g1u1(
#         input,
#         w1,
#         w2,
#         sorted_ids,
#         sorted_expert_ids,
#         num_valid_ids,
#         tmp_out,
#         inter_dim,
#         kernelName,
#         block_m,
#         ksplit=ksplit,
#         activation=activation,
#         quant_type=quant_type,
#         a1_scale=a1_scale,
#         w1_scale=w1_scale,
#         sorted_weights=sorted_weights,
#     )
#     if ksplit > 0:
#         if activation == ActivationType.Silu:
#             aiter.silu_and_mul(out, tmp_out.view(dtypes.fp32).to(dtype))
#         else:
#             aiter.gelu_and_mul(out, tmp_out.view(dtypes.fp32).to(dtype))
#     return out


# def ck_stage1(
#     input,  # [token, model_dim]
#     w1,  # [E, inter_dim*2, model_dim]
#     w2,  # [E, model_dim, inter_dim]
#     sorted_ids,  # [max_num_tokens_padded]
#     sorted_expert_ids,  # [max_num_m_blocks]
#     num_valid_ids,  # [1]
#     out,  # [token_num, topk, inter_dim]
#     block_m=32,
#     activation=ActivationType.Silu,
#     a1_scale=None,
#     w1_scale=None,
#     sorted_weights=None,
# ):
#     _, topk, _ = out.shape
#     # max_num_tokens_padded = sorted_expert_ids.shape[0]*block_size

#     if activation == ActivationType.Silu:
#         act_op = 1
#     else:
#         act_op = 0

#     aiter.ck_moe_stage1(
#         input,
#         w1,
#         w2,
#         sorted_ids,
#         sorted_expert_ids,
#         num_valid_ids,
#         out,
#         topk,
#         w1_scale,
#         a1_scale,
#         block_m,
#         sorted_weights,
#         act_op,
#     )

#     return out


def torch_moe(
    hidden_states,
    w1,
    w2,
    topk_weight,
    topk_ids,
    # following for int8 quant
    fc1_scale=None,  # [expert(local_expert:EP), inter_dim, 1]
    fc2_scale=None,  # [expert(local_expert:EP), model_dim, 1]
    fc1_smooth_scale=None,  # [expert(local_expert:EP), 1, model_dim]
    fc2_smooth_scale=None,  # [expert(local_expert:EP), 1, inter_dim]
    expert_mask=None,
    activation=ActivationType.Silu,
):
    computeType = dtypes.fp32
    dtype = hidden_states.dtype
    torch_act = aiter.get_torch_act(activation)
    hidden_states = hidden_states.to(computeType)
    w1 = w1.to(computeType)
    w2 = w2.to(computeType)
    B, D = hidden_states.shape
    topk = topk_weight.shape[1]
    if expert_mask is not None:
        local_expert_hash = expert_mask.cumsum(0, dtype=dtypes.i32) - 1
        local_expert_hash[expert_mask == 0] = -1
        topk_ids = local_expert_hash[topk_ids]

    hidden_states = hidden_states.view(B, -1, D).repeat(1, topk, 1)
    out = torch.zeros(
        (B, topk, D),
        dtype=computeType,
        device=hidden_states.device,
    )

    inter_dim = w2.shape[2]

    if fc1_scale is not None:
        # gose to quant D_w8a8/w8a8
        expert = w1.shape[0]
        w2D = w2.shape[-1]
        w1 = (w1.view(-1, D) * fc1_scale.view(-1, 1)).view(expert, -1, D)
        w2 = (w2.view(-1, w2D) * fc2_scale.view(-1, 1)).view(expert, -1, w2D)

    if fc1_smooth_scale is not None:
        expert = fc1_smooth_scale.shape[0]
        fc1_smooth_scale = fc1_smooth_scale.view(expert, -1)
        fc2_smooth_scale = fc2_smooth_scale.view(expert, -1)

    for E_id in range(w1.shape[0]):
        mask = topk_ids == E_id
        if mask.sum():
            sub_tokens = hidden_states[mask]
            if fc1_smooth_scale is not None:
                sub_tokens = sub_tokens * (fc1_smooth_scale[E_id])

            act_input = sub_tokens @ (w1[E_id].transpose(0, 1))
            act_out = torch_moe_act(act_input, torch_act, inter_dim)
            if fc2_smooth_scale is not None:
                act_out = act_out * (fc2_smooth_scale[E_id])
            out[mask] = act_out @ (w2[E_id].transpose(0, 1))

    return (out * topk_weight.view(B, -1, 1)).sum(dim=1).to(dtype)

# For test
def torch_moe_blockscale(
    hidden_states,
    w1,  # [expert, inter_dim*2, model_dim]
    w2,  # [expert, model_dim, inter_dim]
    topk_weight,
    topk_ids,
    dtype,
    # following for quant
    scale_blks=(128, 128),
    a_scale=None,
    # [expert, inter_dim/blk_m, model_dim/blk_k]
    fc1_scale=None,
    # [expert, model_dim/blk_m, inter_dim/blk_k]
    fc2_scale=None,
    expert_mask=None,
    computeType=torch.float32,
):
    hidden_states = hidden_states.float().to(computeType)
    w1 = w1.float().to(computeType)
    w2 = w2.float().to(computeType)
    token_num, topk = topk_ids.shape
    expert, model_dim, inter_dim = w2.shape
    B, D = hidden_states.shape
    topk = topk_weight.shape[1]
    if expert_mask is not None:
        local_expert_hash = expert_mask.cumsum(0, dtype=dtypes.i32) - 1
        local_expert_hash[expert_mask == 0] = -1
        topk_ids = local_expert_hash[topk_ids]

    blk_n, blk_k = scale_blks
    if a_scale is not None:
        # print(f'{a_scale.unsqueeze(-1).shape=}, {hidden_states.view(token_num, -1, blk_k).shape=}')
        hidden_states = hidden_states.view(token_num, -1, blk_k) * a_scale.unsqueeze(-1)
        hidden_states = hidden_states.view(token_num, -1)

    hidden_states = hidden_states.view(token_num, 1, model_dim).repeat(1, topk, 1)
    out = torch.zeros(
        (B, topk, D),
        dtype=computeType,
        device=hidden_states.device,
    )
    if w2.shape[2] * 2 == w1.shape[1]:
        moeType = "g1u1"
    else:
        moeType = "g1u0"

    nblk_n = inter_dim // blk_n
    nblk_k = model_dim // blk_k
    if fc1_scale is not None:
        fc1_scale = fc1_scale.to(computeType)
        fc2_scale = fc2_scale.to(computeType)
        fc1_scale = rearrange(
            fc1_scale.view(-1, 1)
            .repeat(1, blk_n * blk_k)
            .view(expert, -1, nblk_k, blk_n, blk_k),
            "e num_blk_n num_blk_k blk_n blk_k -> e (num_blk_n blk_n) (num_blk_k blk_k)",
        )
        fc2_scale = rearrange(
            fc2_scale.view(-1, 1)
            .repeat(1, blk_n * blk_k)
            .view(expert, nblk_k, nblk_n, blk_k, blk_n),
            "e num_blk_n num_blk_k blk_n blk_k -> e (num_blk_n blk_n) (num_blk_k blk_k)",
        )
        w1 = w1 * fc1_scale
        w2 = w2 * fc2_scale

    for E_id in range(w1.shape[0]):
        mask = topk_ids == E_id
        if mask.sum():
            sub_tokens = hidden_states[mask]
            act_input = sub_tokens @ (w1[E_id].transpose(0, 1))
            if moeType == "g1u1":
                gate, up = act_input.split([inter_dim, inter_dim], dim=-1)
                act_out = F.silu(gate) * up
            else:
                act_out = F.gelu(act_input)
            out[mask] = act_out @ (w2[E_id].transpose(0, 1))

    return (out * topk_weight.view(B, -1, 1)).sum(dim=1).to(dtype)

def torch_moe_stage1(
    hidden_states,
    w1,  # E, inter_dim*2, model_dim
    w2,  # E, model_dim, inter_dim
    topk_weight,
    topk_ids,
    dtype=dtypes.fp16,
    activation=ActivationType.Silu,
    quant_type=QuantType.No,
    # following for quant
    a1_scale=None,  # [token, 1]
    w1_scale=None,  # [expert, inter_dim, 1]
    doweight=False,
    group_by_expert=False,
):
    ctype = dtypes.fp32  # compute type
    hidden_states = hidden_states.to(ctype)
    w1 = w1.to(ctype)

    B, D = hidden_states.shape
    topk = topk_weight.shape[1]
    N = w1.shape[1]
    E, model_dim, inter_dim = get_inter_dim(w1.shape, w2.shape)

    if quant_type in [QuantType.per_Token, QuantType.per_Tensor]:
        w1 = w1 * w1_scale.view(w1_scale.shape[0], -1, 1)
        hidden_states = hidden_states * a1_scale
    # per_128x128
    elif quant_type == QuantType.per_128x128:
        w1_shape = w1.shape
        w1 = w1.view(
            w1.shape[0], w1.shape[1] // 128, 128, w1.shape[2] // 128, 128
        ) * w1_scale.view(
            w1_scale.shape[0], w1.shape[1] // 128, 1, w1.shape[2] // 128, 1
        )
        w1 = w1.view(w1_shape)

        a1_scale = a1_scale.view(hidden_states.shape[0], -1, 1)
        a1_scale = a1_scale.repeat(
            1, 1, hidden_states.shape[-1] // a1_scale.shape[1]
        ).view(hidden_states.shape[0], -1)
        hidden_states = hidden_states * a1_scale
    elif quant_type == QuantType.No:
        pass
    else:
        assert False, f"Unsupported quant_type: {quant_type}"

    hidden_states = hidden_states.view(B, -1, D).repeat(1, topk, 1)

    out = torch.zeros(
        (B, topk, N),
        dtype=ctype,
        device=hidden_states.device,
    )
    for E_id in range(w1.shape[0]):
        mask = topk_ids == E_id
        if mask.sum():
            sub_tokens = hidden_states[mask]
            act_input = sub_tokens @ (w1[E_id].transpose(0, 1))
            if doweight:
                act_input = act_input * topk_weight[mask].view(-1, 1)
            out[mask] = act_input


    if group_by_expert:
        out_flat = out.reshape(-1, out.shape[-1])
        expert_indices = []
        for expert_id in range(E):
            positions = torch.nonzero(topk_ids == expert_id, as_tuple=False)
            if positions.numel() == 0:
                continue
            linear_idx = positions[:, 0] * topk + positions[:, 1]
            expert_indices.append(linear_idx)

        if expert_indices:
            gather_idx = torch.cat(expert_indices).to(
                device=out_flat.device, dtype=torch.long
            )
            out_grouped = out_flat.index_select(0, gather_idx)
        else:
            out_grouped = out_flat[:0]

        out = out_grouped

    use_g1u1 = w1.shape[1] == (2 * inter_dim)
    torch_act = aiter.get_torch_act(activation)
    if use_g1u1:
        gate, up = out.split([inter_dim, inter_dim], dim=-1)
        out = torch_act(gate) * up
    else:
        out = torch_act(out)
    return out.to(dtype)


def torch_moe_stage2(
    hidden_states,
    w1,  # E, inter_dim*2, model_dim
    w2,  # E, model_dim, inter_dim
    topk_weights,
    topk_ids,
    dtype=dtypes.fp16,
    quant_type=QuantType.No,
    w2_scale=None,  # [1]
    a2_scale=None,  # [expert]]'
    doweight=True,
):
    ctype = dtypes.fp32  # compute type
    hidden_states = hidden_states.to(ctype)
    w2 = w2.to(ctype)

    token_num, topk = topk_ids.shape
    num_experts, model_dim, inter_dim = w2.shape
    hidden_states = hidden_states.view(token_num, topk, inter_dim)

    if quant_type in [QuantType.per_Token, QuantType.per_Tensor]:
        w2 = w2 * w2_scale.view(w2_scale.shape[0], -1, 1)
    # per_128x128
    elif quant_type == QuantType.per_128x128:
        w2_shape = w2.shape
        w2 = w2.view(
            w2.shape[0], w2.shape[1] // 128, 128, w2.shape[2] // 128, 128
        ) * w2_scale.view(
            w2_scale.shape[0], w2.shape[1] // 128, 1, w2.shape[2] // 128, 1
        )
        w2 = w2.view(w2_shape)

    if quant_type in [QuantType.per_Token, QuantType.per_Tensor]:
        hidden_states = hidden_states * a2_scale.view(a2_scale.shape[0], -1, 1)
    elif quant_type == QuantType.per_128x128:
        a2_scale = a2_scale.view(hidden_states.shape[0], topk, -1, 1)
        a2_scale = a2_scale.repeat(1, 1, 1, 128).view(hidden_states.shape[0], topk, -1)
        hidden_states = hidden_states * a2_scale

    out = torch.zeros(
        (token_num, topk, model_dim),
        dtype=ctype,
        device=hidden_states.device,
    )
    for E_id in range(w1.shape[0]):
        mask = topk_ids == E_id
        if mask.sum():
            sub_tokens = hidden_states[mask]
            act_input = sub_tokens @ (w2[E_id].transpose(0, 1))
            out[mask] = act_input
    if doweight:
        out = out * topk_weights.view(token_num, -1, 1)
    return out.sum(1).to(dtype)


def fused_topk(
    hidden_states: torch.Tensor,
    gating_output: torch.Tensor,
    topk: int,
    renormalize: bool,
    topk_ids: Optional[torch.Tensor] = None,
    topk_weights: Optional[torch.Tensor] = None,
    is_softmax: bool = True,
):
    assert hidden_states.shape[0] == gating_output.shape[0], "Number of tokens mismatch"

    M, _ = hidden_states.shape

    if topk_weights is None:
        topk_weights = torch.empty(
            M, topk, dtype=dtypes.fp32, device=hidden_states.device
        )
    if topk_ids is None:
        topk_ids = torch.empty(M, topk, dtype=dtypes.i32, device=hidden_states.device)

    if is_softmax:
        token_expert_indicies = torch.empty(
            M, topk, dtype=dtypes.i32, device=hidden_states.device
        )

        aiter.topk_softmax(
            topk_weights,
            topk_ids,
            token_expert_indicies,
            gating_output.float(),  # TODO(woosuk): Optimize this.
            renormalize,
        )
        del token_expert_indicies  # Not used. Will be used in the future.
    
    # sigmoid
    else:
        # Use sigmoid and simple topk
        # scores = gating_output.sigmoid()
        # topk_weights_temp, topk_ids_temp = torch.topk(scores, k=topk, dim=-1)
        # topk_weights.copy_(topk_weights_temp)
        # topk_ids.copy_(topk_ids_temp.to(dtypes.i32))
        # if renormalize:
        #     topk_weights.div_(topk_weights.sum(dim=-1, keepdim=True))

        aiter.grouped_topk(
            gating_output,
            topk_weights,
            topk_ids,
            1,
            1,
            renormalize,
            False,      # is_softmax=False, go sigmoid
            routed_scaling_factor = 1.0
        )

    return topk_weights, topk_ids
