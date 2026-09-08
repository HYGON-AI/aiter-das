# SPDX-License-Identifier: MIT
"""Correctness and performance tests for store_kv_cache / store_kv_cache_paged."""

import argparse

import pytest
import torch

from aiter import dtypes
from aiter.ops.cache import store_kv_cache, store_kv_cache_paged
from aiter.test_common import checkAllclose, run_perftest

DEVICE = "cuda"
KV_CACHE_DTYPES = ["auto", "int8"]


def _make_accum_q_lens(q_lens: torch.Tensor) -> torch.Tensor:
    accum = torch.zeros_like(q_lens)
    if q_lens.numel() > 1:
        accum[1:] = torch.cumsum(q_lens[:-1], dim=0)
    return accum


def _make_kv_scales(
    kv_head_num: int, head_dim: int, kv_cache_dtype: str, device: str = DEVICE,
) -> tuple[torch.dtype, torch.Tensor, torch.Tensor]:
    if kv_cache_dtype == "auto":
        cache_dtype = dtypes.bf16
        k_scale = torch.ones(kv_head_num, head_dim, dtype=torch.float32, device=device)
        v_scale = torch.ones(kv_head_num, head_dim, dtype=torch.float32, device=device)
    elif kv_cache_dtype == "int8":
        cache_dtype = dtypes.i8
        k_scale = torch.rand(kv_head_num, head_dim, dtype=torch.float32, device=device) * 0.5 + 0.5
        v_scale = torch.rand(kv_head_num, head_dim, dtype=torch.float32, device=device) * 0.5 + 0.5
    else:
        raise ValueError(f"unsupported kv_cache_dtype: {kv_cache_dtype}")
    return cache_dtype, k_scale, v_scale


def _quantize_kv(
    k_src: torch.Tensor,
    v_src: torch.Tensor,
    kv_cache_dtype: str,
    k_scale: torch.Tensor,
    v_scale: torch.Tensor,
) -> tuple[torch.Tensor, torch.Tensor]:
    if kv_cache_dtype == "auto":
        return k_src, v_src
    if kv_cache_dtype == "int8":
        return (
            torch.round(k_src.float() * k_scale).to(torch.int8),
            torch.round(v_src.float() * v_scale).to(torch.int8),
        )
    raise ValueError(f"unsupported kv_cache_dtype: {kv_cache_dtype}")


def _assert_kv_cache_match(
    k_ref: torch.Tensor,
    v_ref: torch.Tensor,
    k_aiter: torch.Tensor,
    v_aiter: torch.Tensor,
    kv_cache_dtype: str,
    label: str,
) -> None:
    rtol, atol = (1e-2, 1e-2) if kv_cache_dtype == "auto" else (0.0, 0.0)
    checkAllclose(
        k_ref.to(dtypes.fp32), k_aiter.to(dtypes.fp32),
        rtol=rtol, atol=atol, msg=f"{label} k_cache",
    )
    checkAllclose(
        v_ref.to(dtypes.fp32), v_aiter.to(dtypes.fp32),
        rtol=rtol, atol=atol, msg=f"{label} v_cache",
    )


def ref_store_kv_cache(
    packed_qkv: torch.Tensor,
    q_lens: torch.Tensor,
    accum_q_lens: torch.Tensor,
    cache_lens: torch.Tensor,
    cache_slot_ids: torch.Tensor,
    q_head_num: int,
    kv_head_num: int,
    kv_cache_dtype: str,
    k_scale: torch.Tensor,
    v_scale: torch.Tensor,
    max_kv_len: int,
    num_cache_slots: int,
    head_dim: int,
    cache_dtype: torch.dtype,
) -> tuple[torch.Tensor, torch.Tensor]:
    k_cache = torch.zeros(
        num_cache_slots, kv_head_num, max_kv_len, head_dim,
        dtype=cache_dtype, device=packed_qkv.device,
    )
    v_cache = torch.zeros_like(k_cache)

    for batch_idx in range(q_lens.numel()):
        q_len = int(q_lens[batch_idx].item())
        if q_len == 0:
            continue
        q_token_offset = int(accum_q_lens[batch_idx].item())
        cache_start_pos = int(cache_lens[batch_idx].item())
        cache_slot_id = int(cache_slot_ids[batch_idx].item())

        for token_idx_in_q in range(q_len):
            abs_token_idx = q_token_offset + token_idx_in_q
            dst_token_idx = cache_start_pos + token_idx_in_q
            k_src = packed_qkv[abs_token_idx, q_head_num : q_head_num + kv_head_num, :]
            v_src = packed_qkv[
                abs_token_idx,
                q_head_num + kv_head_num : q_head_num + 2 * kv_head_num,
                :,
            ]
            k_dst, v_dst = _quantize_kv(k_src, v_src, kv_cache_dtype, k_scale, v_scale)
            k_cache[cache_slot_id, :, dst_token_idx, :] = k_dst
            v_cache[cache_slot_id, :, dst_token_idx, :] = v_dst

    return k_cache, v_cache


