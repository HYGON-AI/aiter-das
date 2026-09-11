# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Test-only adapters for the existing gfx938 paged MQA Triton kernels.

All Triton launch compatibility lives here. No production dispatch flags are
changed, and no Triton computation kernel is copied. Preparation validates GPU
metadata values and allocates padded stage1 scratch outside measured launches.
The prepared input tensors must retain their shapes, storage and valid metadata.
"""

import hashlib
import importlib
from pathlib import Path

import torch


class PagedMQATritonBaseline:
    def __init__(self, q, kv_cache, weights, context_lens, block_tables,
                 max_model_len, *, chunk_k=256, waves_per_eu=2,
                 preshuffle=False, varctx_schedule=None):
        if preshuffle or varctx_schedule is not None:
            raise ValueError("plain baseline requires no preshuffle/VarCtx schedule")
        if not isinstance(max_model_len, int) or max_model_len <= 0:
            raise ValueError("max_model_len must be a positive integer")
        if chunk_k != 256 or waves_per_eu != 2:
            raise ValueError("frozen baseline uses ChunkK=256, WavePerEU=2")
        tensors = (q, kv_cache, weights, context_lens, block_tables)
        if any(not t.is_cuda or t.device != q.device for t in tensors):
            raise ValueError("all inputs must be on the same GPU")
        arch = torch.cuda.get_device_properties(q.device).gcnArchName.split(":")[0]
        if arch != "gfx938":
            raise NotImplementedError(f"baseline is validated only on gfx938, got {arch}")
        if q.ndim != 4 or q.dtype != torch.float8_e4m3fn or not q.is_contiguous():
            raise ValueError("q must be contiguous E4M3FN [B,R,H,128]")
        b, r, h, d = q.shape
        if b < 1 or r not in (1, 2, 4) or h not in (32, 64) or d != 128:
            raise ValueError("requires B>0, R=1/2/4, H=32/64, D=128")
        if (kv_cache.dtype != torch.uint8 or kv_cache.ndim != 4
                or kv_cache.shape[0] < 1 or tuple(kv_cache.shape[1:]) != (1, 1, d+4)
                or not kv_cache.is_contiguous()):
            raise ValueError("cache must be contiguous uint8 [P,1,1,132], P>0")
        if (weights.dtype != torch.float32 or tuple(weights.shape) != (b*r, h)
                or not weights.is_contiguous()):
            raise ValueError("weights must be contiguous FP32 [B*R,H]")
        if context_lens.dtype != torch.int32 or not context_lens.is_contiguous():
            raise ValueError("context_lens must be contiguous int32")
        if tuple(context_lens.shape) == (b, r):
            last = context_lens[:, -1]
            canonical = last[:, None] - r + torch.arange(1, r+1, device=q.device)
            if not torch.equal(context_lens, canonical):
                raise ValueError("2D context must describe consecutive MTP queries")
            context_lens = last.contiguous()
        elif tuple(context_lens.shape) != (b,):
            raise ValueError("context_lens must be [B] or canonical [B,R]")
        if (block_tables.dtype != torch.int32 or block_tables.ndim != 2
                or block_tables.shape[0] != b or not block_tables.is_contiguous()):
            raise ValueError("block_tables must be contiguous int32 [B,T]")
        lengths = context_lens.cpu().tolist()
        if any(x < r or x > max_model_len or x > block_tables.shape[1] for x in lengths):
            raise ValueError("context must satisfy R <= L <= min(max_model_len,T)")
        for i, length in enumerate(lengths):
            pages = block_tables[i, :length]
            if bool(((pages < 0) | (pages >= kv_cache.shape[0])).any()):
                raise ValueError("valid block table entries must lie in [0,P)")
        self.q, self.cache, self.weights = q, kv_cache, weights
        self.context, self.tables = context_lens, block_tables
        self.b, self.r, self.h, self.d = b, r, h, d
        self.max_len, self.chunk_k, self.waves = max_model_len, chunk_k, waves_per_eu
        self.cu = torch.cuda.get_device_properties(q.device).multi_processor_count
        self.split_kv = (max(1, self.cu // (b*r)) + 4) // 5 * 5 * waves_per_eu
        packed = kv_cache.view(-1, d+4)
        self.k = packed[:, :d].view(torch.float8_e4m3fn)
        self.scales = packed[:, d:].view(torch.float32)
        if not bool((torch.isfinite(self.scales) & (self.scales > 0)).all()):
            raise ValueError("K scales must be positive and finite")
        self.padded_len = (max_model_len + chunk_k-1) // chunk_k * chunk_k
        # Guard both ends while preserving the contiguous physical row stride.
        size = h*b*r*self.padded_len
        self._guarded_qk = torch.full((size+128,), 123456.0, device=q.device)
        self.qk = self._guarded_qk[64:64+size].view(h, b*r, self.padded_len)
        self.sum_out = torch.empty((b*r, self.padded_len), device=q.device)
        kernel_module = importlib.import_module(
            "aiter.ops.triton._triton_kernels.attention.pa_mqa_logits")
        wrapper = importlib.import_module("aiter.ops.triton.attention.pa_mqa_logits")
        self._fused = kernel_module._deepgemm_fp8_paged_mqa_logits
        self._stage1 = wrapper.deepgemm_fp8_paged_mqa_logits_stage1
        self.metadata = {
            "backend": "existing_plain_triton", "arch": arch,
            "ChunkK": chunk_k, "ChunkQ": h, "WavePerEU": waves_per_eu,
            "TotalCuCount": self.cu, "SplitKV": self.split_kv,
            "max_model_len": max_model_len, "padded_len": self.padded_len,
            "stage1_workspace_bytes": self.qk.numel()*4+self.sum_out.numel()*4,
            "source_sha256": {str(Path(m.__file__).resolve()):
                hashlib.sha256(Path(m.__file__).read_bytes()).hexdigest()
                for m in (kernel_module, wrapper)},
        }

    def _validate_out(self, out):
        if (out.device != self.q.device or out.dtype != torch.float32
                or tuple(out.shape) != (self.b*self.r, self.max_len)
                or not out.is_contiguous()):
            raise ValueError("out must be contiguous FP32 [B*R,max_model_len] on input GPU")

    def run_fused(self, out, clean_logits=True):
        self._validate_out(out)
        if clean_logits:
            out.fill_(-float("inf"))
        self._fused[(self.b*self.r*self.split_kv, 1, 1)](
            self.b, self.r, self.h, self.q, *self.q.stride()[:3],
            self.k, self.k.stride(0), self.scales, self.scales.stride(0),
            self.context, self.tables, self.weights, self.weights.stride(0),
            out, out.stride(0), self.max_len, self.tables.shape[1],
            ChunkQ=self.h, ChunkK=self.chunk_k, HiddenDim=self.d,
            SplitKV=self.split_kv, waves_per_eu=self.waves)
        return out

    def run_stage1_sum(self, out, clean_logits=True):
        self._validate_out(out)
        if clean_logits:
            self.qk.fill_(-float("inf"))
        self._stage1(self.q, self.cache, self.weights, self.qk, self.context,
                     self.tables, self.max_len, ChunkQ=self.h, ChunkK=self.chunk_k,
                     TotalCuCount=self.cu, WavePerEU=self.waves)
        if self.padded_len == self.max_len:
            torch.sum(self.qk, dim=0, out=out)
        else:
            torch.sum(self.qk, dim=0, out=self.sum_out)
            out.copy_(self.sum_out[:, :self.max_len])
        return out

    def check_workspace_canaries(self):
        return bool((self._guarded_qk[:64] == 123456.0).all()
                    and (self._guarded_qk[-64:] == 123456.0).all())


def prepare_baseline(q, kv_cache, weights, context_lens, block_tables,
                     max_model_len, **options):
    """Validate/allocate outside timing or Graph capture; return a prepared adapter."""
    return PagedMQATritonBaseline(q, kv_cache, weights, context_lens,
                                  block_tables, max_model_len, **options)
