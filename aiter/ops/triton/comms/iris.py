# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2025, Advanced Micro Devices, Inc. All rights reserved.

"""
Minimal Iris context wrapper for AITER communication operations.

This module provides a thin wrapper around the iris library context to
support reduce-scatter and all-gather operations. All core iris functions
(load, store, put, atomic_*, etc.) are provided by the iris library itself.
"""

import logging
import math
import ctypes

import iris
import torch
import torch.distributed as dist

# If we got here, iris is available
IRIS_AVAILABLE = True

logger = logging.getLogger("aiter")


def calculate_heap_size(
    M: int,
    N: int,
    dtype: "torch.dtype",
    world_size: int | None = None,
    quant_mode: str = "none",
    all_gather: bool = True,
    overhead_factor: float = 1.2,
) -> int:
    """
    Calculate required Iris heap size for communication operations.

    This function estimates the total memory needed in the Iris symmetric heap
    for reduce-scatter, RMSNorm, quantization, and all-gather operations.

    Args:
        M (int): Number of rows in input tensor
        N (int): Number of columns in input tensor
        dtype (torch.dtype): Data type of input tensor (e.g., torch.float32, torch.float16)
        world_size (int, optional): Number of GPUs. If None, uses torch.distributed.get_world_size()
        quant_mode (str): Quantization mode - "none", "fp8_per_token", or "fp4_per_token"
        all_gather (bool): Whether all-gather is performed after quantization
        overhead_factor (float): Safety margin multiplier (default: 1.2 for 20% overhead)

    Returns:
        int: Required heap size in bytes

    Example:
        >>> # For 2 GPUs, 4096x4096 float32 tensor with FP8 quant and all-gather
        >>> heap_size = calculate_heap_size(4096, 4096, torch.float32,
        ...                                  world_size=2, quant_mode="fp8_per_token")
        >>> with IrisCommContext(heap_size=heap_size) as ctx:
        ...     # Your operations here
        ...     pass
    """
    if world_size is None:
        if not torch.distributed.is_initialized():
            raise RuntimeError(
                "torch.distributed not initialized and world_size not provided. "
                "Either initialize torch.distributed or pass world_size explicitly."
            )
        world_size = torch.distributed.get_world_size()

    if not all(isinstance(v, int) and not isinstance(v, bool) and v > 0 for v in (M, N, world_size)):
        raise ValueError("M, N and world_size must be positive integers")
    if M % world_size:
        raise ValueError("M must be divisible by world_size")
    if quant_mode not in ("none", "fp8_per_token", "fp4_per_token"):
        raise ValueError("Unknown quant_mode")
    if not math.isfinite(overhead_factor) or overhead_factor < 1:
        raise ValueError("overhead_factor must be finite and >= 1")

    # Calculate element size in bytes (fast path for common types)
    if dtype in (torch.float32, torch.int32):
        elem_bytes = 4
    elif dtype in (torch.float16, torch.bfloat16, torch.int16):
        elem_bytes = 2
    elif dtype in (torch.float64, torch.int64):
        elem_bytes = 8
    elif dtype == torch.int8:
        elem_bytes = 1
    else:
        # Fallback for uncommon types (e.g., float8, complex types, future dtypes)
        elem_bytes = torch.empty(0, dtype=dtype).element_size()

    M_shard = M // world_size

    # Memory for input tensor (M x N)
    mem_input = M * N * elem_bytes

    # Memory for reduce-scatter output (M_shard x N)
    mem_rs = M_shard * N * elem_bytes

    # Memory for quantization output
    mem_quant = 0
    if quant_mode == "fp8_per_token":
        mem_quant = M_shard * N  # 1 byte per element
    elif quant_mode == "fp4_per_token":
        if N % 32 != 0:
            raise ValueError("FP4 quantization requires N divisible by 32")
        mem_quant = M_shard * (N // 2)  # 0.5 bytes per element

    # Memory for all-gather output
    mem_gather = 0
    if all_gather:
        if quant_mode == "fp8_per_token":
            mem_gather = M * N  # 1 byte per element
        elif quant_mode == "fp4_per_token":
            mem_gather = M * (N // 2)  # 0.5 bytes per element
        else:
            mem_gather = M * N * elem_bytes  # Full precision

    # Total with overhead
    # Every Iris allocation is aligned to 1024 bytes. Include scale storage
    # for callers that allocate per-token quantization intermediates.
    mem_scale = M_shard * 4 if quant_mode != "none" else 0
    total_bytes = sum(math.ceil(n / 1024) * 1024 for n in
                      (mem_input, mem_rs, mem_quant, mem_gather, mem_scale))
    total_with_overhead = math.ceil(total_bytes * overhead_factor)

    logger.debug(
        "Heap size calculation: M=%d, N=%d, dtype=%s, world_size=%s, "
        "quant_mode=%s, all_gather=%s\n"
        "  Input: %d bytes\n"
        "  RS buffer: %d bytes\n"
        "  Quant buffer: %d bytes\n"
        "  Gather buffer: %d bytes\n"
        "  Total (with %fx overhead): %d bytes (%.2f GB)",
        M,
        N,
        dtype,
        world_size,
        quant_mode,
        all_gather,
        mem_input,
        mem_rs,
        mem_quant,
        mem_gather,
        overhead_factor,
        total_with_overhead,
        total_with_overhead / (1024**3),
    )

    return total_with_overhead


class IrisCommContext:
    """
    Minimal context wrapper for Iris-based communication operations.

    This is a thin wrapper around iris.iris() that provides convenient access
    to the iris context for use in reduce-scatter and all-gather operations.

    Example:
        >>> # Manual heap size
        >>> with IrisCommContext(heap_size=2**30) as ctx:
        >>>     shard = ctx.iris_ctx.zeros((1024, 1024), dtype=torch.float32)
        >>>     full = all_gather(shard, ctx)

        >>> # Automatic heap size calculation
        >>> heap_size = calculate_heap_size(4096, 4096, torch.float32,
        ...                                  world_size=2, quant_mode="fp8_per_token")
        >>> with IrisCommContext(heap_size=heap_size) as ctx:
        >>>     # Guaranteed to have enough memory for your operations
        >>>     input_tensor = ctx.iris_ctx.empty((4096, 4096), dtype=torch.float32)
    """

    def __init__(self, heap_size: int = 1 << 30):
        """
        Initialize Iris communication context.

        Args:
            heap_size (int): Size of the symmetric heap in bytes. Default: 1GB
                Use calculate_heap_size() to automatically determine the required size
                based on your tensor dimensions and operations.

        Example:
            >>> # Option 1: Fixed size
            >>> ctx = IrisCommContext(heap_size=2**30)  # 1GB

            >>> # Option 2: Auto-calculated size
            >>> M, N = 4096, 4096
            >>> heap_size = calculate_heap_size(M, N, torch.float32,
            ...                                  world_size=2, quant_mode="fp8_per_token")
            >>> ctx = IrisCommContext(heap_size=heap_size)
        """
        if not IRIS_AVAILABLE:
            raise RuntimeError("Iris library is not available. Please install iris.")

        self.heap_size = heap_size
        if not isinstance(heap_size, int) or heap_size <= 0:
            raise ValueError("heap_size must be a positive integer")
        self.iris_ctx = None
        self._initialized = False

    def __enter__(self):
        """Initialize Iris context when entering context manager."""
        if torch.cuda.is_current_stream_capturing():
            raise RuntimeError("Iris communication currently supports eager execution only")
        if not dist.is_initialized():
            raise RuntimeError("Initialize a Gloo process group before IrisCommContext")
        if str(dist.get_backend()).lower() != "gloo":
            raise RuntimeError("IrisCommContext requires a Gloo process group for host coordination")
        if not iris.hip._is_amd_backend:
            raise RuntimeError("IrisCommContext currently supports HIP only")
        if not self._initialized:
            from aiter.dist.parallel_state import in_the_same_node_as
            if not all(in_the_same_node_as(dist.group.WORLD, source_rank=0)):
                raise RuntimeError("Iris IPC requires all ranks on the same node")
            sizes = [None] * dist.get_world_size()
            dist.all_gather_object(sizes, self.heap_size)
            if len(set(sizes)) != 1:
                raise ValueError("All ranks must use the same Iris heap_size")
            self.iris_ctx = iris.iris(heap_size=self.heap_size)
            self._initialized = True
            self.cur_rank = self.iris_ctx.cur_rank
            self.num_ranks = self.iris_ctx.num_ranks

            logger.info(
                "Iris context initialized: rank %d/%d, heap_size=%d",
                self.cur_rank,
                self.num_ranks,
                self.heap_size,
            )
        return self

    def __exit__(self, exc_type, exc_val, exc_tb):
        """
        Clean up when exiting context manager.

        Used by Python's with statement (automatically called).

        Example:
            with IrisCommContext(...) as ctx:
                pass
            # __exit__() is called here automatically
        """
        self.close()

    def close(self):
        """Collectively detach peer IPC mappings; existing local views stay valid.

        Call on every rank after the last collective. This pinned Iris version
        has no close method, so the wrapper releases each imported HIP mapping.
        PyTorch owns the local allocation and releases it after its last view.
        """
        if not self._initialized:
            return
        if torch.cuda.is_current_stream_capturing():
            raise RuntimeError("Cannot close an Iris context during graph capture")
        ctx = self.iris_ctx
        with torch.cuda.device(ctx.memory_pool.device):
            ctx.barrier()
            addresses = ctx.heap_bases.cpu().tolist()
            runtime = iris.hip.gpu_runtime
            if not iris.hip._is_amd_backend:
                raise RuntimeError("This Iris context lifecycle currently supports HIP only")
            close = runtime.hipIpcCloseMemHandle
            close.argtypes = [ctypes.c_void_p]
            close.restype = ctypes.c_int
            errors = []
            for rank, address in enumerate(addresses):
                if rank != ctx.cur_rank:
                    rc = close(ctypes.c_void_p(address))
                    if rc:
                        errors.append((rank, rc))
            peer_errors = [None] * ctx.num_ranks
            dist.all_gather_object(peer_errors, errors)
            # CCL holds a back-reference to Iris; break that cycle explicitly.
            ctx.ccl = None
            self.iris_ctx = None
            self._initialized = False
            if any(peer_errors):
                raise RuntimeError(f"Iris IPC detach failed: {peer_errors}")

    def validate_collective(self, tensor, op, block_m, block_n, group_size_m, num_sms, output_bytes=None):
        """Collectively reject invalid layouts or asymmetric heap allocations."""
        if torch.cuda.is_current_stream_capturing():
            raise RuntimeError("Iris communication currently supports eager execution only")
        ctx = self.iris_ctx
        error = None
        if tensor.ndim != 2 or not tensor.is_contiguous() or tensor.numel() == 0:
            error = "Input must be a nonempty contiguous 2-D tensor"
        elif tensor.dtype not in (torch.float16, torch.bfloat16, torch.float32):
            error = "Input dtype must be FP16, BF16 or FP32"
        elif tensor.device != ctx.memory_pool.device:
            error = "Input must reside on the context device"
        elif tensor.data_ptr() < ctx.memory_pool.data_ptr() or (
            tensor.data_ptr() + tensor.numel() * tensor.element_size()
            > ctx.memory_pool.data_ptr() + ctx.heap_size
        ):
            error = "Input must be allocated from this Iris symmetric heap"
        elif op == "reduce_scatter" and tensor.shape[0] % ctx.num_ranks:
            error = "Input rows must be divisible by world_size"
        elif any(not isinstance(v, int) or v <= 0 for v in (block_m, block_n, group_size_m, num_sms)):
            error = "Launch dimensions must be positive integers"
        elif block_m & (block_m - 1) or block_n & (block_n - 1):
            error = "block_m and block_n must be powers of two"
        if error is None:
            if output_bytes is None:
                output_bytes = tensor.numel() * tensor.element_size()
                output_bytes = output_bytes * ctx.num_ranks if op == "all_gather" else output_bytes // ctx.num_ranks
            if ctx.heap_offset + math.ceil(output_bytes / ctx.alignment) * ctx.alignment > ctx.heap_size:
                error = "Insufficient symmetric heap capacity"
        metadata = (op, tuple(tensor.shape), str(tensor.dtype), tensor.data_ptr() - ctx.memory_pool.data_ptr(),
                    ctx.heap_offset, block_m, block_n, group_size_m, num_sms)
        records = [None] * ctx.num_ranks
        dist.all_gather_object(records, (error, metadata))
        if any(r[0] is not None for r in records):
            raise ValueError(f"Invalid Iris collective inputs: {[r[0] for r in records]}")
        if any(r[1] != metadata for r in records):
            raise ValueError("Ranks must use matching shapes, dtypes, launch settings and symmetric heap offsets")

    @property
    def is_initialized(self) -> bool:
        """Check if the Iris context has been initialized."""
        return self._initialized

    def get_heap_bases(self):
        """Get the heap bases tensor for use in Triton kernels."""
        if not self.is_initialized:
            raise RuntimeError("Iris context not initialized. Use as context manager.")
        return self.iris_ctx.heap_bases