def ref_store_kv_cache_paged(
    key: torch.Tensor,
    value: torch.Tensor,
    q_lens: torch.Tensor,
    accum_q_lens: torch.Tensor,
    cache_lens: torch.Tensor,
    block_table: torch.Tensor,
    kv_cache_dtype: str,
    k_scale: torch.Tensor,
    v_scale: torch.Tensor,
    block_size: int,
    num_physical_blocks: int,
    cache_dtype: torch.dtype,
) -> tuple[torch.Tensor, torch.Tensor]:
    kv_head_num = key.shape[1]
    head_dim = key.shape[2]
    k_cache = torch.zeros(
        num_physical_blocks, kv_head_num, block_size, head_dim,
        dtype=cache_dtype, device=key.device,
    )
    v_cache = torch.zeros_like(k_cache)

    for batch_idx in range(q_lens.numel()):
        q_len = int(q_lens[batch_idx].item())
        if q_len == 0:
            continue
        q_token_offset = int(accum_q_lens[batch_idx].item())
        cache_start_pos = int(cache_lens[batch_idx].item())

        for token_idx_in_q in range(q_len):
            abs_token_idx = q_token_offset + token_idx_in_q
            dst_token_idx = cache_start_pos + token_idx_in_q
            logical_block_idx = dst_token_idx // block_size
            offset_in_block = dst_token_idx % block_size
            physical_block_id = int(block_table[batch_idx, logical_block_idx].item())

            k_dst, v_dst = _quantize_kv(
                key[abs_token_idx], value[abs_token_idx],
                kv_cache_dtype, k_scale, v_scale,
            )
            k_cache[physical_block_id, :, offset_in_block, :] = k_dst
            v_cache[physical_block_id, :, offset_in_block, :] = v_dst

    return k_cache, v_cache


def _setup_store_kv_cache_tensors(
    batch_size: int,
    q_lens_list: list[int],
    q_head_num: int,
    kv_head_num: int,
    head_dim: int,
    max_kv_len: int,
    kv_cache_dtype: str,
    seed: int,
) -> dict:
    torch.manual_seed(seed)
    q_lens = torch.tensor(q_lens_list, dtype=torch.int32, device=DEVICE)
    accum_q_lens = _make_accum_q_lens(q_lens)
    total_tokens = int(q_lens.sum().item())
    cache_lens = torch.randint(
        0, max(1, max_kv_len - max(q_lens_list) - 1),
        (batch_size,), dtype=torch.int32, device=DEVICE,
    )
    cache_slot_ids = torch.arange(batch_size, dtype=torch.int32, device=DEVICE) + 1
    cache_dtype, k_scale, v_scale = _make_kv_scales(kv_head_num, head_dim, kv_cache_dtype)
    num_cache_slots = batch_size + 2
    k_cache = torch.zeros(
        num_cache_slots, kv_head_num, max_kv_len, head_dim,
        dtype=cache_dtype, device=DEVICE,
    )

    return {
        "packed_qkv": torch.randn(
            total_tokens, q_head_num + 2 * kv_head_num, head_dim,
            dtype=dtypes.bf16, device=DEVICE,
        ),
        "k_cache": k_cache,
        "v_cache": torch.zeros_like(k_cache),
        "q_lens": q_lens,
        "accum_q_lens": accum_q_lens,
        "cache_lens": cache_lens,
        "cache_slot_ids": cache_slot_ids,
        "k_scale": k_scale,
        "v_scale": v_scale,
        "kv_cache_dtype": kv_cache_dtype,
        "q_head_num": q_head_num,
        "kv_head_num": kv_head_num,
        "head_dim": head_dim,
        "total_tokens": total_tokens,
        "num_cache_slots": num_cache_slots,
        "max_kv_len": max_kv_len,
        "cache_dtype": cache_dtype,
    }


