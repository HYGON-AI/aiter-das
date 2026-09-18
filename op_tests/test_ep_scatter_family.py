# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

"""Correctness tests for the ep_scatter operator family.

Covers (aiter.ops.moe_op, JIT module_moe_utils):
  ep_scatter                    int8 activations, scan + scatter
  ep_gather                     inverse permutation with topk-weight reduce
  ep_build_m_indices            m_indices built straight from topk_ids
  ep_fused_quant_scatter        bf16/fp16 -> per-token int8 quant + scatter
  ep_fused_fp8_quant_scatter    bf16/fp16 -> per-token fp8 (e4m3/e5m2) quant
  ep_fused_smooth_quant_scatter bf16/fp16 -> per-(token,expert) smooth int8

References are pure torch mirrors of the kernel arithmetic (same fp32 op
order), so the int8 / smooth paths are expected to match bitwise; the fp8
path is checked via dequantization error plus byte-match rate (hardware cvt
vs torch cast may differ on rounding ties).

Besides the original shapes, the suite pins down every host dispatch branch
and the kernel-side edge cases:

  * ep_scatter: fast-vs-generic kernel boundary (num_tokens=4096 / H=8192),
    M=1, K=1, E=1 (single expert), E=1024 (EP_SCAN_MAX_EXPERTS), align=1,
    all tokens dropped (M_sum=0), all tokens on one expert (skew).
  * ep_build_m_indices: E=1024 grid-stride tail, E=1 / align=1, odd M with
    zero-count experts interleaved.
  * ep_gather: K_MAX=8 template with large M, deepseek branch with
    expert_map, M just past the [256,512]&H=4096 special branch.
  * int8 quant: with_map + H=8192, M=1/K=1, large M.
  * fp8: fill x {e4m3, e5m2} x with_map cross product, H=1024/16384, M=1.
  * smooth: small-batch (num_tokens<=128) tk kernel for every compiled H
    branch (1024/2048/4096/7168/8192/16384), the M=128/129 dispatch
    boundary, large-M low-reg kernel, fallback H, E=1, with_map, all
    dropped.

Timing: pass --bench (or set AITER_TEST_BENCH=1) to print a per-op timing
table (CUDA events, min of 3 rounds, scan-input clone overhead subtracted)
after the correctness run:

Run:  python op_tests/test_ep_scatter_family.py [--bench]   (or via pytest)
"""

from __future__ import annotations

import os

import pytest
import torch

from aiter.ops.moe_op import (
    ep_build_m_indices,
    ep_fused_fp8_quant_scatter,
    ep_fused_quant_scatter,
    ep_fused_smooth_quant_scatter,
    ep_gather,
    ep_scatter,
)

DEV = "cuda"


# ---------------------------------------------------------------------------
# helpers
# ---------------------------------------------------------------------------
def make_topk(M: int, K: int, E_local: int, *, with_map: bool, seed: int = 0):
    """Returns (topk_ids int64 [M,K], expert_map or None, E_local).

    With with_map: E_global = 2*E_local, the upper half of experts is dropped
    (mapped to -1) and every 7th flat entry is set to -1 (dropped tokens).
    """
    g = torch.Generator(device=DEV).manual_seed(seed)
    if with_map:
        E_global = 2 * E_local
        topk_ids = torch.randint(
            0, E_global, (M, K), dtype=torch.int64, device=DEV, generator=g
        )
        expert_map = torch.arange(E_global, dtype=torch.int32, device=DEV)
        expert_map[E_local:] = -1
        topk_ids.view(-1)[::7] = -1
        return topk_ids, expert_map, E_local
    topk_ids = torch.randint(
        0, E_local, (M, K), dtype=torch.int64, device=DEV, generator=g
    )
    return topk_ids, None, E_local


def map_ids(topk_ids: torch.Tensor, expert_map, E_local: int) -> torch.Tensor:
    """Local expert id per (t,k); -1 where invalid (mirrors kernel checks)."""
    n_global = E_local if expert_map is None else expert_map.numel()
    valid = (topk_ids >= 0) & (topk_ids < n_global)
    mapped = torch.where(valid, topk_ids, torch.full_like(topk_ids, -1))
    if expert_map is not None:
        safe = mapped.clamp(min=0)
        mapped = torch.where(valid, expert_map[safe].long(), mapped)
        mapped = torch.where(mapped < E_local, mapped, torch.full_like(mapped, -1))
    return mapped


def layout(mapped: torch.Tensor, E_local: int, alignment: int):
    """Per-expert counts, alignment-padded starts, padded sizes and total rows."""
    valid = mapped >= 0
    counts = torch.bincount(mapped[valid], minlength=E_local)
    padded = (counts + alignment - 1) // alignment * alignment
    starts = padded.cumsum(0) - padded
    return valid, counts, starts, padded, int(padded.sum())


