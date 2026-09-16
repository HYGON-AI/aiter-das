# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Training Add + SwiGLU with explicit eager dtype rounding boundaries.

Contract: silu((base + delta)[..., :D]) * (base + delta)[..., D:].
This is the ordinary PyTorch expression, not the clipped/interleaved SwiGLU
variant. Only contiguous, matching FP16/BF16 tensors are accepted. The input
sum is recomputed in backward instead of saving another full activation.
"""

import torch
import triton
import triton.language as tl
from torch.autograd.function import once_differentiable


@triton.jit
def _forward(A, B, Y, N: tl.constexpr, D: tl.constexpr, BLOCK: tl.constexpr):
    i = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    row, col = i // D, i % D
    offset = row * (2 * D) + col
    dtype = A.dtype.element_ty
    gate = (tl.load(A + offset, i < N, 0).to(tl.float32)
            + tl.load(B + offset, i < N, 0).to(tl.float32)).to(dtype).to(tl.float32)
    up = (tl.load(A + offset + D, i < N, 0).to(tl.float32)
          + tl.load(B + offset + D, i < N, 0).to(tl.float32)).to(dtype).to(tl.float32)
    # Keep the separate SiLU output rounding of the eager expression.
    silu = (gate / (1.0 + tl.exp(-gate))).to(dtype).to(tl.float32)
    tl.store(Y + i, silu * up, i < N)


@triton.jit
def _backward(A, B, DY, DX, N: tl.constexpr, D: tl.constexpr, BLOCK: tl.constexpr):
    i = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    offset = (i // D) * (2 * D) + i % D
    dtype = A.dtype.element_ty
    gate = (tl.load(A + offset, i < N, 0).to(tl.float32)
            + tl.load(B + offset, i < N, 0).to(tl.float32)).to(dtype).to(tl.float32)
    up = (tl.load(A + offset + D, i < N, 0).to(tl.float32)
          + tl.load(B + offset + D, i < N, 0).to(tl.float32)).to(dtype).to(tl.float32)
    dy = tl.load(DY + i, i < N, 0).to(tl.float32)
    sigmoid = 1.0 / (1.0 + tl.exp(-gate))
    silu = (gate * sigmoid).to(dtype).to(tl.float32)
    # MulBackward materializes its output in the input dtype before SiLUBackward.
    dsilu = (dy * up).to(dtype).to(tl.float32)
    dgate = dsilu * (sigmoid * (1.0 + gate * (1.0 - sigmoid)))
    tl.store(DX + offset, dgate, i < N)
    tl.store(DX + offset + D, dy * silu, i < N)


class _AddSwiGLU(torch.autograd.Function):
    @staticmethod
    def forward(ctx, base, delta):
        width = base.shape[-1] // 2
        output = torch.empty((*base.shape[:-1], width), dtype=base.dtype, device=base.device)
        if output.numel():
            with torch.cuda.device(base.device):
                _forward[(triton.cdiv(output.numel(), 256),)](
                    base, delta, output, output.numel(), width, 256,
                    num_warps=4, enable_fp_fusion=False,
                )
        ctx.save_for_backward(base, delta)
        return output

    @staticmethod
    @once_differentiable
    def backward(ctx, grad):
        base, delta = ctx.saved_tensors
        grad = grad.contiguous()
        dx = torch.empty_like(base)
        if grad.numel():
            with torch.cuda.device(base.device):
                _backward[(triton.cdiv(grad.numel(), 256),)](
                    base, delta, grad, dx, grad.numel(), base.shape[-1] // 2, 256,
                    num_warps=4, enable_fp_fusion=False,
                )
        # Add has identical derivatives for both branches. Autograd owns the
        # accumulation; never modify either input or the shared gradient here.
        return (dx if ctx.needs_input_grad[0] else None,
                dx if ctx.needs_input_grad[1] else None)


def add_swiglu(base: torch.Tensor, delta: torch.Tensor) -> torch.Tensor:
    """Fuse elementwise addition and split-half SwiGLU.

    Args:
        base: Contiguous CUDA/HIP FP16 or BF16 tensor of shape (..., 2 * D),
            with at least two dimensions and D > 0.
        delta: Tensor with the same shape, dtype and device as ``base``.

    Returns:
        A tensor of shape (..., D), with the input dtype and device.

    Supports first-order autograd for either or both inputs and empty leading
    dimensions. Inputs are not mutated. No broadcasting, implicit dtype
    promotion or forward input copies are performed. Backward recomputes the
    rounded sum and makes the incoming gradient contiguous if necessary.

    Floating-point exp/reciprocal implementations can differ from native
    kernels; bitwise parity is not claimed. Higher-order gradients and
    torch.compile/fullgraph compatibility are not supported contracts.
    """
    if (not base.is_cuda or base.device != delta.device
            or base.dtype not in (torch.float16, torch.bfloat16)
            or delta.dtype != base.dtype or base.shape != delta.shape
            or base.ndim < 2 or base.shape[-1] == 0 or base.shape[-1] % 2
            or not base.is_contiguous() or not delta.is_contiguous()):
        raise ValueError("add_swiglu requires matching contiguous CUDA/HIP FP16/BF16 tensors with even nonzero width")
    return _AddSwiGLU.apply(base, delta)
