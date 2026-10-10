# SPDX-License-Identifier: MIT
# Copyright (C) 2026, Advanced Micro Devices, Inc. All rights reserved.
"""HCU Iris RS + RMSNorm + optional FP8 + AG, with one owner per row.

API follows ROCm/aiter 89a47b84. A whole row stays within one program so
normalization never consumes partial reduce-scatter tiles from another CU.
The public call is eager-only because it coordinates peers on the host.
"""
import math

import iris
import torch
import torch.distributed as dist
import triton
import triton.language as tl


@triton.jit
def _fp8_bits(x):
    """Saturating E4M3FN round-to-nearest-even without native FP8 conversion."""
    bits = x.to(tl.uint32, bitcast=True)
    magnitude = bits & 0x7FFFFFFF
    rounded = magnitude + 0x7FFFF + ((magnitude >> 20) & 1)
    normal = ((rounded >> 20).to(tl.int32) - 960)
    scaled = tl.abs(x) * 512.0
    base = scaled.to(tl.int32)
    fraction = scaled - base.to(tl.float32)
    subnormal = base + ((fraction > 0.5) | ((fraction == 0.5) & ((base & 1) != 0))).to(tl.int32)
    code = tl.where(magnitude < 0x3C800000, subnormal, normal)
    code = tl.minimum(tl.maximum(code, 0), 126)
    code = tl.where(magnitude > 0x7F800000, 127, code)
    return (code.to(tl.uint32) | ((bits >> 24) & 128)).to(tl.uint8)


@triton.jit
def _pipeline(input_ptr, gamma_ptr, rs_ptr, norm_ptr, quant_ptr, gather_ptr,
              heap_bases, rows: tl.constexpr, cols: tl.constexpr,
              rank: tl.constexpr, world: tl.constexpr, eps: tl.constexpr,
              QUANT: tl.constexpr, GATHER: tl.constexpr, BLOCK: tl.constexpr):
    row = tl.program_id(0)
    col = tl.arange(0, BLOCK)
    mask = col < cols
    source = input_ptr + (rank * rows + row) * cols + col
    total = tl.full((BLOCK,), 0, tl.float32)
    for peer in tl.static_range(world):
        value = iris.load(source, rank, peer, heap_bases, mask=mask)
        total += tl.where(mask, value.to(tl.float32), 0.0)
    # Match the upstream RS output storage boundary before RMSNorm.
    reduced = total.to(rs_ptr.dtype.element_ty)
    tl.store(rs_ptr + row * cols + col, reduced, mask=mask)
    reduced_f = reduced.to(tl.float32)
    inv = tl.rsqrt(tl.sum(tl.where(mask, reduced_f * reduced_f, 0.0), 0) / cols + eps)
    gamma = tl.load(gamma_ptr + col, mask=mask, other=0).to(tl.float32)
    normalized = reduced_f * inv * gamma
    tl.store(norm_ptr + row * cols + col, normalized, mask=mask)
    if QUANT:
        maximum = tl.max(tl.where(mask, tl.abs(normalized), 0.0), 0)
        # Approximate reciprocal division can cross an FP8 halfway point.
        # Keep scale construction and normalization correctly rounded.
        scale = tl.maximum(tl.div_rn(maximum, 448.0), 1.0e-8)
        scaled = tl.minimum(tl.maximum(tl.div_rn(normalized, scale), -448.0), 448.0)
        result = _fp8_bits(scaled)
        tl.store(quant_ptr + row * cols + col, result, mask=mask)
    else:
        result = normalized.to(gather_ptr.dtype.element_ty)
    if GATHER:
        destination = gather_ptr + (rank * rows + row) * cols + col
        for peer in tl.static_range(world):
            iris.store(destination, result, rank, peer, heap_bases, mask=mask)