def check_perm_layout(inv_perm, m_indices, mapped, counts, starts, M_sum,
                      *, m_indices_fill=-1):
    """Order-agnostic validation of the permutation outputs."""
    valid = mapped >= 0
    assert torch.all(inv_perm[valid] >= 0), "valid entries must claim a row"
    assert torch.all(inv_perm[~valid] == -1), "invalid entries must be -1"

    rows = inv_perm[valid].long()
    assert rows.unique().numel() == rows.numel(), "claimed rows must be unique"
    if rows.numel() > 0:  # all-dropped case has nothing to range-check
        assert int(rows.min()) >= 0 and int(rows.max()) < M_sum

    seg_lo = starts[mapped[valid]]
    seg_ok = (rows >= seg_lo) & (rows < seg_lo + counts[mapped[valid]])
    assert torch.all(seg_ok), "rows must stay inside their expert segment"

    assert torch.equal(m_indices[rows], mapped[valid].to(torch.int32))
    covered = torch.zeros(M_sum, dtype=torch.bool, device=DEV)
    covered[rows] = True
    assert torch.all(m_indices[~covered] == m_indices_fill), (
        f"unclaimed rows must hold {m_indices_fill}, "
        f"got {m_indices[~covered].unique().tolist()}"
    )


def check_scatter_data(aq_out, aq_scale_out, inv_perm, mapped, row_aq, row_scale):
    """row_aq: [M, H] or [M, K, H] quantized rows; row_scale likewise."""
    valid = mapped >= 0
    rows = inv_perm[valid].long()
    M, K = mapped.shape
    if row_aq.dim() == 2:  # per-token rows, replicated to every k
        exp_aq = row_aq.unsqueeze(1).expand(M, K, -1)[valid]
    else:  # per-(token, k) rows
        exp_aq = row_aq[valid]
    assert torch.equal(aq_out[rows], exp_aq)
    if row_scale.dim() == 1 or row_scale.size(-1) == 1:  # per-token scale
        exp_scale = row_scale.reshape(M, 1).expand(M, K)[valid]
    else:  # per-(token, k) scale
        exp_scale = row_scale[valid]
    assert torch.equal(aq_scale_out[rows].reshape(-1), exp_scale)


def full_m_indices_ref(starts, counts, padded, E_local, *, pad_value_fn):
    """m_indices reference over the full padded buffer."""
    M_sum = int(padded.sum().item())
    ref = torch.empty(M_sum, dtype=torch.int32, device=DEV)
    for e in range(E_local):
        s = int(starts[e].item())
        c = int(counts[e].item())
        p = int(padded[e].item())
        ref[s:s + c] = e
        ref[s + c:s + p] = pad_value_fn(e)
    return ref


def full_m_indices_ref_fast(starts, counts, padded, E_local, *, fill_with_expert):
    """Vectorized equivalent of full_m_indices_ref (same result, no host loop).

    Used for the many-expert cases where the per-expert python loop would be
    the slowest part of the test.
    """
    M_sum = int(padded.sum().item())
    row_expert = torch.repeat_interleave(
        torch.arange(E_local, dtype=torch.int32, device=DEV), padded
    )
    if fill_with_expert:
        return row_expert
    off = torch.arange(M_sum, device=DEV, dtype=torch.int64) - starts[row_expert.long()]
    keep = off < counts[row_expert.long()]
    return torch.where(keep, row_expert, torch.full_like(row_expert, -1))


def smooth_quant_ref(x: torch.Tensor, mapped: torch.Tensor,
                     smooth: torch.Tensor):
    """Vectorized per-(token, k) smooth-quant reference.

    Mirrors the kernel arithmetic element-for-element (fp32 products, max,
    clamp_min(1e-6), scale = max/127, inv = 127/max, round-to-nearest-even),
    so it stays bitwise-comparable with the device result. Entries whose
    mapped expert is -1 hold garbage and are ignored by the checks.
    """
    M, K = mapped.shape
    x32 = x.float()
    sm = x32.unsqueeze(1) * smooth[mapped.clamp(min=0)]  # [M, K, H]
    mx = sm.abs().amax(dim=-1).clamp_min(1e-6)           # [M, K]
    inv = torch.div(torch.full_like(mx, 127.0), mx)
    scale = torch.div(mx, torch.full_like(mx, 127.0))
    q = torch.round(sm * inv.unsqueeze(-1)).clamp(-128, 127).to(torch.int8)
    return q, scale


# ---------------------------------------------------------------------------
# ep_scatter
# ---------------------------------------------------------------------------
def _run_ep_scatter_case(topk_ids, expert_map, E_local, align, *, H=2048):
    """Shared body of the ep_scatter correctness tests (ids already prepared)."""
    M, K = topk_ids.shape
    mapped = map_ids(topk_ids, expert_map, E_local)
    valid, counts, starts, padded, M_sum = layout(mapped, E_local, align)

    aq = torch.randint(-128, 128, (M, H), dtype=torch.int8, device=DEV)
    aq_scale = torch.rand(M, 1, dtype=torch.float32, device=DEV)
    aq_out = torch.full((M_sum, H), 99, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.full((M_sum, 1), float("nan"), dtype=torch.float32, device=DEV)
    m_indices = torch.full((M_sum,), -7, dtype=torch.int32, device=DEV)
    inv_perm = torch.full((M, K), -7, dtype=torch.int32, device=DEV)

    ep_scatter(aq, aq_scale, topk_ids, expert_map, counts.to(torch.int32),
               aq_out, aq_scale_out, m_indices, inv_perm, E_local, align)

    # ep_scatter's scan pre-fills padded slots with -1
    assert torch.equal(
        m_indices,
        full_m_indices_ref_fast(starts, counts, padded, E_local, fill_with_expert=False),
    )
    check_perm_layout(inv_perm, m_indices, mapped, counts, starts, M_sum)
    check_scatter_data(aq_out, aq_scale_out, inv_perm, mapped, aq, aq_scale)


@pytest.mark.parametrize(
    "M,H,K,E,align,with_map",
    [
        (512, 7168, 8, 64, 256, False),    # fast kernel, deepseek-like shape
        (333, 2048, 4, 64, 128, False),    # fast kernel, odd num_tokens
        (5000, 2048, 8, 64, 256, False),   # num_tokens > 4096 -> generic kernel
        (256, 16384, 2, 8, 256, False),    # H > 8192 -> generic kernel
        (200, 1024, 4, 32, 64, True),      # expert_map with dropped experts
    ],
)
def test_ep_scatter(M, H, K, E, align, with_map):
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=with_map)
    _run_ep_scatter_case(topk_ids, expert_map, E_local, align, H=H)


