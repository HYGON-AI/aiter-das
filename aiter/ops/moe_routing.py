# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Deterministic local MoE routing with fixed-capacity, graph-safe out APIs."""
from dataclasses import dataclass
from typing import Optional

import torch
from torch import Tensor

from ..jit.core import compile_ops, get_module

__all__ = ["RoutingBuffers", "allocate_moe_routing", "moe_routing_workspace_size",
           "moe_routing_prepare_out", "moe_routing_scatter_out", "moe_routing_gather_out",
           "moe_routing_cumsum_out", "check_moe_routing_status", "moe_init_routing_out",
           "moe_finalize_routing_out"]


@compile_ops("module_moe_utils", fc_name="moe_routing_workspace_size")
def _moe_routing_workspace_query(ids: Tensor) -> int: ...


def _native(anchor):
    try:
        return get_module("module_moe_utils")
    except ModuleNotFoundError:
        _moe_routing_workspace_query(anchor)
        return get_module("module_moe_utils")


def _tensor(t, like, dtype=None):
    if t.device != like.device or t.device.type not in ("cuda", "meta"):
        raise ValueError("routing tensors must be on the same GPU")
    if not t.is_contiguous():
        raise ValueError("routing tensors must be contiguous")
    if dtype is not None and t.dtype != dtype:
        raise TypeError("unexpected routing dtype")
    if t.requires_grad:
        raise RuntimeError("routing is forward-only")


def _ids(ids, E, alignment, expert_capacity=0):
    _tensor(ids, ids)
    if ids.ndim != 2 or ids.dtype not in (torch.int32, torch.int64):
        raise ValueError("ids must be int32/int64[M,K]")
    if not 1 <= ids.shape[1] <= 30 or ids.numel() > 2147483647:
        raise ValueError("routing requires 1<=K<=30 and M*K<=INT32_MAX")
    if not 1 <= E <= 1200 or alignment <= 0 or alignment & (alignment-1):
        raise ValueError("requires 1<=E<=1200 and power-of-two alignment")
    if expert_capacity < 0 or (expert_capacity and alignment != 1):
        raise ValueError("DropPad requires positive C and alignment=1")
    cap = E*expert_capacity if expert_capacity else ids.numel()+E*(alignment-1)
    if cap > 2147483647:
        raise ValueError("routing capacity exceeds INT32_MAX")
    return cap


def moe_routing_workspace_size(ids: Tensor) -> int:
    """Query bytes before capture; this may JIT-compile module_moe_utils."""
    _ids(ids, 1, 1)
    return _moe_routing_workspace_query(ids)


@dataclass(frozen=True)
class RoutingBuffers:
    counts: Tensor
    offsets: Tensor
    route_ids: Tensor
    inv_perm: Tensor
    token_ids: Tensor
    token_weights: Tensor
    m_indices: Tensor
    valid_rows: Tensor
    span_rows: Tensor
    status: Tensor
    workspace: Tensor
    E: int
    alignment: int
    expert_capacity: int

    def prepare(self, ids, weights, expert_map=None, active_num=None):
        moe_routing_prepare_out(ids, weights, expert_map, self.counts, self.offsets,
            self.route_ids, self.inv_perm, self.token_ids, self.token_weights,
            self.m_indices, self.valid_rows, self.span_rows, self.status, self.workspace,
            self.E, self.alignment, active_num, self.expert_capacity)


def allocate_moe_routing(ids: Tensor, E: int, alignment: int = 1,
                         expert_capacity: int = 0) -> RoutingBuffers:
    """Allocate once outside capture. All returned buffers are reused in place."""
    cap = _ids(ids, E, alignment, expert_capacity)
    def empty(shape, dtype=torch.int32):
        return torch.empty(shape, device=ids.device, dtype=dtype)
    return RoutingBuffers(empty((E,)), empty((E,)), empty((cap,)), empty(ids.shape),
        empty((cap,)), empty((cap,), torch.float32), empty((cap,)), empty((1,)),
        empty((1,)), empty((1,)), empty((moe_routing_workspace_size(ids),), torch.uint8),
        E, alignment, expert_capacity)


@torch.library.custom_op("aiter::moe_routing_prepare_out", mutates_args=(
    "counts", "offsets", "route_ids", "inv_perm", "token_ids", "token_weights",
    "m_indices", "valid_rows", "span_rows", "status", "workspace"))
