# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2025, Advanced Micro Devices, Inc. All rights reserved.

import torch

from ..jit.core import (
    compile_ops,
)

MD_NAME = "module_quick_all_reduce"


@compile_ops("module_quick_all_reduce", develop=True)
def init_custom_qr(
    rank: int, world_size: int, qr_max_size: int | None = None
) -> int: ...


@compile_ops("module_quick_all_reduce", develop=True)
def qr_destroy(fa: int) -> None: ...


@compile_ops("module_quick_all_reduce", develop=True)
def qr_all_reduce(
    fa: int,
    inp: torch.Tensor,
    out: torch.Tensor,
    quant_level: int,
    cast_bf2half: bool = False,
) -> None: ...


@compile_ops("module_quick_all_reduce", develop=True)
def qr_all_reduce_rmsnorm(
    fa: int,
    inp: torch.Tensor,
    residual_inp: torch.Tensor,
    residual_out: torch.Tensor,
    out: torch.Tensor,
    weight: torch.Tensor,
    eps: float,
    hidden_dim: int,
    quant_level: int,
    cast_bf2half: bool = False,
) -> None: ...


@compile_ops("module_quick_all_reduce", fc_name="qr_get_handle", develop=True)
def _qr_get_handle(fa: int, out_ptr: int) -> None: ...


@compile_ops("module_quick_all_reduce", fc_name="qr_open_handles", develop=True)
def _qr_open_handles(fa: int, handle_ptrs: list[int]) -> None: ...


@compile_ops("module_quick_all_reduce", develop=True)
def qr_max_size() -> int: ...


def qr_get_handle(fa: int, out_ptr: int | None = None):
    """Return a CPU uint8[64] handle, or fill an explicitly owned host pointer."""
    if out_ptr is None:
        handle = torch.empty(64, dtype=torch.uint8, device="cpu")
        _qr_get_handle(fa, handle.data_ptr())
        return handle
    if type(out_ptr) is not int or out_ptr <= 0:
        raise ValueError("out_ptr must be a valid host handle pointer")
    _qr_get_handle(fa, out_ptr)


def qr_open_handles(fa: int, handle_ptrs: list):
    """Accept legacy CPU handle tensors or the upstream host-pointer list.

    Tensor handles stay alive until the native call has copied their bytes.
    Integer pointers are a low-level ABI: their host ownership is the caller's
    responsibility, as with qr_get_handle(fa, out_ptr).
    """
    handles = handle_ptrs
    if not isinstance(handles, (list, tuple)) or not handles:
        raise ValueError("handles must be a nonempty list")
    pointers = []
    for handle in handles:
        if isinstance(handle, torch.Tensor):
            if handle.device.type != "cpu" or handle.dtype != torch.uint8 or handle.numel() != 64 or not handle.is_contiguous():
                raise ValueError("QR tensor handles must be contiguous CPU uint8[64]")
            pointers.append(handle.data_ptr())
        elif type(handle) is int and handle > 0:
            pointers.append(handle)
        else:
            raise ValueError("QR handles must be CPU tensors or host pointers")
    _qr_open_handles(fa, pointers)