@pytest.mark.parametrize(
    "M,H,K,E,align",
    [
        (1, 2048, 8, 64, 256),      # single token: half-empty fast-kernel block
        (17, 2048, 1, 8, 64),       # K=1
        (96, 2048, 8, 1, 64),       # E=1: every claim hits one counter/segment
        (128, 1024, 8, 1024, 64),   # E=1024 = EP_SCAN_MAX_EXPERTS, many zero-count experts
        (64, 2048, 8, 64, 1),       # alignment=1: padded == counts
        (100, 1536, 4, 16, 64),     # H not on the deepseek path
        (4096, 8192, 4, 16, 256),   # exactly on the fast/generic boundary
    ],
)
def test_ep_scatter_edges(M, H, K, E, align):
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=False)
    _run_ep_scatter_case(topk_ids, expert_map, E_local, align, H=H)


def test_ep_scatter_all_dropped():
    """Every (token, k) invalid -> M_sum == 0, inv_perm all -1."""
    M, H, K, E, align = 32, 2048, 4, 8, 64
    topk_ids = torch.full((M, K), -1, dtype=torch.int64, device=DEV)
    _run_ep_scatter_case(topk_ids, None, E, align, H=H)


def test_ep_scatter_skewed():
    """All tokens on expert 0: max atomic contention on one counter."""
    M, H, K, E, align = 200, 2048, 8, 16, 64
    topk_ids = torch.zeros(M, K, dtype=torch.int64, device=DEV)
    _run_ep_scatter_case(topk_ids, None, E, align, H=H)


