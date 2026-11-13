# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.

import os

import torch
from torch import Tensor
from ..jit.core import compile_ops
from typing import Optional


@compile_ops("module_fused_qk_norm_rope_cache_quant_shuffle")
def fused_qk_norm_rope_cache_quant_shuffle(
    qkv: Tensor,
    num_heads_q: int,
    num_heads_k: int,
    num_heads_v: int,
    head_dim: int,
    eps: float,
    qw: Tensor,
    kw: Tensor,
    cos_sin_cache: Tensor,
    is_neox_style: bool,
    pos_ids: Tensor,
    k_cache: Tensor,
    v_cache: Tensor,
    slot_mapping: Tensor,
    kv_cache_dtype: str,
    k_scale: Tensor,
    v_scale: Tensor,
) -> None: ...


def gen_fused_qk_rmsnorm_fake_tensor(
    q: Tensor,
    q_weight: Tensor,
    q_eps: float,
    k: Tensor,
    k_weight: Tensor,
    k_eps: float,
    q_out: Optional[Tensor],
    k_out: Optional[Tensor],
) -> tuple[Tensor, Tensor]:
    if q_out is None:
        q_out = torch.empty_like(q, dtype=q.dtype, device=q.device)
    if k_out is None:
        k_out = torch.empty_like(k, dtype=k.dtype, device=k.device)
    return q_out, k_out


@compile_ops(
    "module_fused_qk_norm_rope_cache_quant_shuffle",
    fc_name="fused_qk_rmsnorm",
    gen_fake=gen_fused_qk_rmsnorm_fake_tensor,
)
def _fused_qk_rmsnorm_kernel(
    q: Tensor,
    q_weight: Tensor,
    q_eps: float,
    k: Tensor,
    k_weight: Tensor,
    k_eps: float,
    q_out: Optional[Tensor] = None,
    k_out: Optional[Tensor] = None,
) -> tuple[Tensor, Tensor]:
    """
    One 2D-grid kernel normalizes Q and K in parallel (blockIdx.y picks the
    stream), so it beats two separate rmsnorm launches at the moderate M that
    decode/prefill attention actually sees. fp16/bf16, max(N1, N2) <= 8192.
    """
    ...


# The fused 2D-grid kernel only wins at small M: it does Q and K in one launch,
# saving launch + weight-load overhead, but its per-row throughput is below the
# CK rmsnorm2d path, so it loses once there are enough rows to fill the device.
# Measured on gfx936 and gfx938 (bf16, N1/N2 in {1024,1536}/{512,1024}) against
# two independent rmsnorm2d_fwd calls: +100~124% at M=1, +12% at M=8, -7% at
# M=12, and -36~-52% from M=64 up. Hence M<=8. Upstream uses the inverse
# threshold (fused everywhere below M=16384), which is badly wrong for HCU.
# Override with AITER_FUSED_QK_MAX_M when retuning for another architecture.
_FUSED_QK_MAX_M = int(os.environ.get("AITER_FUSED_QK_MAX_M", "8"))


def _fused_qk_rmsnorm(
    q_out: Optional[Tensor],
    q: Tensor,
    q_weight: Tensor,
    q_eps: float,
    k_out: Optional[Tensor],
    k: Tensor,
    k_weight: Tensor,
    k_eps: float,
) -> tuple[Tensor, Tensor]:
    if q_out is None:
        q_out = torch.empty_like(q, dtype=q.dtype, device=q.device)
    if k_out is None:
        k_out = torch.empty_like(k, dtype=k.dtype, device=k.device)

    if q.size(0) <= _FUSED_QK_MAX_M:
        _fused_qk_rmsnorm_kernel(
            q, q_weight, q_eps, k, k_weight, k_eps, q_out, k_out
        )
    else:
        # rmsnorm2d_fwd_out, not rms_norm_cu: q/k are typically row views of a
        # fused QKV projection, and only the CK path reads input.stride(0).
        from .rmsnorm import rmsnorm2d_fwd_out

        rmsnorm2d_fwd_out(q_out, q, q_weight, q_eps)
        rmsnorm2d_fwd_out(k_out, k, k_weight, k_eps)
    return q_out, k_out