def _setup_store_kv_cache_paged_tensors(
    batch_size: int,
    q_lens_list: list[int],
    kv_head_num: int,
    head_dim: int,
    block_size: int,
    max_blocks_per_seq: int,
    kv_cache_dtype: str,
    seed: int,
) -> dict:
    torch.manual_seed(seed)
    q_lens = torch.tensor(q_lens_list, dtype=torch.int32, device=DEVICE)
    accum_q_lens = _make_accum_q_lens(q_lens)
    total_tokens = int(q_lens.sum().item())
    max_seq_len = max(q_lens_list) + 32
    cache_lens = torch.randint(
        0, max(1, max_seq_len - max(q_lens_list)),
        (batch_size,), dtype=torch.int32, device=DEVICE,
    )

    block_table = torch.zeros(
        batch_size, max_blocks_per_seq, dtype=torch.int32, device=DEVICE,
    )
    for b in range(batch_size):
        base = b * max_blocks_per_seq + 1
        block_table[b] = torch.arange(
            base, base + max_blocks_per_seq, dtype=torch.int32, device=DEVICE,
        )
    num_physical_blocks = int(block_table.max().item()) + 1
    cache_dtype, k_scale, v_scale = _make_kv_scales(kv_head_num, head_dim, kv_cache_dtype)

    k_cache = torch.zeros(
        num_physical_blocks, kv_head_num, block_size, head_dim,
        dtype=cache_dtype, device=DEVICE,
    )
    return {
        "key": torch.randn(total_tokens, kv_head_num, head_dim, dtype=dtypes.bf16, device=DEVICE),
        "value": torch.randn(total_tokens, kv_head_num, head_dim, dtype=dtypes.bf16, device=DEVICE),
        "k_cache": k_cache,
        "v_cache": torch.zeros_like(k_cache),
        "q_lens": q_lens,
        "accum_q_lens": accum_q_lens,
        "cache_lens": cache_lens,
        "block_table": block_table,
        "k_scale": k_scale,
        "v_scale": v_scale,
        "kv_cache_dtype": kv_cache_dtype,
        "kv_head_num": kv_head_num,
        "head_dim": head_dim,
        "total_tokens": total_tokens,
        "batch_size": batch_size,
        "max_blocks_per_seq": max_blocks_per_seq,
        "block_size": block_size,
        "num_physical_blocks": num_physical_blocks,
        "cache_dtype": cache_dtype,
    }


def _run_store_kv_cache_case(
    batch_size: int,
    q_lens_list: list[int],
    q_head_num: int,
    kv_head_num: int,
    head_dim: int,
    max_kv_len: int,
    kv_cache_dtype: str,
    seed: int,
    label: str,
) -> None:
    t = _setup_store_kv_cache_tensors(
        batch_size, q_lens_list, q_head_num, kv_head_num, head_dim,
        max_kv_len, kv_cache_dtype, seed,
    )
    k_ref, v_ref = ref_store_kv_cache(
        t["packed_qkv"], t["q_lens"], t["accum_q_lens"], t["cache_lens"], t["cache_slot_ids"],
        t["q_head_num"], t["kv_head_num"], t["kv_cache_dtype"], t["k_scale"], t["v_scale"],
        t["max_kv_len"], t["num_cache_slots"], t["head_dim"], t["cache_dtype"],
    )
    k_aiter = torch.zeros_like(k_ref)
    v_aiter = torch.zeros_like(v_ref)
    store_kv_cache(
        t["packed_qkv"], k_aiter, v_aiter, t["q_lens"], t["accum_q_lens"], t["cache_lens"],
        t["cache_slot_ids"], t["k_scale"], t["v_scale"], t["kv_cache_dtype"],
        t["q_head_num"], t["kv_head_num"],
    )
    torch.cuda.synchronize()
    _assert_kv_cache_match(k_ref, v_ref, k_aiter, v_aiter, kv_cache_dtype, label)