def test_ep_scatter_scale_1d():
    """aq_scale may be [M] instead of [M, 1]."""
    M, H, K, E, align = 64, 2048, 8, 16, 128
    topk_ids, _, E_local = make_topk(M, K, E, with_map=False)
    mapped = map_ids(topk_ids, None, E_local)
    _, counts, _, _, M_sum = layout(mapped, E_local, align)

    aq = torch.randint(-128, 128, (M, H), dtype=torch.int8, device=DEV)
    aq_scale = torch.rand(M, dtype=torch.float32, device=DEV)
    aq_out = torch.empty(M_sum, H, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.empty(M_sum, 1, dtype=torch.float32, device=DEV)
    m_indices = torch.empty(M_sum, dtype=torch.int32, device=DEV)
    inv_perm = torch.empty(M, K, dtype=torch.int32, device=DEV)

    ep_scatter(aq, aq_scale, topk_ids, None, counts.to(torch.int32),
               aq_out, aq_scale_out, m_indices, inv_perm, E_local, align)
    check_scatter_data(aq_out, aq_scale_out, inv_perm, mapped, aq, aq_scale)


# ---------------------------------------------------------------------------
# ep_build_m_indices
# ---------------------------------------------------------------------------
@pytest.mark.parametrize("dtype", [torch.int64, torch.int32])
@pytest.mark.parametrize("M,K,E,align", [(1024, 8, 64, 128), (333, 4, 16, 64)])
def test_ep_build_m_indices(M, K, E, align, dtype):
    torch.manual_seed(0)
    topk_ids = torch.randint(-1, E, (M, K), dtype=torch.int64, device=DEV).to(dtype)
    mapped = map_ids(topk_ids.long(), None, E)
    _, counts, starts, padded, M_sum = layout(mapped, E, align)

    ref = full_m_indices_ref(starts, counts, padded, E, pad_value_fn=lambda e: -1)
    m_indices = torch.full((M_sum,), -7, dtype=torch.int32, device=DEV)
    ep_build_m_indices(topk_ids, m_indices, E, align)
    assert torch.equal(m_indices, ref)


@pytest.mark.parametrize(
    "M,K,E,align,dtype",
    [
        (2048, 8, 1024, 128, torch.int64),  # E=1024 max, 16k elements: grid-stride tail
        (512, 8, 1, 1, torch.int64),        # single expert, alignment=1
        (777, 8, 96, 128, torch.int32),     # odd M, zero-count experts interleaved
    ],
)
def test_ep_build_m_indices_more(M, K, E, align, dtype):
    torch.manual_seed(0)
    topk_ids = torch.randint(-1, E, (M, K), dtype=torch.int64, device=DEV).to(dtype)
    mapped = map_ids(topk_ids.long(), None, E)
    _, counts, starts, padded, M_sum = layout(mapped, E, align)

    ref = full_m_indices_ref_fast(starts, counts, padded, E, fill_with_expert=False)
    m_indices = torch.full((M_sum,), -7, dtype=torch.int32, device=DEV)
    ep_build_m_indices(topk_ids, m_indices, E, align)
    assert torch.equal(m_indices, ref)


# ---------------------------------------------------------------------------
# ep_gather
# ---------------------------------------------------------------------------
@pytest.mark.parametrize(
    "M,H,K,dtype,with_map",
    [
        (300, 4096, 2, torch.bfloat16, False),  # M in [256,512] & H=4096 branch
        (64, 7168, 8, torch.bfloat16, False),   # deepseek branch
        (129, 1024, 4, torch.float16, True),    # expert_map drops
        (33, 512, 1, torch.float32, False),     # K=1 -> K_MAX=2, fp32 input
    ],
)
def test_ep_gather(M, H, K, dtype, with_map):
    _run_ep_gather_case(M, H, K, dtype, with_map)


@pytest.mark.parametrize(
    "M,H,K,dtype,with_map",
    [
        (2048, 2048, 8, torch.bfloat16, False),  # K_MAX=8 template, M > 512
        (100, 7168, 2, torch.float16, True),     # deepseek branch + expert_map
        (513, 4096, 4, torch.bfloat16, False),   # one past the [256,512] special branch
    ],
)
def test_ep_gather_more(M, H, K, dtype, with_map):
    _run_ep_gather_case(M, H, K, dtype, with_map)


def _run_ep_gather_case(M, H, K, dtype, with_map):
    torch.manual_seed(0)
    topk_ids, expert_map, _ = make_topk(M, K, 8, with_map=with_map)
    mapped = map_ids(topk_ids, expert_map, E_local=8)
    valid = mapped >= 0
    M_sum = int(valid.sum())

    a = torch.randn(M_sum + 8, H, dtype=dtype, device=DEV)  # some dead rows too
    # deterministic unique rows for valid entries; -1 elsewhere
    inv_perm = torch.full((M, K), -1, dtype=torch.int32, device=DEV)
    inv_perm[valid] = torch.arange(M_sum, device=DEV, dtype=torch.int32)
    topk_weights = torch.rand(M, K, dtype=torch.float32, device=DEV)

    out = torch.empty(M, H, dtype=dtype, device=DEV)
    ep_gather(a, topk_ids, topk_weights, inv_perm, expert_map, out)

    # reference: fp32 accumulate in k order, single cast (mirrors the kernel)
    acc = torch.zeros(M, H, dtype=torch.float32, device=DEV)
    mapped_cpu = mapped.cpu()
    for k in range(K):
        sel = (mapped_cpu[:, k] >= 0) & (inv_perm[:, k].cpu() >= 0)
        idx = torch.nonzero(sel, as_tuple=True)[0].to(DEV)
        acc[idx] += a[inv_perm[idx, k].long()].float() * topk_weights[idx, k, None]
    torch.testing.assert_close(out, acc.to(dtype), rtol=1e-2, atol=1e-3)


# ---------------------------------------------------------------------------
# ep_fused_quant_scatter (int8)
# ---------------------------------------------------------------------------
@pytest.mark.parametrize(
    "M,H,K,E,align,dtype,with_map",
    [
        (257, 4096, 8, 64, 256, torch.bfloat16, False),
        (128, 2048, 4, 16, 128, torch.float16, True),
    ],
)
def test_ep_fused_quant_scatter(M, H, K, E, align, dtype, with_map):
    _run_quant_scatter_case(M, H, K, E, align, dtype, with_map)


@pytest.mark.parametrize(
    "M,H,K,E,align,dtype,with_map",
    [
        (129, 8192, 8, 8, 256, torch.bfloat16, True),   # with_map + H=8192
        (1, 2048, 1, 4, 64, torch.float16, False),      # M=1, K=1
        (4096, 4096, 4, 64, 256, torch.bfloat16, False)  # large M
    ],
)
def test_ep_fused_quant_scatter_more(M, H, K, E, align, dtype, with_map):
    _run_quant_scatter_case(M, H, K, E, align, dtype, with_map)


def _run_quant_scatter_case(M, H, K, E, align, dtype, with_map):
    torch.manual_seed(0)
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=with_map)
    mapped = map_ids(topk_ids, expert_map, E_local)
    valid, counts, starts, _, M_sum = layout(mapped, E_local, align)

    x = (torch.randn(M, H, device=DEV) * 3).to(dtype)
    x32 = x.float()
    smax = x32.abs().amax(dim=1)
    # torch.div(tensor, tensor) stays a true fp32 division (the /
    # operator takes a reciprocal-multiply path that breaks bitwise parity
    # with the kernel's __fdiv_rn)
    inv = torch.div(torch.full_like(smax, 127.0), smax)
    scale = torch.div(torch.ones_like(inv), inv)
    q = torch.round(x32 * inv[:, None]).clamp(-128, 127).to(torch.int8)

    aq_out = torch.full((M_sum, H), 99, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.full((M_sum, 1), float("nan"), dtype=torch.float32, device=DEV)
    m_indices = torch.full((M_sum,), -1, dtype=torch.int32, device=DEV)
    inv_perm = torch.full((M, K), -7, dtype=torch.int32, device=DEV)

    ep_fused_quant_scatter(x, topk_ids, expert_map, counts.to(torch.int32),
                           aq_out, aq_scale_out, m_indices, inv_perm,
                           E_local, align)

    # this variant scans without m_indices prefill: padding must keep our -1
    check_perm_layout(inv_perm, m_indices, mapped, counts, starts, M_sum,
                      m_indices_fill=-1)
    check_scatter_data(aq_out, aq_scale_out, inv_perm, mapped, q, scale)


# ---------------------------------------------------------------------------
# ep_fused_fp8_quant_scatter
# ---------------------------------------------------------------------------
@pytest.mark.parametrize(
    "M,H,K,E,align,dtype,fp8type,fill",
    [
        (257, 7168, 8, 32, 256, torch.bfloat16, 0, False),
        (128, 2048, 4, 16, 128, torch.float16, 1, True),
    ],
)
def test_ep_fused_fp8_quant_scatter(M, H, K, E, align, dtype, fp8type, fill):
    _run_fp8_case(M, H, K, E, align, dtype, fp8type, fill, with_map=False)


@pytest.mark.parametrize(
    "M,H,K,E,align,dtype,fp8type,fill,with_map",
    [
        (200, 2048, 4, 16, 128, torch.bfloat16, 0, True, False),   # e4m3 + expert-id fill
        (200, 4096, 8, 32, 256, torch.float16, 1, False, False),   # e5m2 + -1 fill
        (129, 2048, 4, 16, 128, torch.bfloat16, 0, False, True),   # with_map drops
        (64, 16384, 2, 8, 256, torch.bfloat16, 0, True, False),    # H=16384 vector stress
        (97, 1024, 8, 64, 64, torch.float16, 1, True, False),      # H=1024, K=8
        (1, 4096, 1, 4, 64, torch.bfloat16, 0, False, False),      # M=1, K=1
    ],
)
def test_ep_fused_fp8_quant_scatter_more(M, H, K, E, align, dtype, fp8type, fill,
                                         with_map):
    _run_fp8_case(M, H, K, E, align, dtype, fp8type, fill, with_map=with_map)


def _run_fp8_case(M, H, K, E, align, dtype, fp8type, fill, with_map):
    torch.manual_seed(0)
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=with_map)
    mapped = map_ids(topk_ids, expert_map, E_local)
    valid, counts, starts, padded, M_sum = layout(mapped, E_local, align)

    x = (torch.randn(M, H, device=DEV) * 3).to(dtype)
    x32 = x.float()
    smax = x32.abs().amax(dim=1)
    fp8_max = 448.0 if fp8type == 0 else 57344.0
    scale = torch.maximum(torch.div(smax, torch.full_like(smax, fp8_max)),
                          torch.full_like(smax, 1.0 / (fp8_max * 512.0)))
    inv = torch.div(torch.ones_like(scale), scale)
    fp8_dtype = torch.float8_e4m3fn if fp8type == 0 else torch.float8_e5m2
    q_ref = (x32 * inv[:, None]).to(fp8_dtype)

    aq_out = torch.full((M_sum, H), 0x55, dtype=torch.uint8, device=DEV)
    aq_scale_out = torch.full((M_sum, 1), float("nan"), dtype=torch.float32, device=DEV)
    m_indices = torch.full((M_sum,), -7, dtype=torch.int32, device=DEV)
    inv_perm = torch.full((M, K), -7, dtype=torch.int32, device=DEV)

    ep_fused_fp8_quant_scatter(x, topk_ids, expert_map, counts.to(torch.int32),
                               aq_out, aq_scale_out, m_indices, inv_perm,
                               E_local, align, fp8type, fill)

    if fill:
        # scan fills padding with the owning expert id
        ref = full_m_indices_ref_fast(starts, counts, padded, E_local,
                                      fill_with_expert=True)
        assert torch.equal(m_indices, ref)
    else:
        check_perm_layout(inv_perm, m_indices, mapped, counts, starts, M_sum)

    rows = inv_perm[valid].long()
    assert torch.equal(aq_scale_out[rows].reshape(-1),
                       scale.unsqueeze(1).expand(M, K)[valid])

    got = aq_out[rows].view(fp8_dtype)
    assert not torch.isnan(got.float()).any()
    # hardware cvt vs torch cast may differ on ties: allow a tiny byte-mismatch rate
    mismatch = got.view(torch.uint8) != q_ref.unsqueeze(1).expand(M, K, H)[valid].view(torch.uint8)
    rate = mismatch.float().mean().item()
    assert rate < 0.02, f"fp8 byte mismatch rate {rate:.4f}"
    # dequantized rows must reproduce the input within half an fp8 ulp (+ fp32 noise)
    ulp_rel = 0.125 if fp8type == 0 else 0.25
    tok_scale = scale.unsqueeze(1).expand(M, K)[valid][:, None]
    tok_smax = smax.unsqueeze(1).expand(M, K)[valid][:, None]
    err = (got.float() * tok_scale - x32.unsqueeze(1).expand(M, K, H)[valid]).abs()
    bound = tok_smax * ulp_rel * 1.1
    assert torch.all(err <= bound), f"max dequant err {err.max().item()}"


