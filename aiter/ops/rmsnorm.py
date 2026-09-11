# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
 
import torch
from torch import Tensor
from ..jit.core import compile_ops
from typing import Optional, Tuple

MD_NAME = "module_rmsnorm"


@compile_ops("module_rmsnorm")
def rms_norm_cu(
    out: Tensor,
    input: Tensor,
    weight: Tensor,
    epsilon: float,
) -> None:
    """
    Cuda version of rmsnorm
    """
    ...


@compile_ops("module_rmsnorm")
def fused_add_rms_norm_cu(
    input: Tensor,  # input/out
    residual_in: Tensor,  # residual_in/out
    weight: Tensor,
    epsilon: float,
) -> None:
    """
    Cuda version of rmsnorm fused add
    """
    ...


def gen_rms_norm_fake_tensor(
    input: Tensor,
    weight: Tensor,
    epsilon: float,
) -> Tensor:
    return torch.empty_like(input, dtype=input.dtype, device=input.device)


@compile_ops(
    "module_rmsnorm", fc_name="rmsnorm2d_fwd", gen_fake=gen_rms_norm_fake_tensor
)
def rms_norm(
    input: Tensor,
    weight: Tensor,
    epsilon: float,
) -> Tensor:
    """
    CK version of rmsnorm
    """
    ...


@compile_ops("module_rmsnorm", gen_fake=gen_rms_norm_fake_tensor)
def rmsnorm2d_fwd(
    input: torch.Tensor,
    weight: torch.Tensor,
    epsilon: float,
) -> Tensor: ...


@compile_ops("module_rmsnorm")
def rmsnorm2d_fwd_with_add(
    out: Tensor,
    input: Tensor,
    residual_in: Tensor,
    residual_out: Tensor,
    weight: Tensor,
    epsilon: float,
) -> None: ...


@compile_ops("module_rmsnorm")
def rmsnorm2d_fwd_with_smoothquant(
    out: Tensor,
    input: Tensor,
    xscale: Tensor,
    yscale: Tensor,
    weight: Tensor,
    epsilon: float,
) -> None: ...


@compile_ops("module_rmsnorm")
def rmsnorm2d_fwd_with_add_smoothquant(
    out: Tensor,
    input: Tensor,
    residual_in: Tensor,
    residual_out: Tensor,
    xscale: Tensor,
    yscale: Tensor,
    weight: Tensor,
    epsilon: float,
    out_before_quant: Optional[Tensor] = None,
) -> None: ...


@compile_ops("module_rmsnorm")
def rmsnorm2d_fwd_with_dynamicquant(
    out: Tensor,
    input: Tensor,
    yscale: Tensor,
    weight: Tensor,
    epsilon: float,
) -> None: ...


@compile_ops("module_rmsnorm")
def rmsnorm2d_fwd_with_add_dynamicquant(
    out: Tensor,
    input: Tensor,
    residual_in: Tensor,
    residual_out: Tensor,
    yscale: Tensor,
    weight: Tensor,
    epsilon: float,
) -> None: ...


def gen_rmsnorm_forward_fake_tensors(
    x: Tensor,
    weight: Tensor,
    eps: float,
    training: bool,
) -> Tuple[Tensor, Tensor]:
    y = torch.empty_like(x, dtype=x.dtype, device=x.device)
    if training:
        rows = x.numel() // x.shape[-1]
        rstd = torch.empty((rows,), dtype=torch.float32, device=x.device)
    else:
        rstd = torch.empty((0,), dtype=torch.float32, device=x.device)
    return y, rstd


def gen_rmsnorm_backward_fake_tensors(
    grad: Tensor,
    x: Tensor,
    rstd: Tensor,
    weight: Tensor,
) -> Tuple[Tensor, Tensor]:
    return torch.empty_like(x), torch.empty_like(weight)


@compile_ops(
    "module_rmsnorm",
    gen_fake=gen_rmsnorm_forward_fake_tensors,
    fc_name="rmsnorm_forward_autograd",
)
def _rmsnorm_forward_kernel(
    x: Tensor,
    weight: Tensor,
    eps: float,
    training: bool,
) -> Tuple[Tensor, Tensor]:
    ...


def rmsnorm_forward(
    x: Tensor,
    weight: Tensor,
    eps: float,
    training: bool,
) -> Tuple[Tensor, Tensor]:
    """
    RMSNorm forward. Returns (output, rstd).
    rstd is populated only when training=True.
    """
    y, rstd = _rmsnorm_forward_kernel(x, weight, eps, training)
    if rstd is None:
        rstd = torch.empty((0,), dtype=torch.float32, device=x.device)
    return y, rstd


@compile_ops(
    "module_rmsnorm",
    gen_fake=gen_rmsnorm_backward_fake_tensors,
    fc_name="rmsnorm_backward_autograd",
)
def _rmsnorm_backward_kernel(
    grad: Tensor,
    x: Tensor,
    rstd: Tensor,
    weight: Tensor,
) -> Tuple[Tensor, Tensor]:
    ...


def rmsnorm_backward_autograd(
    grad: Tensor,
    x: Tensor,
    rstd: Tensor,
    weight: Tensor,
) -> Tuple[Tensor, Tensor]:
    """
    RMSNorm backward. Returns (dx, dweight).
    """
    return _rmsnorm_backward_kernel(grad, x, rstd, weight)


class _RMSNormAutograd(torch.autograd.Function):
    @staticmethod
    def forward(ctx, x, weight, epsilon, training):
        y, rstd = rmsnorm_forward(x, weight, epsilon, training)
        if training:
            ctx.save_for_backward(x, rstd, weight)
        ctx.training = training
        return y

    @staticmethod
    def backward(ctx, grad_output):
        if not ctx.saved_tensors:
            return None, None, None, None
        x, rstd, weight = ctx.saved_tensors
        dx, dgamma = rmsnorm_backward_autograd(grad_output, x, rstd, weight)
        return dx, dgamma, None, None


def rmsnorm_forward_autograd(
    x: Tensor,
    weight: Tensor,
    epsilon: float,
    training: bool = True,
) -> Tensor:
    """
    RMSNorm with autograd backed by HIP C kernels.
    Does not replace aiter.rms_norm (CK inference path).
    """
    return _RMSNormAutograd.apply(x, weight, epsilon, training)


@compile_ops("module_rmsnorm", gen_fake=gen_rms_norm_fake_tensor)
def head_rms_norm(
    input: Tensor,       # [num_tokens, num_heads * head_dim]
    weight: Tensor,      # [num_heads * head_dim]
    epsilon: float,
    norm_head_dim: int,  # head_dim (size of each head's normalization window)
) -> Tensor:
    """
    Apply RMS normalization per head independently.

    Unlike standard rms_norm which normalizes over the entire last dimension,
    head_rms_norm normalizes each head's head_dim elements separately with
    its own weight parameters.

    Args:
        input: shape [num_tokens, num_heads * head_dim]
        weight: shape [num_heads * head_dim]
        epsilon: small value for numerical stability
        norm_head_dim: the dimension of each head (head_dim)

    Returns:
        Tensor with same shape as input
    """
    ...