def _run_store_kv_cache_paged_case(
    batch_size: int,
    q_lens_list: list[int],
    kv_head_num: int,
    head_dim: int,
    block_size: int,
    max_blocks_per_seq: int,
    kv_cache_dtype: str,
    seed: int,
    label: str,
) -> None:
    t = _setup_store_kv_cache_paged_tensors(
        batch_size, q_lens_list, kv_head_num, head_dim, block_size,
        max_blocks_per_seq, kv_cache_dtype, seed,
    )
    k_ref, v_ref = ref_store_kv_cache_paged(
        t["key"], t["value"], t["q_lens"], t["accum_q_lens"], t["cache_lens"], t["block_table"],
        t["kv_cache_dtype"], t["k_scale"], t["v_scale"],
        t["block_size"], t["num_physical_blocks"], t["cache_dtype"],
    )
    k_aiter = torch.zeros_like(t["k_cache"])
    v_aiter = torch.zeros_like(t["v_cache"])
    store_kv_cache_paged(
        t["key"], t["value"], k_aiter, v_aiter, t["q_lens"], t["accum_q_lens"], t["cache_lens"],
        t["block_table"], t["k_scale"], t["v_scale"], t["kv_cache_dtype"],
    )
    torch.cuda.synchronize()
    _assert_kv_cache_match(k_ref, v_ref, k_aiter, v_aiter, kv_cache_dtype, label)


def _estimate_kv_store_io_bytes(
    total_tokens: int,
    kv_head_num: int,
    head_dim: int,
    input_elem_size: int,
    cache_elem_size: int,
    extra_meta: int = 0,
) -> int:
    kv_elems = total_tokens * kv_head_num * head_dim * 2
    return (
        kv_elems * (input_elem_size + cache_elem_size)
        + kv_head_num * head_dim * 4 * 2
        + 4096
        + extra_meta
    )


def _print_perf_result(
    label: str,
    total_tokens: int,
    kv_head_num: int,
    head_dim: int,
    kv_cache_dtype: str,
    io_bytes: int,
    us: float,
) -> None:
    gbps = io_bytes / us / 1e3
    tbps = io_bytes / us / 1e6
    print(
        f"[perf] {label:<40} tokens={total_tokens:<6} kv_heads={kv_head_num:<3} "
        f"head_dim={head_dim:<4} dtype={kv_cache_dtype:<5} "
        f"io={io_bytes / 1e9:.4f} GB  time={us:>8.2f} us  "
        f"bw={gbps:>8.2f} GB/s ({tbps:.3f} TB/s)"
    )


def benchmark_store_kv_cache(
    batch_size: int,
    q_lens_list: list[int],
    q_head_num: int,
    kv_head_num: int,
    head_dim: int,
    max_kv_len: int,
    kv_cache_dtype: str,
    seed: int,
    label: str,
    num_iters: int = 101,
) -> float:
    t = _setup_store_kv_cache_tensors(
        batch_size, q_lens_list, q_head_num, kv_head_num, head_dim,
        max_kv_len, kv_cache_dtype, seed,
    )
    _, us = run_perftest(
        store_kv_cache,
        t["packed_qkv"], t["k_cache"], t["v_cache"],
        t["q_lens"], t["accum_q_lens"], t["cache_lens"], t["cache_slot_ids"],
        t["k_scale"], t["v_scale"], t["kv_cache_dtype"],
        t["q_head_num"], t["kv_head_num"],
        num_iters=num_iters,
    )
    io_bytes = _estimate_kv_store_io_bytes(
        t["total_tokens"], kv_head_num, head_dim,
        t["packed_qkv"].element_size(), t["k_cache"].element_size(),
    )
    _print_perf_result(label, t["total_tokens"], kv_head_num, head_dim, kv_cache_dtype, io_bytes, us)
    return us