def fused_qk_rmsnorm(
    q_out_quantized: Optional[Tensor] = None,
    q_out_scale: Optional[Tensor] = None,
    q: Optional[Tensor] = None,
    q_weight: Optional[Tensor] = None,
    q_epsilon: float = 1e-6,
    q_out_unquantized: Optional[Tensor] = None,
    k_out: Optional[Tensor] = None,
    q_res_out: Optional[Tensor] = None,
    k: Optional[Tensor] = None,
    k_weight: Optional[Tensor] = None,
    k_epsilon: Optional[float] = None,
    q_residual: Optional[Tensor] = None,
    gemma_norm: bool = False,
    quant_type=None,
    group_size: Optional[int] = None,
    transpose_scale: bool = False,
) -> None:
    """Centralized fused Q/K RMSNorm entry.

    Keeps the upstream keyword contract so framework code ports unchanged.
    Only the unquantized path (``QuantType.No``) is implemented on HCU; the
    quantized variants belong to ops that have not been brought up yet.
    """
    from .enum import QuantType

    if quant_type is None:
        quant_type = QuantType.No
    if quant_type != QuantType.No:
        raise NotImplementedError(
            f"fused_qk_rmsnorm on HCU only supports QuantType.No, got {quant_type}"
        )
    _fused_qk_rmsnorm(
        q_out_quantized, q, q_weight, q_epsilon, k_out, k, k_weight, k_epsilon
    )


@compile_ops("module_fused_qk_norm_rope_cache_quant_shuffle")
def fused_qk_norm_rope_cache_block_quant_shuffle(
    qkv: Tensor,
    num_heads_q: int,
    num_heads_k: int,
    num_heads_v: int,
    head_dim: int,
    eps: float,
    qw: Tensor,
    kw: Tensor,
    cos_sin_cache: Tensor,
    is_neox_style: bool,
    pos_ids: Tensor,
    k_cache: Tensor,
    v_cache: Tensor,
    slot_mapping: Tensor,
    cu_q_len: Tensor,
    kv_cache_dtype: str,
    k_scale: Tensor,
    v_scale: Tensor,
    max_tokens_per_batch: int = 0,
) -> None: ...


@compile_ops("module_fused_qk_norm_rope_cache_quant_shuffle")
def fused_qk_norm_rope_cache_pts_quant_shuffle(
    qkv: Tensor,
    qw: Tensor,
    kw: Tensor,
    cos_sin: Tensor,
    positions: Tensor,
    num_tokens: int,
    num_heads_q: int,
    num_heads_k: int,
    num_heads_v: int,
    head_size: int,
    is_neox_style: bool,
    eps: float,
    q_out: Tensor,
    k_cache: Tensor,
    v_cache: Tensor,
    slot_mapping: Tensor,
    per_tensor_k_scale: Tensor,
    per_tensor_v_scale: Tensor,
    k_out: Optional[Tensor],
    v_out: Optional[Tensor],
    return_kv: bool,
    use_shuffle_layout: bool,
    block_size: int,
    x: int,
    rotary_dim: int = 0,
) -> None: ...


@compile_ops("module_fused_qk_norm_rope_cache_quant_shuffle")
def fused_qk_norm_rope_2way(
    q0: Tensor,
    k0: Tensor,
    q1: Tensor,
    k1: Tensor,
    w_q0: Tensor,
    w_k0: Tensor,
    w_q1: Tensor,
    w_k1: Tensor,
    cos_sin0: Tensor,
    cos_sin1: Tensor,
    batch_size: int,
    num_tokens0: int,
    num_tokens1: int,
    num_heads_q: int,
    num_heads_k: int,
    head_size: int,
    is_interleaved: bool,
    eps: float,
    out_q01: Tensor,
    out_k01: Tensor,
) -> None: ...
