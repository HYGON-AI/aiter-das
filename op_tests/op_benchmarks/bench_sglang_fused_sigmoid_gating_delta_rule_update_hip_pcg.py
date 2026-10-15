# SPDX-License-Identifier: MIT
"""Benchmark the SGLang target-verify GDN shape (H=8, HV=16, K=V=128) vs Triton.

Run from the repository root:

    PYTHONPATH=. python \
      op_tests/op_benchmarks/bench_sglang_gdn_target_verify_h8_hv16.py

Default logical shape (matches the reference capture):

    A_log                       [16]                    FP32
    a                           [4, 16]                 BF16
    dt_bias                     [16]                    BF16
    q                           [1, 4, 8, 128]          BF16
    k                           [1, 4, 8, 128]          BF16
    v                           [1, 4, 16, 128]         BF16
    b                           [4, 16]                 BF16
    initial_state_source        [188, 16, 128, 128]     FP32
    initial_state_indices       [1]                     INT32
    cu_seqlens                  [2]                     INT32
    intermediate_states_buffer  [38, 4, 16, 128, 128]   FP32
    intermediate_state_indices  [37]                    INT32

i.e. N=1 request, T=4 tokens, H=8 key heads, HV=16 value heads, h_ratio=2,
non-KDA gating, no eagle tree, state write-back disabled.

Note on the index tensors: they are pool sized, so they are longer than N and
only entries [0, N) are consumed by the kernel.  Correspondingly only the state
/ cache slots those entries point at are written, and the verification below
compares exactly those rows -- the rest of the buffers stay uninitialised.

Sweep N with --reqs-list to check the occupancy behaviour at larger batch:

    ... bench_sglang_gdn_target_verify_h8_hv16.py --reqs-list 1,4,8,16,32,48
"""

import argparse
import json
from pathlib import Path
from typing import Any, Dict, Tuple

import torch
import triton

import aiter
from aiter.ops.triton.fla.fused_sigmoid_gating_recurrent import (
    fused_sigmoid_gating_delta_rule_update as triton_fused_sigmoid_gating_delta_rule_update,
)


# --------------------------------------------------------------------------
# Reference capture defaults
# --------------------------------------------------------------------------
DEF_T = 4
DEF_H = 8
DEF_HV = 16
DEF_K = 128
DEF_V = 128
DEF_STATE_POOL = 188
DEF_CACHE_POOL = 38
DEF_CACHE_INDEX_POOL = 37


def parse_dtype(name: str) -> torch.dtype:
    if name == "fp16":
        return torch.float16
    if name == "bf16":
        return torch.bfloat16
    if name == "fp32":
        return torch.float32
    raise ValueError(f"unsupported dtype={name}")


def parse_int_list(text: str) -> Tuple[int, ...]:
    values = tuple(int(x.strip()) for x in text.split(",") if x.strip())
    if not values:
        raise ValueError("empty integer list")
    return values


def randn(shape: Tuple[int, ...], dtype: torch.dtype, scale: float) -> torch.Tensor:
    return (torch.randn(shape, device="cuda", dtype=dtype) * scale).contiguous()


# --------------------------------------------------------------------------
# Inputs
# --------------------------------------------------------------------------
def make_inputs(args: argparse.Namespace, N: int) -> Dict[str, Any]:
    if args.HV % args.H != 0:
        raise ValueError("--HV must be divisible by --H")
    if args.K > 128:
        raise ValueError("the HIP kernel supports K <= 128")

    dtype = parse_dtype(args.dtype)
    tokens = N * args.T

    state_pool = max(args.state_pool, N)
    cache_pool = max(args.cache_pool, N)
    cache_index_pool = max(args.cache_index_pool, N)

    # Pool-style slot tables: longer than N on purpose, only [0, N) is read.
    # Non-identity slots on purpose too, so a kernel that ignores the index
    # table cannot pass verification by accident.
    g = torch.Generator(device="cuda").manual_seed(args.seed)
    state_indices = torch.randperm(state_pool, device="cuda", generator=g)[:N]
    state_indices = state_indices.to(torch.int32).contiguous()

    cache_indices = torch.randperm(cache_pool, device="cuda", generator=g)
    if cache_index_pool > cache_pool:
        pad = torch.arange(
            cache_index_pool - cache_pool, device="cuda", dtype=cache_indices.dtype
        ) % cache_pool
        cache_indices = torch.cat([cache_indices, pad])
    cache_indices = cache_indices[:cache_index_pool].to(torch.int32).contiguous()

    return {
        "A_log": randn((args.HV,), torch.float32, args.input_scale),
        "a": randn((tokens, args.HV), dtype, args.input_scale),
        "dt_bias": randn((args.HV,), dtype, args.input_scale),
        "q": randn((1, tokens, args.H, args.K), dtype, args.input_scale),
        "k": randn((1, tokens, args.H, args.K), dtype, args.input_scale),
        "v": randn((1, tokens, args.HV, args.V), dtype, args.input_scale),
        "b": randn((tokens, args.HV), dtype, args.input_scale),
        "initial_state": randn(
            (state_pool, args.HV, args.V, args.K), torch.float32, args.state_scale
        ),
        "initial_state_indices": state_indices,
        "cu_seqlens": torch.arange(
            0, tokens + 1, args.T, device="cuda", dtype=torch.int32
        ).contiguous(),
        "intermediate_states_buffer": torch.empty(
            (cache_pool, args.T, args.HV, args.V, args.K),
            device="cuda",
            dtype=torch.float32,
        ),
        "intermediate_state_indices": cache_indices,
        "cache_steps": args.T,
        "N": N,
    }