def moe_routing_prepare_out(ids: Tensor, weights: Tensor, expert_map: Optional[Tensor],
    counts: Tensor, offsets: Tensor, route_ids: Tensor, inv_perm: Tensor, token_ids: Tensor,
    token_weights: Tensor, m_indices: Tensor, valid_rows: Tensor, span_rows: Tensor,
    status: Tensor, workspace: Tensor, E: int, alignment: int = 1,
    active_num: Optional[Tensor] = None, expert_capacity: int = 0) -> None:
    """Write stable (local expert, token-major route) metadata on the GPU."""
    _native(ids).moe_routing_prepare_out(ids, weights, expert_map, counts, offsets,
        route_ids, inv_perm, token_ids, token_weights, m_indices, valid_rows, span_rows,
        status, workspace, E, alignment, active_num, expert_capacity)


@moe_routing_prepare_out.register_fake
def _prepare_fake(ids, weights, expert_map, counts, offsets, route_ids, inv_perm,
    token_ids, token_weights, m_indices, valid_rows, span_rows, status, workspace,
    E, alignment=1, active_num=None, expert_capacity=0):
    cap = _ids(ids, E, alignment, expert_capacity)
    if weights.shape != ids.shape or inv_perm.shape != ids.shape:
        raise ValueError("ids/weights/inv_perm shape mismatch")
    _tensor(weights, ids, torch.float32)
    for t in (counts, offsets, route_ids, inv_perm, token_ids, m_indices, valid_rows, span_rows, status):
        _tensor(t, ids, torch.int32)
    for t in (counts, offsets):
        if t.shape != (E,): raise ValueError("counts/offsets must be [E]")
    for t in (valid_rows, span_rows, status):
        if t.shape != (1,): raise ValueError("device lengths/status must be [1]")
    for t in (route_ids, token_ids, token_weights, m_indices):
        if t.ndim != 1 or t.numel() != route_ids.numel(): raise ValueError("row metadata mismatch")
    if route_ids.numel() < cap: raise ValueError("insufficient routing capacity")
    _tensor(token_weights, ids, torch.float32); _tensor(workspace, ids, torch.uint8)
    if workspace.ndim != 1: raise ValueError("workspace must be uint8[bytes]")
    if expert_map is not None:
        _tensor(expert_map, ids, torch.int32)
        if expert_map.ndim != 1: raise ValueError("expert_map must be [G]")
    if active_num is not None:
        _tensor(active_num, ids, torch.int64)
        if active_num.numel() != 1: raise ValueError("active_num must be a device scalar")


_MODES = {"none": 0, "int8": 1, "fp8_e4m3fn": 2}


@torch.library.custom_op("aiter::moe_routing_scatter_out", mutates_args=("out", "out_scale"))
def _moe_routing_scatter_out(out: Tensor, out_scale: Optional[Tensor], input: Tensor,
    token_ids: Tensor, m_indices: Tensor, smooth: Optional[Tensor] = None,
    quant_mode: str = "none") -> None:
    """Copy floating rows or quantize X*smooth; padding is zero, scale one."""
    if quant_mode not in _MODES: raise ValueError("unsupported quantization mode")
    _native(token_ids).moe_routing_scatter_out(out, out_scale, input, token_ids, m_indices, smooth, _MODES[quant_mode])


@_moe_routing_scatter_out.register_fake
def _scatter_fake(out, out_scale, input, token_ids, m_indices, smooth=None, quant_mode="none"):
    mode = quant_mode
    if mode not in _MODES: raise ValueError("unsupported quantization mode")
    for t in (out, input, token_ids, m_indices): _tensor(t, input)
    if input.ndim != 2 or out.ndim != 2 or input.shape[1] <= 0 or out.shape[1] != input.shape[1]:
        raise ValueError("scatter expects matching 2D widths")
    if input.dtype not in (torch.float16, torch.bfloat16, torch.float32): raise TypeError("floating input required")
    for t in (token_ids, m_indices):
        if t.shape != (out.shape[0],) or t.dtype != torch.int32: raise ValueError("invalid row metadata")
    if mode == "none":
        if smooth is not None or out_scale is not None or out.dtype != input.dtype: raise ValueError("unquantized scatter preserves dtype, with no scale/smooth")
    else:
        dtype = torch.int8 if mode == "int8" else torch.float8_e4m3fn
        if out.dtype != dtype or out_scale is None: raise ValueError("quant output dtype/scale mismatch")
        _tensor(out_scale, input, torch.float32)
        if out_scale.shape not in ((out.shape[0],), (out.shape[0], 1)): raise ValueError("invalid scale shape")
    if smooth is not None:
        _tensor(smooth, input, torch.float32)
        if smooth.ndim != 2 or smooth.shape[1] != input.shape[1] or not 1 <= smooth.shape[0] <= 1200: raise ValueError("smooth must be [E,H]")


