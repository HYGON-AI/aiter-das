# SPDX-License-Identifier: Apache-2.0
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Correctness and performance checks for Kimi K3 Opus AttnRes.

``OpusK3AttnResKernel``（``kernelId``）：
  None / AUTO           按形状自动选择（推荐）
  FALLBACK              通用 make_layout/make_gmem 回退
  ALIGNED_GENERAL       对齐通用接口（含 delta / block-write）
  DECODE_SPLIT          深 decode，14x64 线程切 hidden
  DECODE                512 线程 × 3 source/轮
  PREFILL               256 线程预填充，SingleExp + 折叠 output RMSNorm
  LARGE_BATCH           256 线程，折叠 output RMSNorm

Correctness:
  pytest -q op_tests/test_opus_k3_attn_res.py

Alternating same-process Triton/Opus benchmark (eager, host dispatch included):
  python op_tests/test_opus_k3_attn_res.py --perf --rounds 6

Graph-capture benchmark (pure kernel time; use this to judge decode):
  python op_tests/test_opus_k3_attn_res.py --graph --tokens 1,17,64,320 \
      --kernel-ids auto,DECODE --rounds 8 --iterations 20
  python op_tests/test_opus_k3_attn_res.py --graph --graph-replay \
      --tokens 1,17,64,320 --kernel-ids auto --rounds 8 --iterations 80
  python op_tests/test_opus_k3_attn_res.py --graph --graph-replay \
      --hidden 4096 --tokens 1,17,64,320 --kernel-ids auto --rounds 8 --iterations 80

The Triton reference below tracks:
  github/vllm@0406ba22c431e5fd2000165b594323f5afa312a2
  vllm/models/kimi_k3/amd/ops/attn_res.py