def clone_for_run(inp: Dict[str, Any]) -> Dict[str, Any]:
    cloned = dict(inp)
    cloned["initial_state"] = inp["initial_state"].clone()
    cloned["intermediate_states_buffer"] = torch.empty_like(
        inp["intermediate_states_buffer"]
    )
    return cloned


def shape_dict(inp: Dict[str, Any]) -> Dict[str, list]:
    names = (
        "A_log",
        "a",
        "dt_bias",
        "q",
        "k",
        "v",
        "b",
        "initial_state",
        "initial_state_indices",
        "cu_seqlens",
        "intermediate_states_buffer",
        "intermediate_state_indices",
    )
    shapes = {n: list(inp[n].shape) for n in names}
    shapes["o"] = list(inp["v"].shape)
    return shapes


# --------------------------------------------------------------------------
# Calls
# --------------------------------------------------------------------------
def call_hip(args: argparse.Namespace, inp: Dict[str, Any]) -> torch.Tensor:
    return aiter.sglang_fused_sigmoid_gating_delta_rule_update(
        A_log=inp["A_log"],
        a=inp["a"],
        dt_bias=inp["dt_bias"],
        softplus_beta=args.softplus_beta,
        softplus_threshold=args.softplus_threshold,
        q=inp["q"],
        k=inp["k"],
        v=inp["v"],
        b=inp["b"],
        initial_state_source=inp["initial_state"],
        initial_state_indices=inp["initial_state_indices"],
        scale=args.scale,
        use_qk_l2norm_in_kernel=args.qk_l2norm,
        cu_seqlens=inp["cu_seqlens"],
        is_kda=False,
        disable_state_update=args.disable_state_update,
        intermediate_states_buffer=inp["intermediate_states_buffer"],
        intermediate_state_indices=inp["intermediate_state_indices"],
        cache_steps=inp["cache_steps"],
        retrieve_parent_token=None,
    )


def call_triton(args: argparse.Namespace, inp: Dict[str, Any]) -> torch.Tensor:
    return triton_fused_sigmoid_gating_delta_rule_update(
        A_log=inp["A_log"],
        a=inp["a"],
        dt_bias=inp["dt_bias"],
        softplus_beta=args.softplus_beta,
        softplus_threshold=args.softplus_threshold,
        q=inp["q"],
        k=inp["k"],
        v=inp["v"],
        b=inp["b"],
        initial_state_source=inp["initial_state"],
        initial_state_indices=inp["initial_state_indices"],
        scale=args.scale,
        use_qk_l2norm_in_kernel=args.qk_l2norm,
        cu_seqlens=inp["cu_seqlens"],
        is_kda=False,
        disable_state_update=args.disable_state_update,
        intermediate_states_buffer=inp["intermediate_states_buffer"],
        intermediate_state_indices=inp["intermediate_state_indices"],
        cache_steps=inp["cache_steps"],
        retrieve_parent_token=None,
    )


# --------------------------------------------------------------------------
# Verification
# --------------------------------------------------------------------------
def used_rows(indices: torch.Tensor, n: int) -> torch.Tensor:
    rows = indices[:n].to(torch.long)
    return torch.unique(rows[rows >= 0])


