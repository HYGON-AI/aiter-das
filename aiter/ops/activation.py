# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
from typing import Optional, Tuple

import torch
from torch import Tensor

from ..jit.core import compile_ops


MD_NAME = "module_activation"


@compile_ops("module_activation")
def silu_and_mul(out: Tensor, input: Tensor) -> None: ...


@compile_ops("module_activation")
def scaled_silu_and_mul(out: Tensor, input: Tensor, scale: Tensor) -> None: ...


@compile_ops("module_activation")
def gelu_and_mul(out: Tensor, input: Tensor) -> None: ...


@compile_ops("module_activation")
def gelu_tanh_and_mul(out: Tensor, input: Tensor) -> None: ...


@compile_ops("module_activation")
def swiglu_variant(
    out: Tensor,
    input: Tensor,
    alpha: float,
    limit: float,
    mode: int,
    rows_per_block: int = 1,
    vec_size: int = 2,
) -> None: ...


# ---------------------------------------------------------------------------
# Fused silu_and_mul + per-token dynamic quant
# ---------------------------------------------------------------------------


@compile_ops("module_activation", "fuse_silu_mul_quant")
def _jit_fuse_silu_mul_quant(
    out: Tensor,
    input: Tensor,
    scales: Tensor,
    num_local_tokens_tensor: Optional[Tensor],
    topk: int,
    expect_m: int,
    expert_ids: Optional[Tensor],
) -> None: ...


@compile_ops("module_activation", "fuse_silu_mul_fp8_quant")
def _jit_fuse_silu_mul_fp8_quant(
    out: Tensor,
    input: Tensor,
    scales: Tensor,
    fp8type: int,
    num_local_tokens_tensor: Optional[Tensor],
    topk: int,
    expect_m: int,
    expert_ids: Optional[Tensor],
) -> None: ...


@compile_ops("module_activation", "fuse_silu_mul_quant_ep")
def _jit_fuse_silu_mul_quant_ep(
    out: Tensor,
    input: Tensor,
    scales: Tensor,
    tokens_per_expert: Optional[Tensor],
    num_local_tokens_tensor: Optional[Tensor],
    topk: int,
    expect_m: int,
) -> None: ...


@compile_ops("module_activation", "fuse_silu_mul_fp8_quant_ep")
def _jit_fuse_silu_mul_fp8_quant_ep(
    out: Tensor,
    input: Tensor,
    scales: Tensor,
    fp8type: int,
    tokens_per_expert: Optional[Tensor],
    num_local_tokens_tensor: Optional[Tensor],
    topk: int,
    expect_m: int,
) -> None: ...


@compile_ops("module_activation", "fuse_silu_and_mul_ep")
def _jit_fuse_silu_and_mul_ep(
    out: Tensor, input: Tensor, mask_m: Tensor, expect_m: int = -1
) -> None: ...


@compile_ops("module_activation", "relu2")
def _jit_relu2(out: Tensor, input: Tensor) -> None: ...


def fuse_silu_mul_quant(
    input: Tensor,  # [..., 2 * d]
    num_local_tokens_tensor: Optional[Tensor] = None,  # int32[1], device token count
    topk: int = 1,
    expect_m: int = -1,
    output: Optional[Tensor] = None,  # [..., d] int8
    scales: Optional[Tensor] = None,  # [..., 1] fp32
    expert_ids: Optional[Tensor] = None,  # int32, -1 rows are skipped
) -> Tuple[Tensor, Tensor]:
    leading, d2 = input.shape[-2:]
    d = d2 // 2
    if output is None:
        output = torch.empty(leading, d, dtype=torch.int8, device=input.device)
    if scales is None:
        scales = torch.empty((leading, 1), device=input.device, dtype=torch.float32)
    _jit_fuse_silu_mul_quant(
        output, input, scales, num_local_tokens_tensor, topk, expect_m, expert_ids
    )
    return output, scales


def fuse_silu_mul_fp8_quant(
    input: Tensor,
    fp8type: int = 0,  # 0: float8_e4m3fn, 1: float8_e5m2
    num_local_tokens_tensor: Optional[Tensor] = None,
    topk: int = 1,
    expect_m: int = -1,
    output: Optional[Tensor] = None,  # [..., d] fp8
    scales: Optional[Tensor] = None,  # [..., 1] fp32
    expert_ids: Optional[Tensor] = None,
) -> Tuple[Tensor, Tensor]:
    leading, d2 = input.shape[-2:]
    d = d2 // 2
    if output is None:
        fp8_dtype = torch.float8_e4m3fn if fp8type == 0 else torch.float8_e5m2
        output = torch.empty(leading, d, dtype=fp8_dtype, device=input.device)
    if scales is None:
        scales = torch.empty((leading, 1), device=input.device, dtype=torch.float32)
    _jit_fuse_silu_mul_fp8_quant(
        output.view(torch.uint8),
        input,
        scales,
        fp8type,
        num_local_tokens_tensor,
        topk,
        expect_m,
        expert_ids,
    )
    return output, scales


