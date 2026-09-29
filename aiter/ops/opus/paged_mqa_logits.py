# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""FP8 paged MQA scoring on gfx936/gfx938/gfx946."""

from functools import lru_cache

import torch

from ...jit.core import compile_ops


@compile_ops("module_mqa_logits", fc_name="paged_mqa_logits_opus")
def _paged_mqa_logits_opus(q: torch.Tensor, cache: torch.Tensor,
                          weights: torch.Tensor, context: torch.Tensor,
                          tables: torch.Tensor, output: torch.Tensor,
                          max_len: int, kernel_id: int) -> None: ...


@compile_ops("module_mqa_logits", fc_name="paged_mqa_logits_alloc")
def _paged_mqa_logits_alloc(q: torch.Tensor, cache: torch.Tensor,
                            weights: torch.Tensor, context: torch.Tensor,
                            tables: torch.Tensor, max_len: int,
                            kernel_id: int, clean_logits: bool) -> torch.Tensor: ...


@lru_cache(maxsize=None)
def _require_arch(device_index):
    arch = torch.cuda.get_device_properties(device_index).gcnArchName.split(":")[0]
    if arch not in ("gfx936", "gfx938", "gfx946"):
        raise NotImplementedError(f"paged_mqa_logits supports gfx936/gfx938/gfx946, got {arch}")
    return arch


def _resolve_paged_mqa_kernel(kernel_id, *, rows, max_len, arch="gfx938",
                              heads=32, next_n=1, cache_tokens=None):
    if arch == "gfx946":
        # PMD verifies correctness, not production performance thresholds.
        if kernel_id is None:
            return 4
        if type(kernel_id) is not int or kernel_id not in (4, 5):
            raise ValueError("gfx946 kernelId must be None, 4 (K32), or 5 (K64 prefetch)")
        return kernel_id
    if arch not in ("gfx936", "gfx938"):
        raise NotImplementedError(f"paged_mqa_logits does not support {arch}")
    if kernel_id is None:
        # Shape metadata limits preparation cost. The kernel still verifies
        # every used page ID and request length before sharing any K data.
        return 7 if (heads == 32 and next_n == 1 and rows >= 32 and max_len >= (4096 if arch == "gfx936" else 16384)
                     and cache_tokens is not None and cache_tokens <= 2*max_len) else 6
    allowed = (6, 7) if arch == "gfx936" else (0, 1, 2, 3, 6, 7)
    if type(kernel_id) is not int or kernel_id not in allowed:
        raise ValueError(f"{arch} kernelId must be None or one of {allowed}")
    if kernel_id == 7 and (heads != 32 or next_n != 1):
        raise ValueError("kernelId=7 requires H=32 and R=1")
    return kernel_id