# ---------------------------------------------------------------------------
# ep_fused_smooth_quant_scatter
# ---------------------------------------------------------------------------
@pytest.mark.parametrize(
    "M,H,K,E,align,dtype",
    [
        (333, 1024, 4, 16, 128, torch.bfloat16),   # low-reg kernel, block 64, odd M
        (129, 4096, 8, 64, 256, torch.bfloat16),   # low-reg kernel, block 256
        (64, 7168, 8, 32, 256, torch.float16),     # low-reg kernel, block 448
        (97, 5120, 4, 16, 64, torch.bfloat16),     # fallback kernel
    ],
)
def test_ep_fused_smooth_quant_scatter(M, H, K, E, align, dtype):
    torch.manual_seed(0)
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=False)
    mapped = map_ids(topk_ids, expert_map, E_local)
    valid, counts, starts, _, M_sum = layout(mapped, E_local, align)

    x = (torch.randn(M, H, device=DEV) * 2).to(dtype)
    smooth = (torch.rand(E_local, H, device=DEV) + 0.5).float()

    # reference: per-(token, k) quant of x * smooth[e] (mirrors kernel math:
    # max over the fp32 products, clamp_min(1e-6), inv = 127/max, scale = max/127)
    x32 = x.float()
    q = torch.zeros(M, K, H, dtype=torch.int8, device=DEV)
    scale = torch.zeros(M, K, dtype=torch.float32, device=DEV)
    for e in range(E_local):
        sel = mapped == e
        if not sel.any():
            continue
        sm = (x32.unsqueeze(1) * smooth[e]).expand(M, K, H)  # [M, K, H]
        mx = sm.abs().amax(dim=2).clamp_min(1e-6)
        scale[sel] = torch.div(mx, torch.full_like(mx, 127.0))[sel]
        q[sel] = torch.round(
            sm[sel] * torch.div(torch.full_like(mx, 127.0), mx)[sel, None]
        ).clamp(-128, 127).to(torch.int8)

    aq_out = torch.full((M_sum, H), 99, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.full((M_sum, 1), float("nan"), dtype=torch.float32, device=DEV)
    m_indices = torch.full((M_sum,), -1, dtype=torch.int32, device=DEV)
    inv_perm = torch.full((M, K), -7, dtype=torch.int32, device=DEV)

    # this op takes pre-scanned start offsets (no internal scan)
    ep_fused_smooth_quant_scatter(x, topk_ids, expert_map, starts.to(torch.int32),
                                  smooth, aq_out, aq_scale_out, m_indices,
                                  inv_perm, E_local, align)

    # no scan in this op: m_indices padding must keep our -1 prefill
    check_perm_layout(inv_perm, m_indices, mapped, counts, starts, M_sum,
                      m_indices_fill=-1)
    check_scatter_data(aq_out, aq_scale_out, inv_perm, mapped, q, scale)


@pytest.mark.parametrize(
    "M,H,K,E,align,dtype,with_map",
    [
        # small-batch (num_tokens <= 128) tk kernel: every compiled H branch
        (64, 1024, 4, 16, 64, torch.bfloat16, False),    # tk, block 64
        (33, 2048, 8, 32, 128, torch.float16, False),    # tk, block 128, odd M
        (128, 4096, 8, 64, 256, torch.bfloat16, False),  # tk, block 256, M=128 boundary
        (64, 7168, 8, 32, 256, torch.bfloat16, False),   # tk, block 448
        (1, 8192, 4, 4, 64, torch.bfloat16, False),      # tk, block 512, M=1
        (50, 16384, 4, 8, 256, torch.bfloat16, False),   # tk, block 1024
        (100, 4096, 4, 16, 128, torch.bfloat16, True),   # tk + expert_map drops
        (64, 2048, 8, 1, 64, torch.bfloat16, False),     # tk, E=1 skew
        # large-batch low-reg kernel (grid = (M+1)/2 over many blocks)
        (2048, 4096, 8, 8, 256, torch.bfloat16, False),
        (4096, 7168, 4, 8, 256, torch.bfloat16, False),
        # fallback kernel on a non-compiled H
        (200, 1536, 4, 8, 64, torch.float16, False),
    ],
)
def test_ep_fused_smooth_quant_scatter_more(M, H, K, E, align, dtype, with_map):
    torch.manual_seed(0)
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=with_map)
    mapped = map_ids(topk_ids, expert_map, E_local)
    valid, counts, starts, _, M_sum = layout(mapped, E_local, align)

    x = (torch.randn(M, H, device=DEV) * 2).to(dtype)
    smooth = (torch.rand(E_local, H, device=DEV) + 0.5).float()

    # vectorized reference, bitwise-comparable with the kernel math
    q, scale = smooth_quant_ref(x, mapped, smooth)

    aq_out = torch.full((M_sum, H), 99, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.full((M_sum, 1), float("nan"), dtype=torch.float32, device=DEV)
    m_indices = torch.full((M_sum,), -1, dtype=torch.int32, device=DEV)
    inv_perm = torch.full((M, K), -7, dtype=torch.int32, device=DEV)

    ep_fused_smooth_quant_scatter(x, topk_ids, expert_map, starts.to(torch.int32),
                                  smooth, aq_out, aq_scale_out, m_indices,
                                  inv_perm, E_local, align)

    check_perm_layout(inv_perm, m_indices, mapped, counts, starts, M_sum,
                      m_indices_fill=-1)
    check_scatter_data(aq_out, aq_scale_out, inv_perm, mapped, q, scale)


def test_ep_fused_smooth_quant_scatter_all_dropped():
    """Every (token, k) invalid -> M_sum == 0, inv_perm all -1."""
    M, H, K, E, align = 32, 2048, 4, 8, 64
    torch.manual_seed(0)
    topk_ids = torch.full((M, K), -1, dtype=torch.int64, device=DEV)
    mapped = map_ids(topk_ids, None, E)
    valid, counts, starts, _, M_sum = layout(mapped, E, align)
    assert M_sum == 0

    x = (torch.randn(M, H, device=DEV) * 2).to(torch.bfloat16)
    smooth = (torch.rand(E, H, device=DEV) + 0.5).float()

    aq_out = torch.full((M_sum, H), 99, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.full((M_sum, 1), float("nan"), dtype=torch.float32, device=DEV)
    m_indices = torch.full((M_sum,), -1, dtype=torch.int32, device=DEV)
    inv_perm = torch.full((M, K), -7, dtype=torch.int32, device=DEV)

    ep_fused_smooth_quant_scatter(x, topk_ids, None, starts.to(torch.int32),
                                  smooth, aq_out, aq_scale_out, m_indices,
                                  inv_perm, E, align)
    assert torch.all(inv_perm == -1)

# ---------------------------------------------------------------------------
# timing (--bench / AITER_TEST_BENCH=1)
#
# CUDA-event timing, min of 3 rounds (dodges allocator / interference
# spikes). The scan-based ops overwrite expert_counters in place (counts ->
# starts) and the scatter kernels keep incrementing them via atomicAdd, so
# every timed call re-clones the scan input and the clone cost is measured
# separately and subtracted.
# ---------------------------------------------------------------------------
PEAK_TBPS = 1.33  # measured d2d copy bandwidth on this card


def _time_us(fn, iters=30, warmup=5, rounds=3):
    for _ in range(warmup):
        fn()
    torch.cuda.synchronize()
    best = float("inf")
    for _ in range(rounds):
        s = torch.cuda.Event(enable_timing=True)
        e = torch.cuda.Event(enable_timing=True)
        s.record()
        for _ in range(iters):
            fn()
        e.record()
        torch.cuda.synchronize()
        best = min(best, s.elapsed_time(e) / iters * 1e3)
    return best


def _bench_row(rows, name, shape, fn, traffic, overhead=None):
    us = _time_us(fn)
    if overhead is not None:
        us -= _time_us(overhead)
    us = max(us, 0.01)
    bw = traffic / (us * 1e-6) / 1e12
    rows.append((name, shape, us, traffic / 1e6, bw, bw / PEAK_TBPS * 100))


def _bench_ep_scatter(rows, M, H, K, E, align):
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=False)
    mapped = map_ids(topk_ids, expert_map, E_local)
    _, counts, _, _, M_sum = layout(mapped, E_local, align)
    counts = counts.to(torch.int32)

    aq = torch.randint(-128, 128, (M, H), dtype=torch.int8, device=DEV)
    aq_scale = torch.rand(M, 1, dtype=torch.float32, device=DEV)
    aq_out = torch.empty(M_sum, H, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.empty(M_sum, 1, dtype=torch.float32, device=DEV)
    m_indices = torch.empty(M_sum, dtype=torch.int32, device=DEV)
    inv_perm = torch.empty(M, K, dtype=torch.int32, device=DEV)

    def fn():
        ep_scatter(aq, aq_scale, topk_ids, expert_map, counts.clone(),
                   aq_out, aq_scale_out, m_indices, inv_perm, E_local, align)

    traffic = M * H + M_sum * H + M * K * 12 + M_sum * 12
    _bench_row(rows, "ep_scatter", f"M={M} H={H} K={K} E={E} A={align}",
               fn, traffic, overhead=lambda: counts.clone())


def _bench_ep_gather(rows, M, H, K):
    topk_ids, expert_map, E_local = make_topk(M, K, 8, with_map=False)
    mapped = map_ids(topk_ids, expert_map, E_local)
    valid = mapped >= 0
    M_sum = max(int(valid.sum()), M * K)

    a = torch.randn(M_sum, H, dtype=torch.bfloat16, device=DEV)
    inv_perm = torch.rand(M, K, device=DEV).mul(M_sum).int()
    topk_weights = torch.rand(M, K, dtype=torch.float32, device=DEV)
    out = torch.empty(M, H, dtype=torch.bfloat16, device=DEV)

    def fn():
        ep_gather(a, topk_ids, topk_weights, inv_perm, expert_map, out)

    traffic = M_sum * H * 2 + M * H * 2 + M * K * 20
    _bench_row(rows, "ep_gather", f"M={M} H={H} K={K}", fn, traffic)


def _bench_ep_build_m_indices(rows, M, K, E, align):
    topk_ids, _, E_local = make_topk(M, K, E, with_map=False)
    mapped = map_ids(topk_ids, None, E_local)
    _, counts, _, _, M_sum = layout(mapped, E_local, align)
    m_indices = torch.empty(M_sum, dtype=torch.int32, device=DEV)

    def fn():
        ep_build_m_indices(topk_ids, m_indices, E_local, align)

    traffic = M * K * 8 + M_sum * 4
    _bench_row(rows, "ep_build_m_indices", f"M={M} K={K} E={E} A={align}",
               fn, traffic)


def _bench_ep_fused_quant_scatter(rows, M, H, K, E, align, dtype):
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=False)
    mapped = map_ids(topk_ids, expert_map, E_local)
    _, counts, _, _, M_sum = layout(mapped, E_local, align)
    counts = counts.to(torch.int32)

    x = (torch.randn(M, H, device=DEV) * 3).to(dtype)
    aq_out = torch.empty(M_sum, H, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.empty(M_sum, 1, dtype=torch.float32, device=DEV)
    m_indices = torch.empty(M_sum, dtype=torch.int32, device=DEV)
    inv_perm = torch.empty(M, K, dtype=torch.int32, device=DEV)

    def fn():
        ep_fused_quant_scatter(x, topk_ids, expert_map, counts.clone(),
                               aq_out, aq_scale_out, m_indices, inv_perm,
                               E_local, align)

    traffic = M * H * x.element_size() + M_sum * H + M * K * 12 + M_sum * 8
    _bench_row(rows, "ep_fused_quant_scatter",
               f"M={M} H={H} K={K} E={E} A={align}", fn, traffic,
               overhead=lambda: counts.clone())


def _bench_ep_fused_fp8_quant_scatter(rows, M, H, K, E, align, dtype):
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=False)
    mapped = map_ids(topk_ids, expert_map, E_local)
    _, counts, _, _, M_sum = layout(mapped, E_local, align)
    counts = counts.to(torch.int32)

    x = (torch.randn(M, H, device=DEV) * 3).to(dtype)
    aq_out = torch.empty(M_sum, H, dtype=torch.uint8, device=DEV)
    aq_scale_out = torch.empty(M_sum, 1, dtype=torch.float32, device=DEV)
    m_indices = torch.empty(M_sum, dtype=torch.int32, device=DEV)
    inv_perm = torch.empty(M, K, dtype=torch.int32, device=DEV)

    def fn():
        ep_fused_fp8_quant_scatter(x, topk_ids, expert_map, counts.clone(),
                                   aq_out, aq_scale_out, m_indices, inv_perm,
                                   E_local, align, 0, True)

    traffic = M * H * x.element_size() + M_sum * H + M * K * 12 + M_sum * 8
    _bench_row(rows, "ep_fused_fp8_quant_scatter(e4m3)",
               f"M={M} H={H} K={K} E={E} A={align}", fn, traffic,
               overhead=lambda: counts.clone())


def _bench_ep_fused_smooth_quant_scatter(rows, M, H, K, E, align, dtype):
    topk_ids, expert_map, E_local = make_topk(M, K, E, with_map=False)
    mapped = map_ids(topk_ids, expert_map, E_local)
    _, counts, starts, _, M_sum = layout(mapped, E_local, align)
    starts = starts.to(torch.int32)

    x = (torch.randn(M, H, device=DEV) * 2).to(dtype)
    smooth = (torch.rand(E_local, H, device=DEV) + 0.5).float()
    aq_out = torch.empty(M_sum, H, dtype=torch.int8, device=DEV)
    aq_scale_out = torch.empty(M_sum, 1, dtype=torch.float32, device=DEV)
    m_indices = torch.empty(M_sum, dtype=torch.int32, device=DEV)
    inv_perm = torch.empty(M, K, dtype=torch.int32, device=DEV)

    def fn():
        ep_fused_smooth_quant_scatter(x, topk_ids, expert_map, starts.clone(),
                                      smooth, aq_out, aq_scale_out, m_indices,
                                      inv_perm, E_local, align)

    traffic = M * H * x.element_size() + M * K * H * 4 + M_sum * H + M * K * 12
    _bench_row(rows, "ep_fused_smooth_quant_scatter",
               f"M={M} H={H} K={K} E={E} A={align}", fn, traffic,
               overhead=lambda: starts.clone())


def _bench_family():
    rows = []
    for M in (64, 512, 4096, 8192):
        _bench_ep_scatter(rows, M, 7168, 8, 64, 256)
    for M in (64, 1024, 4096):
        _bench_ep_gather(rows, M, 7168, 8)
    _bench_ep_build_m_indices(rows, 4096, 8, 64, 128)
    for M in (64, 4096):
        _bench_ep_fused_quant_scatter(rows, M, 7168, 8, 64, 256, torch.bfloat16)
    for M in (64, 4096):
        _bench_ep_fused_fp8_quant_scatter(rows, M, 7168, 8, 64, 256, torch.bfloat16)
    for M in (64, 129, 1024, 4096):  # 64: tk kernel, 129: low-reg boundary
        _bench_ep_fused_smooth_quant_scatter(rows, M, 7168, 8, 64, 256, torch.bfloat16)

    print(f"\n{'op':34s} {'shape':32s} {'us':>10s} {'MB':>8s} {'TB/s':>7s}")
    for name, shape, us, mb, bw, pct in rows:
        print(f"{name:34s} {shape:32s} {us:10.1f} {mb:8.1f} {bw:7.3f}")


if __name__ == "__main__":
    import shutil
    import sys
    import tempfile

    argv = sys.argv[1:]
    do_bench = "--bench" in argv or os.environ.get("AITER_TEST_BENCH") == "1"
    argv = [a for a in argv if a != "--bench"]

    # pytest only collects .py files; when this script is run from a staged
    # copy with another extension, re-stage it under a .py name first.
    me = os.path.abspath(__file__)
    if not me.endswith(".py"):
        staged = os.path.join(tempfile.gettempdir(), "test_ep_scatter_family_v2.py")
        shutil.copyfile(me, staged)
        me = staged

    code = pytest.main(["-v", "--durations=10", *argv, me])
    if code == 0 and do_bench:
        torch.manual_seed(0)
        _bench_family()
    sys.exit(code)