def benchmark_store_kv_cache_paged(
    batch_size: int,
    q_lens_list: list[int],
    kv_head_num: int,
    head_dim: int,
    block_size: int,
    max_blocks_per_seq: int,
    kv_cache_dtype: str,
    seed: int,
    label: str,
    num_iters: int = 101,
) -> float:
    t = _setup_store_kv_cache_paged_tensors(
        batch_size, q_lens_list, kv_head_num, head_dim, block_size,
        max_blocks_per_seq, kv_cache_dtype, seed,
    )
    _, us = run_perftest(
        store_kv_cache_paged,
        t["key"], t["value"], t["k_cache"], t["v_cache"],
        t["q_lens"], t["accum_q_lens"], t["cache_lens"], t["block_table"],
        t["k_scale"], t["v_scale"], t["kv_cache_dtype"],
        num_iters=num_iters,
    )
    io_bytes = _estimate_kv_store_io_bytes(
        t["total_tokens"], kv_head_num, head_dim,
        t["key"].element_size(), t["k_cache"].element_size(),
        extra_meta=t["batch_size"] * t["max_blocks_per_seq"] * 4,
    )
    _print_perf_result(label, t["total_tokens"], kv_head_num, head_dim, kv_cache_dtype, io_bytes, us)
    return us


STORE_KV_CACHE_CASES = [
    pytest.param(
        dict(name="decode", batch_size=1, q_lens_list=[1], q_head_num=8, kv_head_num=2, head_dim=128, max_kv_len=256, seed=0),
        id="decode",
    ),
    pytest.param(
        dict(name="prefill", batch_size=1, q_lens_list=[17], q_head_num=8, kv_head_num=2, head_dim=128, max_kv_len=512, seed=1),
        id="prefill",
    ),
    pytest.param(
        dict(name="batch", batch_size=4, q_lens_list=[1, 7, 3, 0], q_head_num=16, kv_head_num=4, head_dim=64, max_kv_len=1024, seed=2),
        id="batch",
    ),
]

STORE_KV_CACHE_PAGED_CASES = [
    pytest.param(
        dict(name="decode", batch_size=1, q_lens_list=[1], kv_head_num=2, head_dim=128, block_size=16, max_blocks_per_seq=32, seed=3),
        id="decode",
    ),
    pytest.param(
        dict(name="prefill", batch_size=1, q_lens_list=[23], kv_head_num=2, head_dim=128, block_size=16, max_blocks_per_seq=32, seed=4),
        id="prefill",
    ),
    pytest.param(
        dict(name="batch", batch_size=3, q_lens_list=[2, 11, 5], kv_head_num=4, head_dim=64, block_size=8, max_blocks_per_seq=24, seed=5),
        id="batch",
    ),
]

PERF_STORE_KV_CACHE_CASES = [
    ("store_kv_cache decode", dict(batch_size=1, q_lens_list=[1], q_head_num=8, kv_head_num=2, head_dim=128, max_kv_len=256, seed=10)),
    ("store_kv_cache prefill", dict(batch_size=1, q_lens_list=[512], q_head_num=8, kv_head_num=2, head_dim=128, max_kv_len=2048, seed=11)),
    ("store_kv_cache batch", dict(batch_size=8, q_lens_list=[1, 128, 64, 32, 16, 8, 4, 2], q_head_num=16, kv_head_num=4, head_dim=128, max_kv_len=4096, seed=12)),
]

PERF_STORE_KV_CACHE_PAGED_CASES = [
    ("store_kv_cache_paged decode", dict(batch_size=1, q_lens_list=[1], kv_head_num=2, head_dim=128, block_size=16, max_blocks_per_seq=32, seed=13)),
    ("store_kv_cache_paged prefill", dict(batch_size=1, q_lens_list=[512], kv_head_num=2, head_dim=128, block_size=16, max_blocks_per_seq=64, seed=14)),
    ("store_kv_cache_paged batch", dict(batch_size=4, q_lens_list=[1, 128, 64, 32], kv_head_num=4, head_dim=128, block_size=16, max_blocks_per_seq=32, seed=15)),
]