def paged_mqa_logits(q, kv_cache, weights, context_lens, block_tables,
                     max_model_len, *, out=None, clean_logits=True, kernelId=None):
    """Return FP32 weighted-ReLU QK scores ``[B*R,max_model_len]``.

    Supported: gfx936/gfx938/gfx946; contiguous Q E4M3FN [B,R,H,128], R=1/2/4,
    H=32/64; uint8 KV [P,S,1,132]. S=1/64 on gfx936/gfx938; S=1 on gfx946.
    Each page contains S*128 K bytes
    followed by S positive finite FP32 scales (not interleaved for S=64).
    FP32 weights [B*R,H]; int32 lengths [B]
    and page tables [B,T]. Q/cache addresses must be 4-byte aligned.

    Caller metadata obligations: R<=length[b]<=min(max_model_len,T*S),
    valid page ids in [0,P), and positive finite scales. These device values
    are not read back to the host in the hot path. Query r sees candidates
    n<length[b]-R+r+1. Weights may be negative. Inputs are inference-only.

    On gfx936/gfx938, ID6 is a four-wave paged pipeline. ID7 groups two
    queries when H=32,R=1. It verifies all used page IDs and lengths on GPU;
    nonmatching groups execute independently. Auto selects ID7 for B>=32,
    P*S<=2*max_model_len and max_model_len>=4096 on gfx936 or >=16384 on gfx938;
    otherwise it selects ID6.
    ID7 repacks S=1 cache into aligned physical blocks on every call. gfx936
    converts Q exactly to FP16; its S64 independent path decodes KV in registers
    without a full converted KV buffer, preserving FP8 subnormals and signed zero.
    Reused/small caches and S1 retain vectorized global conversion. gfx938 uses
    native FP8 MMAC with MLS on aligned S64: N64 for B*R*max_model_len<=16384,
    N128 for <=32768, and N256 for larger grids.
    S1 and 4-byte offset views retain the buffer-load path. Preparation is timed.
    Approximate scratch: gfx936 direct S64 uses 2*Q.numel() bytes; conversion
    paths additionally use 260*ceil(P*S/64)*64 bytes. ID7 gfx938 S1 uses
    132*ceil(P/64)*64 bytes. Grouped paths also allocate checked page metadata.
    Explicit gfx938 IDs 0-3 retain the original S=1 Opus paths for comparison.
    On gfx946, None selects ID4 (K32); explicit ID5 uses K64 prefetch.
    IDs 4/5 use the N64 DPP pipeline with 8-byte aligned LDS row strides
    and fused invalid-tail writes. gfx946 is validated on Perf Model;
    physical-device correctness and performance tuning remain pending.
    IDs 4/5 and S=1 remain the only supported gfx946 path.
    No Triton fallback is imported. Unsupported shapes/architectures raise.
    ``out`` may be preallocated and must not share storage with inputs.
    With ``clean_logits=True`` (default), invalid output is -inf, including
    the far tail. With False the caller owns tail initialization/masking.
    Allocation/fill occur on the current stream; no host synchronization is
    performed. Warm up the JIT before capturing the call in a GPU graph.
    """
    # The eager allocating entry validates tensor metadata and allocates on the
    # current stream in C++. Compiled and supplied-output calls retain the
    # registered preallocated operator below.
    if out is None and not torch.compiler.is_compiling():
        if type(max_model_len) is not int or not 0 < max_model_len < 2**31:
            raise ValueError("max_model_len must be a positive int32 value")
        if type(clean_logits) is not bool:
            raise ValueError("clean_logits must be bool")
        if kernelId is not None and (type(kernelId) is not int or not 0 <= kernelId <= 7):
            raise ValueError("kernelId must be None or an integer in [0,7]")
        if kernelId == 7 and q.ndim == 4 and (q.shape[2] != 32 or q.shape[1] != 1):
            raise ValueError("kernelId=7 requires H=32 and R=1")
        return _paged_mqa_logits_alloc(q,kv_cache,weights,context_lens,block_tables,
                                      max_model_len,-1 if kernelId is None else kernelId,clean_logits)
    inputs = (q, kv_cache, weights, context_lens, block_tables)
    if any(not t.is_cuda or t.device != q.device for t in inputs):
        raise ValueError("inputs must be on the same GPU")
    arch = _require_arch(q.device.index)
    if any(not t.is_contiguous() or t.requires_grad for t in inputs):
        raise ValueError("inputs must be contiguous inference tensors")
    if q.ndim != 4 or q.dtype != torch.float8_e4m3fn:
        raise ValueError("q must be E4M3FN [B,R,H,128]")
    b, r, h, d = q.shape
    if b < 1 or b*r > 65535 or r not in (1,2,4) or h not in (32,64) or d != 128:
        raise ValueError("requires B>0, B*R<=65535, R=1/2/4, H=32/64, D=128")
    if (kv_cache.ndim != 4 or kv_cache.dtype != torch.uint8
            or kv_cache.shape[1] not in (1,64)
            or tuple(kv_cache.shape[2:]) != (1,132)
            or not 0 < kv_cache.shape[0] <= (2**31-1)//(kv_cache.shape[1]*132)):
        raise ValueError("cache must be uint8 [P,S,1,132], S=1/64, P*S*132<=INT_MAX")
    if q.data_ptr()%4 or kv_cache.data_ptr()%4:
        raise ValueError("Q/cache must have 4-byte aligned storage")
    if weights.dtype != torch.float32 or tuple(weights.shape) != (b*r,h):
        raise ValueError("weights must be FP32 [B*R,H]")
    if context_lens.dtype != torch.int32 or tuple(context_lens.shape) != (b,):
        raise ValueError("context_lens must be int32 [B]")
    if (block_tables.dtype != torch.int32 or block_tables.ndim != 2
            or block_tables.shape[0] != b or not 0 < block_tables.shape[1] < 2**31):
        raise ValueError("block_tables must be int32 [B,T]")
    if type(max_model_len) is not int or not 0 < max_model_len < 2**31:
        raise ValueError("max_model_len must be a positive int32 value")
    kid = _resolve_paged_mqa_kernel(kernelId,rows=b*r,max_len=max_model_len,arch=arch,
                                     heads=h,next_n=r,cache_tokens=kv_cache.shape[0]*kv_cache.shape[1])
    if kid < 6 and kv_cache.shape[1] != 1:
        raise ValueError("kernel IDs 0-5 require cache page size S=1")
    if type(clean_logits) is not bool:
        raise ValueError("clean_logits must be bool")
    if out is None:
        out = torch.empty((b*r,max_model_len), device=q.device, dtype=torch.float32)
    if (out.device != q.device or out.dtype != torch.float32 or out.requires_grad
            or not out.is_contiguous() or tuple(out.shape) != (b*r,max_model_len)):
        raise ValueError("out must be contiguous FP32 [B*R,max_model_len] on input GPU")
    if any(out.untyped_storage().data_ptr() == t.untyped_storage().data_ptr() for t in inputs):
        raise ValueError("out must not share storage with inputs")
    if clean_logits and kid < 2:
        out.fill_(-float("inf"))
    _paged_mqa_logits_opus(q,kv_cache,weights,context_lens,block_tables,out,max_model_len,kid)
    return out