def moe_routing_scatter_out(out: Tensor, out_scale: Optional[Tensor], input: Tensor,
    token_ids: Tensor, m_indices: Tensor, smooth: Optional[Tensor] = None,
    mode: str = "none") -> None:
    """Write rows in place. The public mode keyword is stable across Torch versions."""
    # Torch 2.10/2.11 auto_functionalized_v2_fake reserves the keyword 'mode'.
    _moe_routing_scatter_out(out, out_scale, input, token_ids, m_indices, smooth, mode)


@torch.library.custom_op("aiter::moe_routing_gather_out", mutates_args=("out",))
def moe_routing_gather_out(out: Tensor, expert_output: Tensor, weights: Tensor,
    inv_perm: Tensor, m_indices: Tensor, bias: Optional[Tensor] = None,
    residual: Optional[Tensor] = None, res_scale: float = 1.0,
    residual_start: int = 0, residual_end: int = -1, x2: Optional[Tensor] = None) -> None:
    """Overwrite out using ordered FP32 accumulation, bias, SP residual and x2."""
    _native(inv_perm).moe_routing_gather_out(out, expert_output, weights, inv_perm,
        m_indices, bias, residual, res_scale, residual_start, residual_end, x2)


@moe_routing_gather_out.register_fake
def _gather_fake(out, expert_output, weights, inv_perm, m_indices, bias=None,
                 residual=None, res_scale=1.0, residual_start=0, residual_end=-1, x2=None):
    for t in (out, expert_output, weights, inv_perm, m_indices): _tensor(t, out)
    if out.ndim != 2 or expert_output.ndim != 2 or out.shape[1] <= 0 or out.shape[1] != expert_output.shape[1]: raise ValueError("gather width mismatch")
    if out.dtype not in (torch.float16,torch.bfloat16,torch.float32) or expert_output.dtype != out.dtype: raise TypeError("floating gather output required")
    if inv_perm.ndim != 2 or inv_perm.shape[0] != out.shape[0] or not 1 <= inv_perm.shape[1] <= 30 or weights.shape != inv_perm.shape: raise ValueError("gather metadata mismatch")
    _tensor(inv_perm,out,torch.int32); _tensor(weights,out,torch.float32); _tensor(m_indices,out,torch.int32)
    if m_indices.shape != (expert_output.shape[0],): raise ValueError("invalid m_indices")
    end = out.shape[0] if residual_end == -1 else residual_end
    if not 0 <= residual_start <= end <= out.shape[0]: raise ValueError("invalid residual interval")
    if bias is not None:
        _tensor(bias,out,torch.float32)
        if bias.ndim != 2 or bias.shape[1] != out.shape[1] or not 1 <= bias.shape[0] <= 1200: raise ValueError("bias must be [E,Hout]")
    if residual is not None:
        _tensor(residual,out,out.dtype)
        if residual.shape not in ((1,out.shape[1]),(end-residual_start,out.shape[1])): raise ValueError("invalid residual shape")
    if x2 is not None:
        _tensor(x2,out,out.dtype)
        if x2.shape != out.shape: raise ValueError("x2 must match out")


@torch.library.custom_op("aiter::moe_routing_cumsum_out", mutates_args=("out",))
def moe_routing_cumsum_out(out: Tensor, counts: Tensor) -> None:
    """Write inclusive valid-count sums; aligned offsets remain separate."""
    _native(counts).moe_routing_cumsum_out(out,counts)


@moe_routing_cumsum_out.register_fake
def _cumsum_fake(out,counts):
    _tensor(out,counts,torch.int32);_tensor(counts,counts,torch.int32)
    if counts.ndim != 1 or out.shape != counts.shape or not 1 <= counts.numel() <= 1200: raise ValueError("cumsum requires int32[E]")


def check_moe_routing_status(status: Tensor) -> None:
    """Explicit synchronizing diagnostic. Do not call inside capture or timing."""
    code = int(status.item())
    if code:
        raise ValueError({1: "active_num must be nonnegative", 2: "DropPad rejects nonzero active_num"}.get(code, "invalid routing status"))


def moe_init_routing_out(out, out_scale, input, ids, weights, buffers,
                         expert_map=None, smooth=None, mode="none", active_num=None):
    buffers.prepare(ids, weights, expert_map, active_num)
    moe_routing_scatter_out(out, out_scale, input, buffers.token_ids, buffers.m_indices, smooth, mode)


def moe_finalize_routing_out(out, expert_output, weights, buffers, bias=None,
    residual=None, res_scale=1.0, residual_start=0, residual_end=-1, x2=None):
    moe_routing_gather_out(out, expert_output, weights, buffers.inv_perm, buffers.m_indices,
        bias, residual, res_scale, residual_start, residual_end, x2)