def verify(args: argparse.Namespace, inp: Dict[str, Any]) -> Dict[str, Any]:
    N = inp["N"]
    hip_inp = clone_for_run(inp)
    triton_inp = clone_for_run(inp)
    hip_out = call_hip(args, hip_inp)
    triton_out = call_triton(args, triton_inp)
    torch.cuda.synchronize()

    torch.testing.assert_close(
        hip_out.float(),
        triton_out.float(),
        rtol=args.rtol,
        atol=args.atol,
        equal_nan=True,
    )

    # Only the slots the index tables point at are defined; the rest of the
    # pool is still whatever torch.empty left there.
    cache_rows = used_rows(inp["intermediate_state_indices"], N)
    hip_cache = hip_inp["intermediate_states_buffer"].index_select(0, cache_rows)
    triton_cache = triton_inp["intermediate_states_buffer"].index_select(0, cache_rows)
    torch.testing.assert_close(
        hip_cache, triton_cache, rtol=args.rtol, atol=args.atol, equal_nan=True
    )

    state_rows = used_rows(inp["initial_state_indices"], N)
    if args.disable_state_update:
        # Nothing may be written back at all.
        torch.testing.assert_close(
            hip_inp["initial_state"], inp["initial_state"], rtol=0, atol=0
        )
        torch.testing.assert_close(
            triton_inp["initial_state"], inp["initial_state"], rtol=0, atol=0
        )
    else:
        torch.testing.assert_close(
            hip_inp["initial_state"].index_select(0, state_rows),
            triton_inp["initial_state"].index_select(0, state_rows),
            rtol=args.rtol,
            atol=args.atol,
            equal_nan=True,
        )

    return {
        "verify_pass": True,
        "out_max_abs": float((hip_out.float() - triton_out.float()).abs().max().item()),
        "cache_max_abs": float((hip_cache - triton_cache).abs().max().item()),
        "cache_rows_checked": int(cache_rows.numel()),
    }


# --------------------------------------------------------------------------
# Bandwidth model
# --------------------------------------------------------------------------
def estimate_bytes(args: argparse.Namespace, N: int) -> int:
    act = torch.tensor([], dtype=parse_dtype(args.dtype)).element_size()
    f32 = 4
    tokens = N * args.T
    slot_elems = args.HV * args.V * args.K

    qk = 2 * tokens * args.H * args.K * act
    v_in = tokens * args.HV * args.V * act
    out = tokens * args.HV * args.V * act
    gates = 2 * tokens * args.HV * act
    static_gates = args.HV * (f32 + act)

    state_read = N * slot_elems * f32
    state_write = 0 if args.disable_state_update else N * slot_elems * f32
    cache_write = tokens * slot_elems * f32

    return (
        qk
        + v_in
        + out
        + gates
        + static_gates
        + state_read
        + state_write
        + cache_write
    )


def gbps(num_bytes: int, ms: float) -> float:
    return num_bytes / (ms * 1e-3) / 1e9


# --------------------------------------------------------------------------
# Driver
# --------------------------------------------------------------------------
def bench_one(args: argparse.Namespace, N: int) -> Dict[str, Any]:
    inp = make_inputs(args, N)

    correctness = None
    if not args.no_verify and not args.skip_triton:
        correctness = verify(args, inp)

    hip_inp = clone_for_run(inp)
    triton_inp = clone_for_run(inp)
    call_hip(args, hip_inp)
    if not args.skip_triton:
        call_triton(args, triton_inp)
    torch.cuda.synchronize()

    hip_ms = float(
        triton.testing.do_bench(
            lambda: call_hip(args, hip_inp), warmup=args.warmup, rep=args.rep
        )
    )
    triton_ms = None
    if not args.skip_triton:
        triton_ms = float(
            triton.testing.do_bench(
                lambda: call_triton(args, triton_inp), warmup=args.warmup, rep=args.rep
            )
        )

    num_bytes = estimate_bytes(args, N)
    return {
        "shape": {
            "N": N,
            "T": args.T,
            "H": args.H,
            "HV": args.HV,
            "K": args.K,
            "V": args.V,
            "h_ratio": args.HV // args.H,
            "dtype": args.dtype,
            "is_kda": False,
            "target_verify": True,
            "disable_state_update": args.disable_state_update,
            "qk_l2norm": args.qk_l2norm,
            "state_pool": max(args.state_pool, N),
            "cache_pool": max(args.cache_pool, N),
            "cache_index_pool": max(args.cache_index_pool, N),
            "kernel_bv": args.kernel_bv,
            "kernel_num_warps": args.kernel_num_warps,
            "triton_bv": args.triton_bv,
            "triton_num_warps": args.triton_num_warps,
        },
        "tensor_shapes": shape_dict(inp),
        "bench": {
            "hip_ms": hip_ms,
            "triton_ms": triton_ms,
            "speedup_vs_triton": triton_ms / hip_ms if triton_ms is not None else None,
            "bytes_est": num_bytes,
            "hip_gbps": gbps(num_bytes, hip_ms),
            "triton_gbps": gbps(num_bytes, triton_ms) if triton_ms is not None else None,
        },
        "correctness": correctness,
    }