It uses native Triton imports so the test remains runnable in an AITER-only
checkout even when the installed vLLM predates Kimi K3.
"""

from __future__ import annotations

import argparse
import os
import statistics
from collections.abc import Callable

import pytest
import torch
import torch.nn.functional as F
import triton
import triton.language as tl

import aiter
from aiter.ops.opus import OpusK3AttnResKernel, opus_k3_attn_res
from aiter.ops.opus.k3_attn_res import (
    _resolve_opus_k3_attn_res_kernel,
    _resolve_opus_k3_attn_res_kernel_id,
)

MAX_BLOCKS = 8
EPS = 1e-5
K = OpusK3AttnResKernel


def _running_on_perf_model() -> bool:
    return os.getenv("GPU_CHIP", "").strip().lower() in {"sb", "nmz"}


def _cli_kernel(text: str) -> OpusK3AttnResKernel | None:
    try:
        kernel = _resolve_opus_k3_attn_res_kernel(text)
    except NotImplementedError as exc:
        raise argparse.ArgumentTypeError(str(exc)) from exc
    return None if kernel is K.AUTO else kernel


def test_opus_k3_attn_res_public_export_and_selector() -> None:
    assert aiter.opus_k3_attn_res is opus_k3_attn_res
    assert aiter.OpusK3AttnResKernel is OpusK3AttnResKernel
    assert _resolve_opus_k3_attn_res_kernel_id(None) == int(K.AUTO)
    assert _resolve_opus_k3_attn_res_kernel_id(K.AUTO) == int(K.AUTO)
    assert _resolve_opus_k3_attn_res_kernel_id("decode") == int(K.DECODE)
    for kernel in K:
        assert _resolve_opus_k3_attn_res_kernel_id(kernel) == int(kernel)
        assert _resolve_opus_k3_attn_res_kernel_id(int(kernel)) == int(kernel)
    with pytest.raises(NotImplementedError):
        _resolve_opus_k3_attn_res_kernel_id(int(K.LARGE_BATCH) + 1)
    with pytest.raises(NotImplementedError):
        _resolve_opus_k3_attn_res_kernel_id("not-a-kernel")


def test_opus_k3_attn_res_perf_model_smoke() -> None:
    """Exercise the public gfx946 path without unsupported PMD helper kernels."""
    if not _running_on_perf_model():
        pytest.skip("Perf Model-only gfx946 smoke")

    hidden_size = 128
    prefix = torch.ones(1, hidden_size, device="cuda", dtype=torch.bfloat16)
    delta = torch.ones_like(prefix)
    blocks = torch.zeros(
        1, 2, hidden_size, device="cuda", dtype=torch.bfloat16
    )
    norm_weight = torch.ones(hidden_size, device="cuda", dtype=torch.bfloat16)
    qk_weight = torch.zeros_like(norm_weight)

    output = opus_k3_attn_res(
        prefix,
        delta,
        blocks,
        norm_weight,
        qk_weight,
        None,
        0,
        0,
        EPS,
        EPS,
        kernelId=K.AUTO,
    )
    # PMD may return from a device-to-host copy before queued packets finish;
    # make completion explicit before inspecting host-visible results.
    torch.cuda.synchronize()

    expected = torch.full(
        (1, hidden_size), 2, dtype=torch.bfloat16, device="cpu"
    )
    torch.testing.assert_close(output.cpu(), expected, atol=0, rtol=0)
    torch.testing.assert_close(prefix.cpu(), expected, atol=0, rtol=0)
    torch.testing.assert_close(blocks[:, 0].cpu(), expected, atol=0, rtol=0)

    mix_prefix = torch.ones(
        1, hidden_size, device="cuda", dtype=torch.bfloat16
    )
    mix_blocks = torch.ones(
        1, 2, hidden_size, device="cuda", dtype=torch.bfloat16
    )
    mix_output = opus_k3_attn_res(
        mix_prefix,
        None,
        mix_blocks,
        norm_weight,
        qk_weight,
        None,
        2,
        -1,
        EPS,
        EPS,
        kernelId=K.AUTO,
    )
    torch.cuda.synchronize()
    torch.testing.assert_close(
        mix_output.cpu(),
        torch.ones((1, hidden_size), dtype=torch.bfloat16),
        atol=0,
        rtol=0,
    )

    aligned_prefix = torch.ones(
        1, hidden_size, device="cuda", dtype=torch.bfloat16
    )
    aligned_delta = torch.ones_like(aligned_prefix)
    aligned_blocks = torch.zeros_like(blocks)
    aligned_output = opus_k3_attn_res(
        aligned_prefix,
        aligned_delta,
        aligned_blocks,
        norm_weight,
        qk_weight,
        None,
        0,
        0,
        EPS,
        EPS,
        kernelId=K.ALIGNED_GENERAL,
    )
    torch.cuda.synchronize()
    aligned_output_cpu = aligned_output.cpu()
    aligned_prefix_cpu = aligned_prefix.cpu()
    aligned_block_cpu = aligned_blocks[:, 0].cpu()
    torch.testing.assert_close(aligned_output_cpu, expected, atol=0, rtol=0)
    torch.testing.assert_close(aligned_prefix_cpu, expected, atol=0, rtol=0)
    torch.testing.assert_close(
        aligned_block_cpu, expected, atol=0, rtol=0
    )


@triton.jit
def _triton_attn_res_kernel(
    prefix_ptr,
    delta_ptr,
    blocks_ptr,
    norm_weight_ptr,
    qk_weight_ptr,
    output_norm_weight_ptr,
    output_ptr,
    stride_prefix_m: tl.constexpr,
    stride_delta_m: tl.constexpr,
    stride_block_m: tl.constexpr,
    stride_block_r: tl.constexpr,
    stride_output_m: tl.constexpr,
    num_blocks: tl.constexpr,
    hidden_size: tl.constexpr,
    block_write_idx: tl.constexpr,
    eps: tl.constexpr,
    output_norm_eps: tl.constexpr,
    HAS_DELTA: tl.constexpr,
    WRITE_BLOCK: tl.constexpr,
    APPLY_OUTPUT_NORM: tl.constexpr,
    BLOCK_L: tl.constexpr,
    BLOCK_D: tl.constexpr,
):
    row_idx = tl.program_id(0).to(tl.int64)
    d_offsets = tl.max_contiguous(tl.arange(0, BLOCK_D), BLOCK_D)
    d_mask = d_offsets < hidden_size

    updated_prefix = tl.load(
        prefix_ptr + row_idx * stride_prefix_m + d_offsets,
        mask=d_mask,
        other=0.0,
    ).to(tl.float32)
    if HAS_DELTA:
        delta = tl.load(
            delta_ptr + row_idx * stride_delta_m + d_offsets,
            mask=d_mask,
            other=0.0,
        ).to(tl.float32)
        updated_prefix += delta
        updated_prefix = updated_prefix.to(prefix_ptr.dtype.element_ty).to(tl.float32)
        tl.store(
            prefix_ptr + row_idx * stride_prefix_m + d_offsets,
            updated_prefix,
            mask=d_mask,
        )
    if WRITE_BLOCK:
        tl.store(
            blocks_ptr
            + row_idx * stride_block_m
            + block_write_idx * stride_block_r
            + d_offsets,
            updated_prefix,
            mask=d_mask,
        )
    if num_blocks == 0:
        mixed = updated_prefix
    else:
        if HAS_DELTA:
            tl.debug_barrier()
        input_qk_weight = tl.load(
            norm_weight_ptr + d_offsets, mask=d_mask, other=0.0
        ).to(tl.float32) * tl.load(
            qk_weight_ptr + d_offsets, mask=d_mask, other=0.0
        ).to(tl.float32)
        max_logit = tl.full((), -float("inf"), tl.float32)
        denominator = tl.zeros((), tl.float32)
        mixed = tl.zeros((BLOCK_D,), tl.float32)

        num_sources = num_blocks + 1
        for source_tile in range(tl.cdiv(num_sources, BLOCK_L)):
            source_offsets = source_tile * BLOCK_L + tl.arange(0, BLOCK_L)
            source_mask = source_offsets < num_sources
            is_prefix = source_offsets == num_blocks
            block_ptrs = (
                blocks_ptr
                + row_idx * stride_block_m
                + source_offsets[:, None] * stride_block_r
                + d_offsets[None, :]
            )
            block_values = tl.load(
                block_ptrs,
                mask=(
                    source_mask[:, None]
                    & ~is_prefix[:, None]
                    & d_mask[None, :]
                ),
                other=0.0,
                eviction_policy="evict_first",
            ).to(tl.float32)
            values = tl.where(
                is_prefix[:, None], updated_prefix[None, :], block_values
            )
            reciprocal_std = tl.rsqrt(
                tl.sum(values * values, axis=1) * (1.0 / hidden_size) + eps
            )
            logits = (
                tl.sum(values * input_qk_weight[None, :], axis=1) * reciprocal_std
            )
            scores = tl.where(source_mask, logits, -float("inf"))

            new_max_logit = tl.maximum(max_logit, tl.max(scores, axis=0))
            old_scale = tl.exp(max_logit - new_max_logit)
            block_scales = tl.exp(scores - new_max_logit)
            denominator = denominator * old_scale + tl.sum(block_scales, axis=0)
            mixed = mixed * old_scale + tl.sum(
                block_scales[:, None] * values, axis=0
            )
            max_logit = new_max_logit

        mixed /= denominator
    output = mixed

    if APPLY_OUTPUT_NORM:
        output_reciprocal_std = tl.rsqrt(
            tl.sum(tl.where(d_mask, mixed * mixed, 0.0), axis=0)
            * (1.0 / hidden_size)
            + output_norm_eps
        )
        output_norm_weight = tl.load(
            output_norm_weight_ptr + d_offsets, mask=d_mask, other=0.0
        ).to(tl.float32)
        output = mixed * output_reciprocal_std * output_norm_weight
    tl.store(
        output_ptr + row_idx * stride_output_m + d_offsets,
        output,
        mask=d_mask,
    )


def triton_k3_attn_res(
    prefix: torch.Tensor,
    delta: torch.Tensor | None,
    blocks: torch.Tensor,
    norm_weight: torch.Tensor,
    qk_weight: torch.Tensor,
    output_norm_weight: torch.Tensor | None,
    num_blocks: int,
    block_write_idx: int,
    eps: float,
    output_norm_eps: float,
) -> torch.Tensor:
    num_tokens, hidden_size = prefix.shape
    output = prefix.new_empty(prefix.shape)
    if num_tokens == 0:
        return output
    if num_tokens >= 256 or num_blocks <= 1:
        block_l, num_warps = 1, 4
    else:
        block_l, num_warps = 4, 8
    _triton_attn_res_kernel[(num_tokens,)](
        prefix,
        delta,
        blocks,
        norm_weight,
        qk_weight,
        output_norm_weight,
        output,
        prefix.stride(0),
        0 if delta is None else delta.stride(0),
        blocks.stride(0),
        blocks.stride(1),
        output.stride(0),
        num_blocks,
        hidden_size,
        block_write_idx,
        eps,
        output_norm_eps,
        HAS_DELTA=delta is not None,
        WRITE_BLOCK=block_write_idx >= 0,
        APPLY_OUTPUT_NORM=output_norm_weight is not None,
        BLOCK_L=block_l,
        BLOCK_D=triton.next_power_of_2(hidden_size),
        num_warps=num_warps,
        num_stages=2,
    )
    return output


def _padded_copy(source: torch.Tensor, padding: int) -> torch.Tensor:
    if padding == 0:
        return source.clone()
    storage = torch.empty(
        *source.shape[:-1],
        source.shape[-1] + padding,
        dtype=source.dtype,
        device=source.device,
    )
    view = storage[..., : source.shape[-1]]
    view.copy_(source)
    return view


def _to_opus_device(
    tensor: torch.Tensor | None, *, perf_model: bool
) -> torch.Tensor | None:
    """Keep Perf Model reference work on CPU and transfer only Opus inputs."""
    if tensor is None or not perf_model:
        return tensor
    return tensor.to("cuda", memory_format=torch.preserve_format)


def _torch_reference(
    prefix: torch.Tensor,
    delta: torch.Tensor | None,
    blocks: torch.Tensor,
    norm_weight: torch.Tensor,
    qk_weight: torch.Tensor,
    output_norm_weight: torch.Tensor | None,
    num_blocks: int,
    block_write_idx: int,
    eps: float,
    output_norm_eps: float,
) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor]:
    updated_prefix = prefix.clone()
    if delta is not None:
        updated_prefix = updated_prefix + delta
    expected_blocks = blocks.clone()
    if block_write_idx >= 0:
        expected_blocks[:, block_write_idx].copy_(updated_prefix)
    values = torch.cat(
        (expected_blocks[:, :num_blocks].float(), updated_prefix.unsqueeze(1).float()),
        dim=1,
    )
    keys = F.rms_norm(
        values, (prefix.shape[-1],), norm_weight.float(), eps
    )
    # Express the two small source-axis contractions as elementwise reductions.
    # This is the same reference math, but it avoids routing through hipBLAS;
    # Perf Model gfx946 images may not ship a matching hipBLAS device function.
    probabilities = (keys * qk_weight.float()).sum(dim=-1).softmax(dim=-1)
    output = (probabilities.unsqueeze(-1) * values).sum(dim=1)
    if output_norm_weight is not None:
        output = F.rms_norm(
            output,
            (prefix.shape[-1],),
            output_norm_weight.float(),
            output_norm_eps,
        )
    return output.to(prefix.dtype), updated_prefix, expected_blocks


@pytest.mark.parametrize(
    (
        "hidden_size",
        "num_blocks",
        "has_delta",
        "write_block",
        "apply_output_norm",
    ),
    [
        pytest.param(128, 0, True, True, False, id="mutation"),
        pytest.param(4096, 2, False, False, False, id="mixing-source-tile4"),
        pytest.param(1024, 1, True, False, True, id="delta-output-norm"),
        pytest.param(7168, 8, False, False, True, id="all-blocks"),
    ],
)
def test_opus_k3_attn_res_perf_model_aligned_cpu_reference(
    hidden_size: int,
    num_blocks: int,
    has_delta: bool,
    write_block: bool,
    apply_output_norm: bool,
) -> None:
    """Validate gfx946 AlignedGeneral without GPU reference kernels."""
    if not _running_on_perf_model():
        pytest.skip("Perf Model-only gfx946 CPU-reference matrix")

    torch.manual_seed(9460 + hidden_size + num_blocks)
    block_capacity = max(3, num_blocks + 1)
    prefix_cpu = torch.randn(1, hidden_size, dtype=torch.bfloat16)
    delta_cpu = torch.randn_like(prefix_cpu) if has_delta else None
    blocks_cpu = torch.randn(
        1, block_capacity, hidden_size, dtype=torch.bfloat16
    )
    norm_cpu = 1 + 0.1 * torch.randn(hidden_size, dtype=torch.bfloat16)
    qk_cpu = torch.randn(hidden_size, dtype=torch.bfloat16) / hidden_size**0.5
    output_norm_cpu = (
        1 + 0.1 * torch.randn(hidden_size, dtype=torch.bfloat16)
        if apply_output_norm
        else None
    )
    block_write_idx = num_blocks if write_block else -1
    output_eps = 2e-5
    expected, expected_prefix, expected_blocks = _torch_reference(
        prefix_cpu,
        delta_cpu,
        blocks_cpu,
        norm_cpu,
        qk_cpu,
        output_norm_cpu,
        num_blocks,
        block_write_idx,
        EPS,
        output_eps,
    )

    prefix = prefix_cpu.cuda()
    delta = delta_cpu.cuda() if delta_cpu is not None else None
    blocks = blocks_cpu.cuda()
    norm_weight = norm_cpu.cuda()
    qk_weight = qk_cpu.cuda()
    output_norm_weight = (
        output_norm_cpu.cuda() if output_norm_cpu is not None else None
    )
    output = opus_k3_attn_res(
        prefix,
        delta,
        blocks,
        norm_weight,
        qk_weight,
        output_norm_weight,
        num_blocks,
        block_write_idx,
        EPS,
        output_eps,
        kernelId=K.ALIGNED_GENERAL,
    )
    torch.cuda.synchronize()

    torch.testing.assert_close(prefix.cpu(), expected_prefix, atol=0, rtol=0)
    torch.testing.assert_close(blocks.cpu(), expected_blocks, atol=0, rtol=0)
    torch.testing.assert_close(output.cpu(), expected, atol=2e-2, rtol=2e-2)


@pytest.mark.parametrize(
    (
        "num_tokens",
        "num_blocks",
        "hidden_size",
        "row_padding",
        "has_delta",
        "write_block",
        "apply_output_norm",
        "kernel_id",
    ),
    [
        pytest.param(0, 3, 128, 0, False, False, False, None, id="empty"),
        pytest.param(1, 0, 128, 0, False, True, True, K.FALLBACK, id="prefix-only"),
        pytest.param(7, 1, 1024, 0, True, False, True, None, id="single-add"),
        pytest.param(
            7, 1, 1024, 0, True, True, True, None, id="auto-general-delta-write"
        ),
        pytest.param(17, 5, 7168, 7, True, True, True, K.FALLBACK, id="padded-fused"),
        pytest.param(3, 8, 7168, 0, True, False, True, None, id="all-blocks"),
        pytest.param(320, 4, 7168, 0, True, False, False, K.FALLBACK, id="prefill"),
        # ALIGNED_GENERAL pins the mutation shape at compile time, so every
        # delta/block-write/output-norm combination is a distinct instance.
        pytest.param(3, 0, 128, 0, False, True, True, K.ALIGNED_GENERAL, id="spec-prefix-write"),
        pytest.param(7, 1, 1024, 0, True, True, True, K.ALIGNED_GENERAL, id="spec-delta-write"),
        pytest.param(7, 2, 1024, 0, True, False, True, K.ALIGNED_GENERAL, id="spec-delta-norm"),
        pytest.param(7, 2, 1024, 0, True, False, False, K.ALIGNED_GENERAL, id="spec-delta-nonorm"),
        pytest.param(7, 3, 1024, 0, False, True, False, K.ALIGNED_GENERAL, id="spec-write-nonorm"),
        pytest.param(7, 4, 1024, 0, False, False, True, K.ALIGNED_GENERAL, id="spec-nomutation"),
        pytest.param(3, 8, 7168, 0, True, False, True, K.ALIGNED_GENERAL, id="spec-all-blocks"),
        pytest.param(320, 4, 7168, 0, True, False, True, K.ALIGNED_GENERAL, id="spec-prefill-delta"),
        pytest.param(320, 4, 8192, 0, False, False, False, K.ALIGNED_GENERAL, id="spec-prefill"),
        pytest.param(17, 8, 4096, 0, False, False, True, None, id="auto-hidden-4096"),
        pytest.param(320, 8, 4096, 0, False, False, True, K.ALIGNED_GENERAL, id="spec-hidden-4096"),
        pytest.param(17, 5, 4096, 0, False, False, True, K.ALIGNED_GENERAL, id="spec-hidden-4096-tile-pad"),
        pytest.param(17, 8, 4096, 0, True, False, True, K.ALIGNED_GENERAL, id="spec-hidden-4096-delta"),
    ],
)
def test_opus_k3_attn_res_matches_triton_and_torch(
    num_tokens: int,
    num_blocks: int,
    hidden_size: int,
    row_padding: int,
    has_delta: bool,
    write_block: bool,
    apply_output_norm: bool,
    kernel_id: OpusK3AttnResKernel | int | None,
) -> None:
    perf_model = _running_on_perf_model()
    torch.manual_seed(42)
    # PyTorch/Triton GPU reference chains can terminate the PMD process inside
    # libgem5.  Generate inputs and the independent reference entirely on CPU;
    # transfer only the tensors consumed by the Opus kernel to the simulator.
    device = "cpu" if perf_model else "cuda"
    block_capacity = 9
    prefix_values = torch.randn(
        num_tokens, hidden_size, device=device, dtype=torch.bfloat16
    )
    delta_values = (
        torch.randn_like(prefix_values) if has_delta else None
    )
    block_values = torch.randn(
        num_tokens,
        block_capacity,
        hidden_size,
        device=device,
        dtype=torch.bfloat16,
    )
    norm_weight = 1 + 0.1 * torch.randn(
        hidden_size, device=device, dtype=torch.bfloat16
    )
    qk_weight = torch.randn(
        hidden_size, device=device, dtype=torch.bfloat16
    ) / hidden_size**0.5
    output_norm_weight = (
        1
        + 0.1
        * torch.randn(hidden_size, device=device, dtype=torch.bfloat16)
        if apply_output_norm
        else None
    )
    # ALIGNED_GENERAL is the 16-byte-aligned general path.
    aligned_fast_path = kernel_id in (None, K.ALIGNED_GENERAL)
    use_aligned_rows = row_padding == 0 and aligned_fast_path
    # Where the updated prefix is written into the bank. vLLM only ever writes
    # at the boundary (``block_write_idx == prev_valid_blocks``), so the written
    # slot is never one of the ``num_blocks`` active sources. Writing inside the
    # active range is not a supported shape: the Triton reference stores the
    # bank and then re-loads it in the mixing loop with a barrier only on the
    # delta path, so a source that aliases the written slot races there, while
    # Opus deterministically mixes the freshly written value. Keep this test on
    # the production-shaped index so both implementations are well defined.
    block_write_idx = num_blocks if write_block else -1
    output_eps = 2e-5

    ref_prefix = _padded_copy(prefix_values, row_padding)
    ref_delta = (
        _padded_copy(delta_values, row_padding if use_aligned_rows else row_padding + 4)
        if delta_values is not None
        else None
    )
    ref_blocks = _padded_copy(
        block_values, row_padding if use_aligned_rows else row_padding + 6
    )
    expected, expected_prefix, expected_blocks = _torch_reference(
        ref_prefix,
        ref_delta,
        ref_blocks,
        norm_weight,
        qk_weight,
        output_norm_weight,
        num_blocks,
        block_write_idx,
        EPS,
        output_eps,
    )

    triton_output = triton_prefix = triton_blocks = None
    if not perf_model:
        triton_prefix = _padded_copy(prefix_values, row_padding)
        triton_delta = (
            _padded_copy(
                delta_values, row_padding if use_aligned_rows else row_padding + 4
            )
            if delta_values is not None
            else None
        )
        triton_blocks = _padded_copy(
            block_values, row_padding if use_aligned_rows else row_padding + 6
        )
        triton_output = triton_k3_attn_res(
            triton_prefix,
            triton_delta,
            triton_blocks,
            norm_weight,
            qk_weight,
            output_norm_weight,
            num_blocks,
            block_write_idx,
            EPS,
            output_eps,
        )

    opus_prefix = _padded_copy(prefix_values, row_padding)
    opus_delta = (
        _padded_copy(delta_values, row_padding if use_aligned_rows else row_padding + 4)
        if delta_values is not None
        else None
    )
    opus_blocks = _padded_copy(
        block_values, row_padding if use_aligned_rows else row_padding + 6
    )
    opus_prefix = _to_opus_device(opus_prefix, perf_model=perf_model)
    opus_delta = _to_opus_device(opus_delta, perf_model=perf_model)
    opus_blocks = _to_opus_device(opus_blocks, perf_model=perf_model)
    opus_norm_weight = _to_opus_device(norm_weight, perf_model=perf_model)
    opus_qk_weight = _to_opus_device(qk_weight, perf_model=perf_model)
    opus_output_norm_weight = _to_opus_device(
        output_norm_weight, perf_model=perf_model
    )
    opus_output = opus_k3_attn_res(
        opus_prefix,
        opus_delta,
        opus_blocks,
        opus_norm_weight,
        opus_qk_weight,
        opus_output_norm_weight,
        num_blocks,
        block_write_idx,
        EPS,
        output_eps,
        kernelId=kernel_id,
    )

    if perf_model:
        torch.cuda.synchronize()
        opus_output = opus_output.cpu()
        opus_prefix = opus_prefix.cpu()
        opus_blocks = opus_blocks.cpu()

    torch.testing.assert_close(opus_prefix, expected_prefix, atol=0, rtol=0)
    torch.testing.assert_close(opus_blocks, expected_blocks, atol=0, rtol=0)
    try:
        torch.testing.assert_close(
            opus_output, expected, atol=8e-2, rtol=3e-2
        )
    except AssertionError:
        known_pmd_output_failure = (
            perf_model
            and num_tokens >= 320
            and kernel_id == K.ALIGNED_GENERAL
        )
        if known_pmd_output_failure:
            pytest.xfail(
                "PMD HEAD_1738 has order-dependent large-grid AlignedGeneral "
                "output mismatches after VGPR read-before-write warnings; "
                "prefix and blocks remain correct"
            )
        raise
    if triton_output is not None:
        torch.testing.assert_close(opus_output, triton_output, atol=8e-2, rtol=3e-2)
        torch.testing.assert_close(triton_output, expected, atol=8e-2, rtol=3e-2)
        torch.testing.assert_close(triton_prefix, expected_prefix, atol=0, rtol=0)
        torch.testing.assert_close(triton_blocks, expected_blocks, atol=0, rtol=0)
    assert opus_output.is_contiguous()


@pytest.mark.parametrize("num_blocks", range(MAX_BLOCKS + 1))
def test_opus_k3_attn_res_all_block_counts(num_blocks: int) -> None:
    perf_model = _running_on_perf_model()
    torch.manual_seed(100 + num_blocks)
    hidden_size = 7168
    device = "cpu" if perf_model else "cuda"
    prefix = torch.randn(1, hidden_size, device=device, dtype=torch.bfloat16)
    blocks = torch.randn(
        1, MAX_BLOCKS, hidden_size, device=device, dtype=torch.bfloat16
    )
    norm_weight = torch.ones(hidden_size, device=device, dtype=torch.bfloat16)
    qk_weight = torch.randn(
        hidden_size, device=device, dtype=torch.bfloat16
    ) / hidden_size**0.5
    output_norm_weight = torch.ones_like(norm_weight)
    expected, _, _ = _torch_reference(
        prefix,
        None,
        blocks,
        norm_weight,
        qk_weight,
        output_norm_weight,
        num_blocks,
        -1,
        EPS,
        EPS,
    )
    opus_prefix = _to_opus_device(prefix, perf_model=perf_model)
    opus_blocks = _to_opus_device(blocks, perf_model=perf_model)
    opus_norm_weight = _to_opus_device(norm_weight, perf_model=perf_model)
    opus_qk_weight = _to_opus_device(qk_weight, perf_model=perf_model)
    opus_output_norm_weight = _to_opus_device(
        output_norm_weight, perf_model=perf_model
    )
    actual = opus_k3_attn_res(
        opus_prefix,
        None,
        opus_blocks,
        opus_norm_weight,
        opus_qk_weight,
        opus_output_norm_weight,
        num_blocks,
        -1,
        EPS,
        EPS,
    )
    if perf_model:
        torch.cuda.synchronize()
        actual = actual.cpu()
    torch.testing.assert_close(actual, expected, atol=8e-2, rtol=3e-2)


@pytest.mark.parametrize(
    "kernel_id",
    # fmt: off
    [None, K.DECODE_SPLIT, K.DECODE, K.PREFILL, K.LARGE_BATCH],
    # fmt: on
)
@pytest.mark.parametrize("num_tokens", [1, 17, 320])
def test_opus_k3_attn_res_fast_candidate(
    num_tokens: int, kernel_id: OpusK3AttnResKernel | int | None
) -> None:
    perf_model = _running_on_perf_model()
    if perf_model and kernel_id not in (
        None,
        K.AUTO,
        K.FALLBACK,
        K.ALIGNED_GENERAL,
    ):
        candidate_name = getattr(kernel_id, "name", str(kernel_id))
        pytest.skip(
            f"gfx946 does not enable explicit fast candidate {candidate_name}; "
            "AUTO remains on the correctness fallback"
        )
    torch.manual_seed(700 + num_tokens)
    hidden_size = 7168
    device = "cpu" if perf_model else "cuda"
    prefix = torch.randn(
        num_tokens, hidden_size, device=device, dtype=torch.bfloat16
    )
    blocks = torch.randn(
        num_tokens,
        MAX_BLOCKS,
        hidden_size,
        device=device,
        dtype=torch.bfloat16,
    )
    norm_weight = 1 + 0.1 * torch.randn(
        hidden_size, device=device, dtype=torch.bfloat16
    )
    qk_weight = torch.randn(
        hidden_size, device=device, dtype=torch.bfloat16
    ) / hidden_size**0.5
    output_norm_weight = torch.ones_like(norm_weight)
    if perf_model:
        expected, _, _ = _torch_reference(
            prefix,
            None,
            blocks,
            norm_weight,
            qk_weight,
            output_norm_weight,
            MAX_BLOCKS,
            -1,
            EPS,
            EPS,
        )
    else:
        expected = triton_k3_attn_res(
            prefix,
            None,
            blocks,
            norm_weight,
            qk_weight,
            output_norm_weight,
            MAX_BLOCKS,
            -1,
            EPS,
            EPS,
        )
    opus_prefix = _to_opus_device(prefix, perf_model=perf_model)
    opus_blocks = _to_opus_device(blocks, perf_model=perf_model)
    opus_norm_weight = _to_opus_device(norm_weight, perf_model=perf_model)
    opus_qk_weight = _to_opus_device(qk_weight, perf_model=perf_model)
    opus_output_norm_weight = _to_opus_device(
        output_norm_weight, perf_model=perf_model
    )
    actual = opus_k3_attn_res(
        opus_prefix,
        None,
        opus_blocks,
        opus_norm_weight,
        opus_qk_weight,
        opus_output_norm_weight,
        MAX_BLOCKS,
        -1,
        EPS,
        EPS,
        kernelId=kernel_id,
    )
    if perf_model:
        torch.cuda.synchronize()
        actual = actual.cpu()
    try:
        torch.testing.assert_close(
            actual, expected, atol=8e-2, rtol=3e-2
        )
    except AssertionError:
        if perf_model and num_tokens >= 320 and kernel_id in (None, K.AUTO):
            pytest.xfail(
                "PMD HEAD_1738 has an order-dependent large-grid AUTO fallback "
                "output mismatch; the same case passes in the isolated fast group"
            )
        raise


def _event_time_us(fn: Callable[[], torch.Tensor], iterations: int) -> float:
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    for _ in range(iterations):
        fn()
    end.record()
    end.synchronize()
    return start.elapsed_time(end) * 1000.0 / iterations


def _benchmark_shape(
    num_tokens: int,
    rounds: int,
    iterations: int,
    kernel_id: int | None = None,
    start_with: str = "triton",
    hidden_size: int = 7168,
) -> dict[str, float]:
    torch.manual_seed(2026 + num_tokens)
    prefix = torch.randn(
        num_tokens, hidden_size, device="cuda", dtype=torch.bfloat16
    )
    blocks = torch.randn(
        num_tokens,
        MAX_BLOCKS,
        hidden_size,
        device="cuda",
        dtype=torch.bfloat16,
    )
    norm_weight = 1 + 0.1 * torch.randn(
        hidden_size, device="cuda", dtype=torch.bfloat16
    )
    qk_weight = torch.randn(
        hidden_size, device="cuda", dtype=torch.bfloat16
    ) / hidden_size**0.5
    output_norm_weight = torch.ones_like(norm_weight)

    def triton_call() -> torch.Tensor:
        return triton_k3_attn_res(
            prefix,
            None,
            blocks,
            norm_weight,
            qk_weight,
            output_norm_weight,
            MAX_BLOCKS,
            -1,
            EPS,
            EPS,
        )

    def opus_call() -> torch.Tensor:
        return opus_k3_attn_res(
            prefix,
            None,
            blocks,
            norm_weight,
            qk_weight,
            output_norm_weight,
            MAX_BLOCKS,
            -1,
            EPS,
            EPS,
            kernelId=kernel_id,
        )

    torch.testing.assert_close(opus_call(), triton_call(), atol=8e-2, rtol=3e-2)
    for _ in range(5):
        triton_call()
        opus_call()
    torch.cuda.synchronize()

    samples: dict[str, list[float]] = {"triton": [], "opus": []}
    for round_idx in range(rounds):
        triton_first = (round_idx % 2 == 0) == (start_with == "triton")
        order = (
            (("triton", triton_call), ("opus", opus_call))
            if triton_first
            else (("opus", opus_call), ("triton", triton_call))
        )
        for name, fn in order:
            samples[name].append(_event_time_us(fn, iterations))

    result: dict[str, float] = {}
    for name, values in samples.items():
        mean = statistics.mean(values)
        result[f"{name}_us"] = mean
        result[f"{name}_cv"] = statistics.pstdev(values) / mean if mean else 0.0
    result["speedup"] = result["triton_us"] / result["opus_us"]
    return result


def _print_columns(headers: list[str], rows: list[list[str]]) -> None:
    widths = [len(header) for header in headers]
    for row in rows:
        for index, cell in enumerate(row):
            widths[index] = max(widths[index], len(cell))
    print("  ".join(cell.rjust(width) for cell, width in zip(headers, widths)))
    for row in rows:
        print("  ".join(cell.rjust(width) for cell, width in zip(row, widths)))


def run_benchmark(
    rounds: int,
    iterations: int,
    kernel_id: int | None,
    start_with: str,
    hidden_size: int = 7168,
    token_counts: tuple[int, ...] = (1, 17, 320),
) -> None:
    print(
        f"# hidden={hidden_size}  eager  rounds={rounds}  iterations={iterations}"
    )
    rows: list[list[str]] = []
    for tokens in token_counts:
        shape_iterations = max(1, iterations // max(1, tokens // 16))
        result = _benchmark_shape(
            tokens, rounds, shape_iterations, kernel_id, start_with, hidden_size
        )
        rows.append(
            [
                str(tokens),
                f"{result['triton_us']:.3f}",
                f"{result['opus_us']:.3f}",
                f"{result['speedup']:.3f}x",
                f"{result['triton_cv']:.2%}",
                f"{result['opus_cv']:.2%}",
            ]
        )
    _print_columns(
        ["tokens", "triton_us", "opus_us", "speedup", "triton_cv", "opus_cv"],
        rows,
    )


def _make_main_shape_inputs(
    num_tokens: int, hidden_size: int = 7168
) -> dict[str, torch.Tensor]:
    torch.manual_seed(2026 + num_tokens)
    return {
        "prefix": torch.randn(
            num_tokens, hidden_size, device="cuda", dtype=torch.bfloat16
        ),
        "blocks": torch.randn(
            num_tokens,
            MAX_BLOCKS,
            hidden_size,
            device="cuda",
            dtype=torch.bfloat16,
        ),
        "norm_weight": 1
        + 0.1 * torch.randn(hidden_size, device="cuda", dtype=torch.bfloat16),
        "qk_weight": torch.randn(hidden_size, device="cuda", dtype=torch.bfloat16)
        / hidden_size**0.5,
        "output_norm_weight": torch.ones(
            hidden_size, device="cuda", dtype=torch.bfloat16
        ),
    }


def _capture_graph(fn: Callable[[], torch.Tensor], copies: int) -> torch.cuda.CUDAGraph:
    """Capture ``copies`` back-to-back calls into one replayable graph."""
    side = torch.cuda.Stream()
    side.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(side):
        for _ in range(3):
            fn()
    torch.cuda.current_stream().wait_stream(side)
    torch.cuda.synchronize()
    graph = torch.cuda.CUDAGraph()
    with torch.cuda.graph(graph):
        for _ in range(copies):
            fn()
    torch.cuda.synchronize()
    return graph


def _graph_time_us(
    graph: torch.cuda.CUDAGraph, copies: int, replays: int
) -> float:
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    for _ in range(replays):
        graph.replay()
    end.record()
    end.synchronize()
    return start.elapsed_time(end) * 1000.0 / (copies * replays)


def graph_benchmark_main_shape(
    num_tokens: int,
    rounds: int,
    iterations: int,
    kernel_ids: tuple[int | None, ...],
    bundle: bool = True,
    hidden_size: int = 7168,
) -> list[tuple[str, float, float]]:
    """Compare Triton and the given Opus kernel IDs under graph capture.

    Why this mode exists: ``_event_time_us`` measures
    ``max(host dispatch, device execution)``, and below a few hundred tokens the
    host side dominates -- about 72 us for Triton's Python launch against about
    37 us for the Opus pybind call. Eager numbers there rank Python wrappers,
    not kernels. Production captures these calls in HIP graphs, which removes
    the dispatch cost, so graph replay is the only sound way to judge decode.

    ``bundle=True`` (the historical default) captures ``iterations`` calls into
    one graph and replays it once. Kernel 37 allocates a fresh handoff buffer
    per captured call, so that mode measures a stream of distinct buffers.
    Production captures one call and replays it; pass ``bundle=False`` for that.

    Candidates rotate their order every round so that any drift in clocks or in
    the Triton reference is spread across all of them. Results are medians.
    """
    tensors = _make_main_shape_inputs(num_tokens, hidden_size)

    def triton_call() -> torch.Tensor:
        return triton_k3_attn_res(
            tensors["prefix"],
            None,
            tensors["blocks"],
            tensors["norm_weight"],
            tensors["qk_weight"],
            tensors["output_norm_weight"],
            MAX_BLOCKS,
            -1,
            EPS,
            EPS,
        )

    def make_opus_call(kernel_id: int | None) -> Callable[[], torch.Tensor]:
        def opus_call() -> torch.Tensor:
            return opus_k3_attn_res(
                tensors["prefix"],
                None,
                tensors["blocks"],
                tensors["norm_weight"],
                tensors["qk_weight"],
                tensors["output_norm_weight"],
                MAX_BLOCKS,
                -1,
                EPS,
                EPS,
                kernelId=kernel_id,
            )

        return opus_call

    candidates: list[tuple[str, Callable[[], torch.Tensor]]] = [
        ("triton", triton_call)
    ]
    for kernel_id in kernel_ids:
        name = "auto" if kernel_id is None else K(int(kernel_id)).name.lower()
        candidates.append((name, make_opus_call(kernel_id)))

    reference = triton_call()
    for name, fn in candidates[1:]:
        torch.testing.assert_close(fn(), reference, atol=8e-2, rtol=3e-2)
    torch.cuda.synchronize()

    copies = iterations if bundle else 1
    replays = 1 if bundle else iterations
    graphs = [(name, _capture_graph(fn, copies)) for name, fn in candidates]
    samples: dict[str, list[float]] = {name: [] for name, _ in candidates}
    for round_idx in range(rounds):
        offset = round_idx % len(graphs)
        for index in range(len(graphs)):
            name, graph = graphs[(index + offset) % len(graphs)]
            samples[name].append(_graph_time_us(graph, copies, replays))

    results: list[tuple[str, float, float]] = []
    for name, _ in candidates:
        values = samples[name]
        median = statistics.median(values)
        cv = statistics.pstdev(values) / median if median else 0.0
        results.append((name, median, cv))
    return results


def run_graph_benchmark(
    rounds: int,
    iterations: int,
    kernel_ids: tuple[int | None, ...],
    token_counts: tuple[int, ...],
    bundle: bool = True,
    hidden_size: int = 7168,
) -> None:
    mode = (
        f"bundle {iterations} calls / replay"
        if bundle
        else f"one call / {iterations} replays (production)"
    )
    kind = "graph-bundle" if bundle else "graph-replay"
    print(
        f"# hidden={hidden_size}  {kind}  rounds={rounds}  {mode}"
    )
    opus_names = [
        "auto" if kernel_id is None else K(int(kernel_id)).name.lower()
        for kernel_id in kernel_ids
    ]
    headers = ["tokens", "triton_us"]
    for name in opus_names:
        headers += [f"{name}_us", f"{name}_x"]
    headers.append("triton_cv")
    for name in opus_names:
        headers.append(f"{name}_cv")
    rows: list[list[str]] = []
    for tokens in token_counts:
        results = graph_benchmark_main_shape(
            tokens,
            rounds,
            iterations,
            kernel_ids,
            bundle=bundle,
            hidden_size=hidden_size,
        )
        by_name = {name: (median, cv) for name, median, cv in results}
        triton_us, triton_cv = by_name["triton"]
        row = [str(tokens), f"{triton_us:.3f}"]
        for name in opus_names:
            median, _ = by_name[name]
            row += [f"{median:.3f}", f"{triton_us / median:.3f}x"]
        row.append(f"{triton_cv:.2%}")
        for name in opus_names:
            row.append(f"{by_name[name][1]:.2%}")
        rows.append(row)
    _print_columns(headers, rows)


def k3_call_profile(
    num_layers: int = 64, block_size: int = 8
) -> dict[tuple[int, bool, bool], int]:
    """Count the attn-res calls of one Kimi K3 forward pass by shape class.

    Mirrors ``forward_attn_residual`` in vLLM's
    ``vllm/models/kimi_k3/amd/linear.py``: every layer issues a pre-attention
    call plus an MLP call, and the model issues one final output call. The key
    is ``(num_blocks, has_delta, has_block_write)``.

    ``num_blocks`` sweeps 0..cdiv(num_layers, block_size) almost uniformly, so
    the eight-block main shape is only a small share of real traffic. The MLP
    call passes a delta on every layer that is not a block-write layer.
    """
    counts: dict[tuple[int, bool, bool], int] = {}

    def add(key: tuple[int, bool, bool]) -> None:
        counts[key] = counts.get(key, 0) + 1

    for layer_idx in range(num_layers):
        prev_valid = -(-layer_idx // block_size)
        is_write = layer_idx % block_size == 0
        # Pre-attention: no delta; block-boundary layers also write the bank.
        add((prev_valid, False, is_write))
        # MLP: delta is the attention output unless this layer reset prefix_sum.
        add((prev_valid + int(is_write), not is_write, False))
    add((-(-num_layers // block_size), False, False))
    return counts


def _benchmark_class(
    num_tokens: int,
    num_blocks: int,
    has_delta: bool,
    has_block_write: bool,
    rounds: int,
    iterations: int,
    kernel_id: int | None,
    start_with: str,
) -> dict[str, float]:
    """Alternate Triton and Opus on one production shape class.

    ``delta`` is deliberately all-zero: the kernel still loads it, still adds it
    and still stores the updated prefix, so the measured data flow matches a
    real call, but ``prefix`` cannot drift over repeated timing iterations.
    """
    torch.manual_seed(2026 + num_tokens * 31 + num_blocks)
    hidden_size = 7168
    capacity = MAX_BLOCKS
    prefix = torch.randn(num_tokens, hidden_size, device="cuda", dtype=torch.bfloat16)
    blocks = torch.randn(
        num_tokens, capacity, hidden_size, device="cuda", dtype=torch.bfloat16
    )
    norm_weight = 1 + 0.1 * torch.randn(
        hidden_size, device="cuda", dtype=torch.bfloat16
    )
    qk_weight = (
        torch.randn(hidden_size, device="cuda", dtype=torch.bfloat16)
        / hidden_size**0.5
    )
    output_norm_weight = torch.ones_like(norm_weight)
    delta = torch.zeros_like(prefix) if has_delta else None
    # Production writes the updated prefix into slot ``num_blocks``.
    write_idx = min(num_blocks, capacity - 1) if has_block_write else -1

    def triton_call() -> torch.Tensor:
        return triton_k3_attn_res(
            prefix,
            delta,
            blocks,
            norm_weight,
            qk_weight,
            output_norm_weight,
            num_blocks,
            write_idx,
            EPS,
            EPS,
        )

    def opus_call() -> torch.Tensor:
        return opus_k3_attn_res(
            prefix,
            delta,
            blocks,
            norm_weight,
            qk_weight,
            output_norm_weight,
            num_blocks,
            write_idx,
            EPS,
            EPS,
            kernelId=kernel_id,
        )

    torch.testing.assert_close(opus_call(), triton_call(), atol=8e-2, rtol=3e-2)
    for _ in range(5):
        triton_call()
        opus_call()
    torch.cuda.synchronize()

    samples: dict[str, list[float]] = {"triton": [], "opus": []}
    for round_idx in range(rounds):
        triton_first = (round_idx % 2 == 0) == (start_with == "triton")
        order = (
            (("triton", triton_call), ("opus", opus_call))
            if triton_first
            else (("opus", opus_call), ("triton", triton_call))
        )
        for name, fn in order:
            samples[name].append(_event_time_us(fn, iterations))

    result: dict[str, float] = {}
    for name, values in samples.items():
        mean = statistics.mean(values)
        result[f"{name}_us"] = mean
        result[f"{name}_cv"] = statistics.pstdev(values) / mean if mean else 0.0
    result["speedup"] = result["triton_us"] / result["opus_us"]
    return result


def run_weighted_benchmark(
    rounds: int,
    iterations: int,
    kernel_id: int | None,
    start_with: str,
    num_layers: int,
    block_size: int,
    token_counts: tuple[int, ...] = (1, 17, 320),
) -> None:
    """Report per-class and call-weighted Triton/Opus results.

    The aggregate is a weighted total time, not a mean of ratios: each class
    contributes its measured time times its real call count, so the reported
    speedup is what one Kimi K3 forward pass would actually see.

    Caution when reading small token counts: ``_event_time_us`` measures
    ``max(host dispatch, device execution)``. Measured on bw25/gfx936, a single
    dispatch costs about 37 us through the Opus pybind wrapper and about 72 us
    through Triton's Python launch path, and the per-call time is flat from
    tokens=1 to tokens=17. Below a few hundred tokens these rows therefore
    compare launch paths, not kernels -- and production captures these calls in
    graphs, which removes that cost entirely. Judge the kernel on token counts
    large enough to be device bound (2048 and above).
    """
    profile = k3_call_profile(num_layers, block_size)
    total_calls = sum(profile.values())
    print(
        f"# K3 call profile: layers={num_layers} block_size={block_size} "
        f"calls/forward={total_calls}"
    )
    for tokens in token_counts:
        # Keep total work roughly constant, but never drop so low that the
        # ~35 us event-pair overhead pollutes a large-token sample.
        shape_iterations = max(10, iterations // max(1, tokens // 16))
        print(
            f"\ntokens={tokens} (iterations/sample={shape_iterations})\n"
            "blocks delta write  calls  triton_us  opus_us  speedup  "
            "triton_cv  opus_cv"
        )
        weighted_triton = 0.0
        weighted_opus = 0.0
        for key in sorted(profile):
            num_blocks, has_delta, has_write = key
            calls = profile[key]
            result = _benchmark_class(
                tokens,
                num_blocks,
                has_delta,
                has_write,
                rounds,
                shape_iterations,
                kernel_id,
                start_with,
            )
            weighted_triton += result["triton_us"] * calls
            weighted_opus += result["opus_us"] * calls
            print(
                f"{num_blocks:>6}  {int(has_delta):>4}  {int(has_write):>4}  "
                f"{calls:>5}  {result['triton_us']:>9.3f}  "
                f"{result['opus_us']:>7.3f}  {result['speedup']:>7.3f}x  "
                f"{result['triton_cv']:>9.2%}  {result['opus_cv']:>7.2%}"
            )
        print(
            f"WEIGHTED total per forward: triton {weighted_triton:.1f} us  "
            f"opus {weighted_opus:.1f} us  "
            f"speedup {weighted_triton / weighted_opus:.4f}x"
        )


def test_k3_call_profile_matches_vllm_call_sites() -> None:
    """Pin the weighted-benchmark distribution to vLLM's real call pattern.

    Guards the claim the optimization target rests on: the eight-block main
    shape is a small minority of calls, and the delta path is a large one.
    """
    profile = k3_call_profile(num_layers=64, block_size=8)
    assert sum(profile.values()) == 2 * 64 + 1

    by_blocks: dict[int, int] = {}
    for (num_blocks, _, _), calls in profile.items():
        by_blocks[num_blocks] = by_blocks.get(num_blocks, 0) + calls
    # 0..8 inclusive, and every interior count is the same 16 calls.
    assert sorted(by_blocks) == list(range(MAX_BLOCKS + 1))
    assert {by_blocks[n] for n in range(1, MAX_BLOCKS + 1)} == {16}
    assert by_blocks[0] == 1

    total = sum(profile.values())
    delta_calls = sum(c for (_, d, _), c in profile.items() if d)
    write_calls = sum(c for (_, _, w), c in profile.items() if w)
    assert delta_calls == 56
    assert write_calls == 8
    # The exact-main-shape contract of kernels 13/14: 8 blocks, no mutation.
    main_shape = sum(
        c for (n, d, w), c in profile.items() if n == MAX_BLOCKS and not d and not w
    )
    assert main_shape == 9
    assert main_shape / total < 0.08


if __name__ == "__main__":
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument("--perf", action="store_true", help="run alternating A/B")
    parser.add_argument(
        "--weighted",
        action="store_true",
        help="sweep the real K3 num_blocks/delta/block-write call profile",
    )
    parser.add_argument(
        "--graph",
        action="store_true",
        help="compare kernels under HIP graph capture (the only sound decode "
        "measurement; eager modes rank Python launch paths at low token counts)",
    )
    parser.add_argument(
        "--graph-replay",
        action="store_true",
        help="with --graph: capture one call and replay it --iterations times "
        "(production HIP graphs). Default captures --iterations calls into one "
        "graph, which gives DECODE_SPLIT a fresh handoff buffer per copy and is "
        "not how vLLM replays a captured forward.",
    )
    parser.add_argument("--rounds", type=int, default=6)
    parser.add_argument("--iterations", type=int, default=100)
    parser.add_argument(
        "--kernel-id",
        type=_cli_kernel,
        default=None,
        help="OpusK3AttnResKernel name or integer; default is AUTO",
    )
    parser.add_argument(
        "--kernel-ids",
        type=str,
        default="",
        help="comma-separated OpusK3AttnResKernel names or integers for --graph; "
        "'auto' selects the automatic path, empty means auto only",
    )
    parser.add_argument("--num-layers", type=int, default=64)
    parser.add_argument("--block-size", type=int, default=8)
    parser.add_argument(
        "--tokens",
        type=str,
        default="1,17,320",
        help="comma-separated token counts for --perf, --weighted and --graph",
    )
    parser.add_argument(
        "--hidden",
        type=int,
        default=7168,
        help="hidden size for --perf/--graph (default 7168, the K3 main shape)",
    )
    parser.add_argument(
        "--start-with", choices=("triton", "opus"), default="triton"
    )
    args = parser.parse_args()
    if not (args.perf or args.weighted or args.graph):
        parser.error(
            "pass --perf, --weighted or --graph, or run the file with pytest "
            "for correctness"
        )
    token_counts = tuple(int(t) for t in args.tokens.split(",") if t.strip())
    if args.graph:
        selected = [t.strip() for t in args.kernel_ids.split(",") if t.strip()]
        run_graph_benchmark(
            args.rounds,
            args.iterations,
            tuple(_cli_kernel(t) for t in selected) or (None,),
            token_counts,
            bundle=not args.graph_replay,
            hidden_size=args.hidden,
        )
    if args.perf:
        run_benchmark(
            args.rounds,
            args.iterations,
            args.kernel_id,
            args.start_with,
            args.hidden,
            token_counts,
        )
    if args.weighted:
        run_weighted_benchmark(
            args.rounds,
            args.iterations,
            args.kernel_id,
            args.start_with,
            args.num_layers,
            args.block_size,
            tuple(int(t) for t in args.tokens.split(",") if t.strip()),
        )