def fuse_silu_mul_quant_ep(
    input: Tensor,  # [E, T, 2 * d]
    tokens_per_expert: Optional[Tensor] = None,  # int32[E]
    num_local_tokens_tensor: Optional[Tensor] = None,
    topk: int = 1,
    expect_m: int = -1,
) -> Tuple[Tensor, Tensor]:
    if input.dim() != 3:
        raise ValueError(
            f"Input tensor must be 3-dimensional [E, T, H], but got shape {input.shape}"
        )
    E, T, H = input.shape
    d = H // 2
    output = torch.empty(E, T, d, dtype=torch.int8, device=input.device)
    scales = torch.empty(E, T, 1, device=input.device, dtype=torch.float32)
    _jit_fuse_silu_mul_quant_ep(
        output, input, scales, tokens_per_expert, num_local_tokens_tensor, topk, expect_m
    )
    return output, scales


def fuse_silu_mul_fp8_quant_ep(
    input: Tensor,  # [E, T, 2 * d]
    fp8type: int = 0,
    tokens_per_expert: Optional[Tensor] = None,
    num_local_tokens_tensor: Optional[Tensor] = None,
    topk: int = 1,
    expect_m: int = -1,
) -> Tuple[Tensor, Tensor]:
    if input.dim() != 3:
        raise ValueError(
            f"Input tensor must be 3-dimensional [E, T, H], but got shape {input.shape}"
        )
    E, T, H = input.shape
    d = H // 2
    fp8_dtype = torch.float8_e4m3fn if fp8type == 0 else torch.float8_e5m2
    output = torch.empty(E, T, d, dtype=fp8_dtype, device=input.device)
    scales = torch.empty(E, T, 1, device=input.device, dtype=torch.float32)
    _jit_fuse_silu_mul_fp8_quant_ep(
        output.view(torch.uint8),
        input,
        scales,
        fp8type,
        tokens_per_expert,
        num_local_tokens_tensor,
        topk,
        expect_m,
    )
    return output, scales


def fuse_silu_mul_per_token_quant(
    input: Tensor,
    dtype: torch.dtype = torch.int8,
    num_local_tokens_tensor: Optional[Tensor] = None,
    topk: int = 1,
    expect_m: int = -1,
    output: Optional[Tensor] = None,
    scales: Optional[Tensor] = None,
    expert_ids: Optional[Tensor] = None,
) -> Tuple[Tensor, Tensor]:
    """Generic entry dispatching to int8 / float8_e4m3fn / float8_e5m2."""
    actual_dtype = output.dtype if output is not None else dtype
    if actual_dtype == torch.int8:
        return fuse_silu_mul_quant(
            input,
            num_local_tokens_tensor,
            topk,
            expect_m,
            output,
            scales,
            expert_ids,
        )
    elif actual_dtype in (torch.float8_e4m3fn, torch.float8_e5m2):
        fp8type = 0 if actual_dtype == torch.float8_e4m3fn else 1
        return fuse_silu_mul_fp8_quant(
            input,
            fp8type,
            num_local_tokens_tensor,
            topk,
            expect_m,
            output,
            scales,
            expert_ids,
        )
    raise ValueError(
        f"Unsupported dtype: {actual_dtype}. "
        "Supported dtypes are torch.int8, torch.float8_e4m3fn, torch.float8_e5m2"
    )


def fuse_silu_and_mul_ep(
    input: Tensor,  # [E, T, 2 * d]
    output: Tensor,  # [E, T, d], same dtype as input
    mask_m: Tensor,  # int32[E], valid tokens per expert
    expect_m: int = -1,
) -> None:
    """Masked EP silu-and-mul; mask_m holds one valid-token count per expert."""
    _jit_fuse_silu_and_mul_ep(output, input, mask_m, expect_m)


def relu2(input: Tensor) -> Tensor:
    """Squared ReLU: out = relu(x)^2."""
    output = torch.empty_like(input)
    _jit_relu2(output, input)
    return output