def run_perf_tests(kv_cache_dtypes: list[str], num_iters: int = 101) -> None:
    print("=" * 72)
    print("PERFORMANCE BENCHMARK (store_kv_cache / store_kv_cache_paged)")
    print("=" * 72)
    for kv_cache_dtype in kv_cache_dtypes:
        for label, case in PERF_STORE_KV_CACHE_CASES:
            benchmark_store_kv_cache(
                **case, kv_cache_dtype=kv_cache_dtype,
                label=f"{label} {kv_cache_dtype}", num_iters=num_iters,
            )
        for label, case in PERF_STORE_KV_CACHE_PAGED_CASES:
            benchmark_store_kv_cache_paged(
                **case, kv_cache_dtype=kv_cache_dtype,
                label=f"{label} {kv_cache_dtype}", num_iters=num_iters,
            )


@pytest.mark.parametrize("kv_cache_dtype", KV_CACHE_DTYPES)
@pytest.mark.parametrize("case", STORE_KV_CACHE_CASES)
def test_store_kv_cache(case, kv_cache_dtype):
    case_args = {k: v for k, v in case.items() if k != "name"}
    _run_store_kv_cache_case(
        **case_args, kv_cache_dtype=kv_cache_dtype,
        label=f"store_kv_cache {case['name']} {kv_cache_dtype}",
    )


@pytest.mark.parametrize("kv_cache_dtype", KV_CACHE_DTYPES)
@pytest.mark.parametrize("case", STORE_KV_CACHE_PAGED_CASES)
def test_store_kv_cache_paged(case, kv_cache_dtype):
    case_args = {k: v for k, v in case.items() if k != "name"}
    _run_store_kv_cache_paged_case(
        **case_args, kv_cache_dtype=kv_cache_dtype,
        label=f"store_kv_cache_paged {case['name']} {kv_cache_dtype}",
    )


@pytest.mark.parametrize("kv_cache_dtype", KV_CACHE_DTYPES)
@pytest.mark.parametrize("label,case", PERF_STORE_KV_CACHE_CASES)
def test_perf_store_kv_cache(kv_cache_dtype, label, case):
    us = benchmark_store_kv_cache(
        **case, kv_cache_dtype=kv_cache_dtype,
        label=f"{label} {kv_cache_dtype}", num_iters=21,
    )
    assert us > 0


@pytest.mark.parametrize("kv_cache_dtype", KV_CACHE_DTYPES)
@pytest.mark.parametrize("label,case", PERF_STORE_KV_CACHE_PAGED_CASES)
def test_perf_store_kv_cache_paged(kv_cache_dtype, label, case):
    us = benchmark_store_kv_cache_paged(
        **case, kv_cache_dtype=kv_cache_dtype,
        label=f"{label} {kv_cache_dtype}", num_iters=21,
    )
    assert us > 0


if __name__ == "__main__":
    parser = argparse.ArgumentParser(description="store_kv_cache correctness and perf tests")
    parser.add_argument("--pytest", action="store_true", help="run via pytest")
    parser.add_argument("--bench", action="store_true", help="run performance benchmark")
    parser.add_argument(
        "--kv-cache-dtype", choices=["auto", "int8", "all"], default="all",
        help="kv cache dtype for --bench (default: all)",
    )
    parser.add_argument("--num-iters", type=int, default=101, help="benchmark iterations")
    args = parser.parse_args()

    if args.pytest:
        raise SystemExit(pytest.main([__file__]))
    if args.bench:
        dtypes_to_run = KV_CACHE_DTYPES if args.kv_cache_dtype == "all" else [args.kv_cache_dtype]
        run_perf_tests(dtypes_to_run, num_iters=args.num_iters)
    else:
        raise SystemExit(pytest.main([__file__, "-k", "not test_perf", "-v"]))