def print_result(result: Dict[str, Any]) -> None:
    s = result["shape"]
    bm = result["bench"]
    line = (
        f"N={s['N']:3d} T={s['T']:d} H={s['H']:d} HV={s['HV']:d} "
        f"K={s['K']:d} V={s['V']:d} dtype={s['dtype']} | "
        f"HIP={bm['hip_ms'] * 1000:9.2f} us {bm['hip_gbps']:8.2f} GB/s"
    )
    if bm["triton_ms"] is not None:
        line += (
            f" | Triton={bm['triton_ms'] * 1000:9.2f} us "
            f"{bm['triton_gbps']:8.2f} GB/s | speedup={bm['speedup_vs_triton']:.3f}x"
        )
    print(line)
    if result["correctness"] is not None:
        print("    verify=" + json.dumps(result["correctness"], sort_keys=True))


def main() -> None:
    p = argparse.ArgumentParser(
        "Benchmark SGLang target-verify GDN (H=8, HV=16, K=V=128) HIP vs Triton"
    )
    p.add_argument("--reqs-list", type=parse_int_list, default=(1,),
                   help="comma separated list of N (number of requests)")
    p.add_argument("--T", type=int, default=DEF_T, help="tokens per request = cache_steps")
    p.add_argument("--H", type=int, default=DEF_H)
    p.add_argument("--HV", type=int, default=DEF_HV)
    p.add_argument("--K", type=int, default=DEF_K)
    p.add_argument("--V", type=int, default=DEF_V)
    p.add_argument("--state-pool", type=int, default=DEF_STATE_POOL)
    p.add_argument("--cache-pool", type=int, default=DEF_CACHE_POOL)
    p.add_argument("--cache-index-pool", type=int, default=DEF_CACHE_INDEX_POOL)
    p.add_argument("--dtype", choices=("fp16", "bf16", "fp32"), default="bf16")
    p.add_argument("--input-scale", type=float, default=0.2)
    p.add_argument("--state-scale", type=float, default=0.02)
    p.add_argument("--softplus-beta", type=float, default=1.0)
    p.add_argument("--softplus-threshold", type=float, default=20.0)
    p.add_argument("--scale", type=float, default=None)
    p.add_argument("--qk-l2norm", action=argparse.BooleanOptionalAction, default=True)
    p.add_argument("--disable-state-update", action=argparse.BooleanOptionalAction,
                   default=True)
    p.add_argument("--kernel-bv", choices=(0, 16, 32, 64), type=int, default=0,
                   help="HIP tuning knob: 0=auto, 16/32/64 rows per block")
    p.add_argument("--kernel-num-warps", type=int, default=1,
                   help="accepted for API parity; HIP selection uses --kernel-bv")
    p.add_argument("--triton-bv", choices=(16, 32, 64), type=int, default=32)
    p.add_argument("--triton-num-warps", type=int, default=1)
    p.add_argument("--warmup", type=int, default=25)
    p.add_argument("--rep", type=int, default=100)
    p.add_argument("--seed", type=int, default=0)
    p.add_argument("--skip-triton", action="store_true")
    p.add_argument("--no-verify", action="store_true")
    p.add_argument("--rtol", type=float, default=6e-2)
    p.add_argument("--atol", type=float, default=6e-2)
    p.add_argument("--out-json", type=str, default="")
    args = p.parse_args()

    if not torch.cuda.is_available():
        raise RuntimeError("a ROCm/HIP device is required")

    torch.manual_seed(args.seed)

    print("=" * 120)
    print(
        "SGLang target-verify GDN | H={} HV={} (h_ratio={}) K={} V={} T={} "
        "dtype={} qk_l2norm={} disable_state_update={} | "
        "HIP_BV={} Triton_BV={} Triton_warps={}".format(
            args.H, args.HV, args.HV // args.H, args.K, args.V, args.T,
            args.dtype, args.qk_l2norm, args.disable_state_update,
            args.kernel_bv, args.triton_bv, args.triton_num_warps,
        )
    )
    print("-" * 120)

    results = []
    for N in args.reqs_list:
        result = bench_one(args, N)
        results.append(result)
        print_result(result)

    print("=" * 120)
    if results and results[0]["correctness"] is not None:
        print("tensor shapes (N={}):".format(results[0]["shape"]["N"]))
        for name, shape in results[0]["tensor_shapes"].items():
            print(f"    {name:28s} {shape}")
        print("=" * 120)

    if args.out_json:
        out_path = Path(args.out_json)
        out_path.parent.mkdir(parents=True, exist_ok=True)
        out_path.write_text(
            json.dumps(results, indent=2, sort_keys=True) + "\n", encoding="utf-8"
        )


if __name__ == "__main__":
    main()