def reduce_scatter_rmsnorm_quant_all_gather(
    input_tensor, gamma, epsilon=1e-6, ctx=None, quant_mode="none",
    do_allgather=True, rs_buffer=None, norm_buffer=None, fp8_out=None,
    gather_out=None,
):
    """Return ``(FP32 normalized shard, FP8 shard, full gathered output)``.

    Exactly one of the first two entries is returned, according to quant_mode.
    As in upstream, FP8 uses independent per-token scales and the tuple does
    not return them. Nonquantized gathered output has the input dtype.
    Optional buffers are reusable; gather_out must be symmetric Iris memory.
    All ranks must use the same options, shapes and symmetric heap offsets.
    """
    if ctx is None or not ctx.is_initialized:
        raise RuntimeError("Use an initialized IrisCommContext")
    # Checks heap ownership, producer shape and launch agreement, and rejects
    # Graph before any host collective or allocation.
    ctx.validate_collective(input_tensor, "reduce_scatter", 1, 1, 1, 1, output_bytes=0)
    m, n = input_tensor.shape
    rows = m // ctx.num_ranks
    dtype = input_tensor.dtype
    device = input_tensor.device
    quant = quant_mode == "fp8_per_token"
    output_dtype = torch.float8_e4m3fn if quant else dtype
    error = None
    if quant_mode not in ("none", "fp8_per_token"):
        error = "quant_mode must be none or fp8_per_token"
    elif not isinstance(do_allgather, bool):
        error = "do_allgather must be boolean"
    elif not math.isfinite(epsilon) or epsilon <= 0:
        error = "epsilon must be finite and positive"
    elif n > 16384:
        error = "HCU Iris fusion currently supports hidden dimensions <= 16384"
    elif gamma.shape != (n,) or gamma.device != device or not gamma.is_contiguous() or gamma.dtype not in (torch.float32, torch.float16, torch.bfloat16):
        error = "gamma must be contiguous FP32/FP16/BF16 [N] on the input device"
    buffers = ((rs_buffer, (rows, n), dtype), (norm_buffer, (rows, n), torch.float32),
               (fp8_out, (rows, n), torch.float8_e4m3fn),
               (gather_out, (m, n), output_dtype))
    for b, shape, expected_dtype in buffers:
        if b is not None and (b.shape != shape or b.dtype != expected_dtype or b.device != device or not b.is_contiguous()):
            error = "Preallocated buffers must match expected shape, dtype, device and contiguous layout"
    pool = ctx.iris_ctx.memory_pool
    if gather_out is not None and do_allgather:
        lo = gather_out.data_ptr() - pool.data_ptr()
        if lo < 0 or lo + gather_out.numel() * gather_out.element_size() > ctx.heap_size:
            error = "gather_out must belong to the Iris symmetric heap"
    intervals = [(input_tensor.data_ptr(), input_tensor.data_ptr() + input_tensor.numel() * input_tensor.element_size())]
    for b, _, _ in buffers:
        if b is not None:
            span = (b.data_ptr(), b.data_ptr() + b.numel() * b.element_size())
            if any(span[0] < hi and lo < span[1] for lo, hi in intervals):
                error = "Input and output buffers must not overlap"
            intervals.append(span)
    needed = 0
    if rs_buffer is None:
        needed += math.ceil(rows * n * input_tensor.element_size() / 1024) * 1024
    if quant and fp8_out is None:
        needed += math.ceil(rows * n / 1024) * 1024
    if do_allgather and gather_out is None:
        elem = 1 if quant else input_tensor.element_size()
        needed += math.ceil(m * n * elem / 1024) * 1024
    if ctx.iris_ctx.heap_offset + needed > ctx.heap_size:
        error = "Insufficient symmetric heap capacity for fused outputs"
    metadata = (quant_mode, do_allgather, epsilon, str(gamma.dtype),
                tuple(b is None for b, _, _ in buffers),
                None if gather_out is None else gather_out.data_ptr() - pool.data_ptr())
    records = [None] * ctx.num_ranks
    dist.all_gather_object(records, (error, metadata))
    if any(r[0] for r in records):
        raise ValueError(f"Invalid Iris fusion arguments: {[r[0] for r in records]}")
    if any(r[1] != metadata for r in records):
        raise ValueError("All ranks must use matching fusion options and gather offsets")
    if rs_buffer is None:
        rs_buffer = ctx.iris_ctx.empty((rows, n), dtype=dtype)
    if norm_buffer is None:
        norm_buffer = torch.empty((rows, n), dtype=torch.float32, device=device)
    if quant and fp8_out is None:
        fp8_out = ctx.iris_ctx.empty((rows, n), dtype=torch.float8_e4m3fn)
    if do_allgather and gather_out is None:
        gather_out = ctx.iris_ctx.empty((m, n), dtype=output_dtype)
    ctx.iris_ctx.barrier()
    quant_ptr = fp8_out.view(torch.uint8) if quant else norm_buffer
    gather_ptr = (gather_out.view(torch.uint8) if quant else gather_out) if do_allgather else input_tensor
    _pipeline[(rows,)](input_tensor, gamma, rs_buffer, norm_buffer, quant_ptr,
                      gather_ptr, ctx.get_heap_bases(), rows, n, ctx.cur_rank,
                      ctx.num_ranks, epsilon, quant, do_allgather,
                      triton.next_power_of_2(n), num_warps=4 if n <= 2048 else 8)
    ctx.iris_ctx.barrier()
    return (None if quant else norm_buffer, fp8_out if quant else None,
            gather_out if do_allgather else None)
