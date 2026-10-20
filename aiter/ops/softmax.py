# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
from typing import Optional

import torch
from torch import Tensor

from ..jit.core import compile_ops

__all__ = ["softmax", "softmax_out"]


def _validate(out: Tensor, input: Tensor, dim: int = -1) -> None:
    """Metadata checks also used by the fake implementation."""
    if input.ndim != 2 or dim not in (-1, 1):
        raise ValueError("softmax requires a 2D input and dim=-1 or 1")
    if not 1 <= input.shape[1] <= 524288:
        raise ValueError("softmax requires 1 <= D <= 524288")
    if input.dtype not in (torch.float16, torch.bfloat16, torch.float32):
        raise TypeError("softmax supports FP16, BF16 and FP32")
    if input.device.type not in ("cuda", "meta"):
        raise ValueError("softmax requires a GPU input")
    if not input.is_contiguous() or not out.is_contiguous():
        raise ValueError("softmax requires contiguous input and out")
    if out.shape != input.shape or out.dtype != input.dtype or out.device != input.device:
        raise ValueError("softmax out must match input shape, dtype and device")
    if torch.is_grad_enabled() and (input.requires_grad or out.requires_grad):
        raise RuntimeError("softmax is forward-only; use no_grad or inference_mode")


@compile_ops("module_softmax", gen_fake=_validate)
def softmax_out(out: Tensor, input: Tensor, dim: int = -1) -> None:
    """Write row-wise softmax to a disjoint, contiguous, preallocated output.

    Supports 2D GPU FP16/BF16/FP32 tensors, dim=-1 or 1, and 1 <= D <= 524288.
    Uses FP32 intermediates. Autograd is unsupported. B=0 is a no-op.
    """
    ...


def softmax(input: Tensor, dim: int = -1, *, out: Optional[Tensor] = None) -> Tensor:
    """Return row-wise softmax, allocating the output only when out is omitted.

    Input and out must be contiguous and must not overlap. Nonzero storage
    offsets are supported. See docs/softmax.md for the complete contract.
    """
    if out is None:
        out = torch.empty_like(input)
    _validate(out, input, dim)
    softmax_out(out, input, dim)
    return out
