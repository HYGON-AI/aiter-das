#!/usr/bin/env python
# SPDX-License-Identifier: MIT
"""Benchmark the B=32 BF16-input, FP32-state packed-decode case.

Run from the repository root:

    PYTHONPATH=. python \
      op_tests/op_benchmarks/bench_aiter_fused_recurrent_gated_delta_rule_packed_decode_hip_b32.py

This case matches the reported workload:

    mixed_qkv [32, 8192]      bf16
    a/b       [32, 32]        bf16
    A_log     [32]             fp32
    dt_bias   [32]             bf16
    state     [716, 32, 128, 128] fp32
    out       [32, 1, 32, 128] bf16

The Triton side is fixed to BV=32, so its logical grid is (4, 1024).
"""

import argparse
import json
from pathlib import Path
from typing import Any, Callable, Dict, Tuple

import torch

from aiter.ops.fla import (
    aiter_fused_recurrent_gated_delta_rule_packed_decode as hip_packed_decode,
)
from aiter.ops.triton.fla.fused_recurrent import (
    fused_recurrent_gated_delta_rule_packed_decode as triton_packed_decode,
)


B = 32
H = 16
HV = 32
K = 128
V = 128
STATE_POOL = 716
SCALE = K ** -0.5
TRITON_BV = 32
TRITON_KERNEL_CFG = {"BV": TRITON_BV, "num_warps": 1, "num_stages": 2}


def randn(shape: Tuple[int, ...], dtype: torch.dtype, scale: float) -> torch.Tensor:
    return (torch.randn(shape, device="cuda", dtype=dtype) * scale).contiguous()


def make_inputs(seed: int) -> Dict[str, torch.Tensor]:
    torch.manual_seed(seed)
    q = randn((B, H * K), torch.bfloat16, 0.2)
    k = randn((B, H * K), torch.bfloat16, 0.2)
    v = randn((B, HV * V), torch.bfloat16, 0.2)
    return {
        "mixed_qkv": torch.cat((q, k, v), dim=-1).contiguous(),
        "a": randn((B, HV), torch.bfloat16, 0.2),
        "b": randn((B, HV), torch.bfloat16, 0.2),
        "A_log": randn((HV,), torch.float32, 0.2),
        "dt_bias": randn((HV,), torch.bfloat16, 0.2),
        "initial_state": randn((STATE_POOL, HV, V, K), torch.float32, 0.05),
        "out": torch.empty((B, 1, HV, V), device="cuda", dtype=torch.bfloat16),
        # Decode requests must update distinct state rows; otherwise B=32 would
        # introduce concurrent writes to the same recurrent state.
        "ssm_state_indices": torch.arange(B, device="cuda", dtype=torch.int32),
    }


def clone_for_run(tensors: Dict[str, torch.Tensor]) -> Dict[str, torch.Tensor]:
    cloned = dict(tensors)
    cloned["initial_state"] = tensors["initial_state"].clone()
    cloned["out"] = torch.empty_like(tensors["out"])
    return cloned


def run_hip(tensors: Dict[str, torch.Tensor]) -> Tuple[torch.Tensor, torch.Tensor]:
    return hip_packed_decode(
        mixed_qkv=tensors["mixed_qkv"],
        a=tensors["a"],
        b=tensors["b"],
        A_log=tensors["A_log"],
        dt_bias=tensors["dt_bias"],
        scale=SCALE,
        initial_state=tensors["initial_state"],
        out=tensors["out"],
        ssm_state_indices=tensors["ssm_state_indices"],
        use_qk_l2norm_in_kernel=True,
    )


def run_triton(tensors: Dict[str, torch.Tensor]) -> Tuple[torch.Tensor, torch.Tensor]:
    return triton_packed_decode(
        mixed_qkv=tensors["mixed_qkv"],
        a=tensors["a"],
        b=tensors["b"],
        A_log=tensors["A_log"],
        dt_bias=tensors["dt_bias"],
        scale=SCALE,
        initial_state=tensors["initial_state"],
        out=tensors["out"],
        ssm_state_indices=tensors["ssm_state_indices"],
        use_qk_l2norm_in_kernel=True,
        kernel_cfg=TRITON_KERNEL_CFG,
    )


def compare_tensor(
    name: str,
    lhs: torch.Tensor,
    rhs: torch.Tensor,
    atol: float,
    rtol: float,
) -> Dict[str, Any]:
    lhs_f = lhs.float()
    rhs_f = rhs.float()
    diff = (lhs_f - rhs_f).abs()
    threshold = atol + rtol * rhs_f.abs()
    finite = torch.isfinite(lhs_f) & torch.isfinite(rhs_f)
    finite_diff = diff[finite]
    finite_threshold = threshold[finite]
    if finite_diff.numel() == 0:
        max_abs = 0.0
        max_rel = 0.0
        mean_abs = 0.0
        within_tol = True
    else:
        max_abs = float(finite_diff.max().item())
        max_rel = float(
            (finite_diff / rhs_f[finite].abs().clamp_min(1.0e-12)).max().item()
        )
        mean_abs = float(finite_diff.mean().item())
        within_tol = bool((finite_diff <= finite_threshold).all().item())
    return {
        "name": name,
        "shape": list(lhs.shape),
        "max_abs": max_abs,
        "max_rel": max_rel,
        "mean_abs": mean_abs,
        "mismatched": int((finite_diff > finite_threshold).sum().item()),
        "finite": int(finite.sum().item()),
        "within_tol": within_tol,
        "hip_nan": int(torch.isnan(lhs_f).sum().item()),
        "triton_nan": int(torch.isnan(rhs_f).sum().item()),
        "hip_inf": int(torch.isinf(lhs_f).sum().item()),
        "triton_inf": int(torch.isinf(rhs_f).sum().item()),
    }


def verify(
    tensors: Dict[str, torch.Tensor],
    atol: float,
    rtol: float,
) -> Dict[str, Any]:
    hip_tensors = clone_for_run(tensors)
    triton_tensors = clone_for_run(tensors)
    hip_out, hip_state = run_hip(hip_tensors)
    triton_out, triton_state = run_triton(triton_tensors)
    torch.cuda.synchronize()

    state_rows = tensors["ssm_state_indices"].to(dtype=torch.long)
    hip_state_row = hip_state.index_select(0, state_rows)
    triton_state_row = triton_state.index_select(0, state_rows)
    out_stats = compare_tensor("out", hip_out, triton_out, atol, rtol)
    state_stats = compare_tensor(
        "final_state", hip_state_row, triton_state_row, atol, rtol
    )
    try:
        torch.testing.assert_close(
            hip_out.float(), triton_out.float(), atol=atol, rtol=rtol
        )
        torch.testing.assert_close(
            hip_state_row.float(), triton_state_row.float(), atol=atol, rtol=rtol
        )
        verify_pass = True
        verify_error = ""
    except AssertionError as exc:
        verify_pass = False
        verify_error = str(exc)
    return {
        "pass": verify_pass,
        "error": verify_error,
        "out": out_stats,
        "final_state": state_stats,
    }


def benchmark(
    fn: Callable[[], Any],
    warmup: int,
    rep: int,
) -> float:
    for _ in range(warmup):
        fn()
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    for _ in range(rep):
        fn()
    end.record()
    end.synchronize()
    return float(start.elapsed_time(end)) / rep


def logical_bytes() -> int:
    input_bytes = 2
    state_bytes = 4
    qkv_elems = 2 * H * K + HV * V
    return (
        B * qkv_elems * input_bytes
        + B * HV * (2 * input_bytes)
        + HV * (4 + input_bytes)
        + B * 4
        + 2 * B * HV * V * K * state_bytes
        + B * HV * V * input_bytes
    )


def gbps(num_bytes: int, ms: float) -> float:
    return num_bytes / (ms * 1.0e-3) / 1.0e9


def run_benchmark(
    args: argparse.Namespace,
    tensors: Dict[str, torch.Tensor],
) -> Dict[str, Any]:
    correctness = None
    if not args.no_verify:
        correctness = verify(tensors, args.atol, args.rtol)

    hip_tensors = clone_for_run(tensors)
    triton_tensors = clone_for_run(tensors)
    run_hip(hip_tensors)
    run_triton(triton_tensors)
    torch.cuda.synchronize()

    hip_ms = benchmark(lambda: run_hip(hip_tensors), args.warmup, args.rep)
    triton_ms = benchmark(
        lambda: run_triton(triton_tensors), args.warmup, args.rep
    )
    bytes_est = logical_bytes()
    result = {
        "shape": {
            "mixed_qkv": [B, 8192],
            "a": [B, HV],
            "b": [B, HV],
            "A_log": [HV],
            "dt_bias": [HV],
            "initial_state": [STATE_POOL, HV, V, K],
            "out": [B, 1, HV, V],
            "q": [B, H * K],
            "k": [B, H * K],
            "v": [B, HV * V],
            "mixed_qkv_dtype": "bfloat16",
            "a_dtype": "bfloat16",
            "b_dtype": "bfloat16",
            "A_log_dtype": "float32",
            "dt_bias_dtype": "bfloat16",
            "state_dtype": "float32",
            "out_dtype": "bfloat16",
            "indices_dtype": "int32",
            "qk_l2norm": True,
        },
        "triton": {
            "BV": TRITON_BV,
            "BK": K,
            "grid": [V // TRITON_BV, B * HV],
            "kernel_cfg": TRITON_KERNEL_CFG,
        },
        "benchmark": {
            "warmup": args.warmup,
            "rep": args.rep,
            "hip_ms": hip_ms,
            "triton_ms": triton_ms,
            "hip_speedup_vs_triton": triton_ms / hip_ms,
            "logical_bytes": bytes_est,
            "hip_gbps": gbps(bytes_est, hip_ms),
            "triton_gbps": gbps(bytes_est, triton_ms),
        },
        "correctness": correctness,
    }

    print("=" * 100)
    print(
        "B=32 H=16 HV=32 K=128 V=128 pool=716 | "
        "HIP aiter_fused_recurrent_gated_delta_rule_packed_decode vs Triton"
    )
    print(
        "dtype: mixed_qkv/a/b/dt_bias/out=bf16, A_log=fp32, state=fp32, "
        "indices=int32, qk_l2norm=True"
    )
    print(
        f"Triton: BV={TRITON_BV} BK={K} grid=({V // TRITON_BV}, {B * HV}) "
        f"cfg={TRITON_KERNEL_CFG}"
    )
    print(f"logical_bytes={bytes_est / 1.0e6:.3f} MB")
    print(f"HIP    : {hip_ms:.4f} ms, {hip_ms * 1000.0:.2f} us, {gbps(bytes_est, hip_ms):.2f} GB/s")
    print(
        f"Triton : {triton_ms:.4f} ms, {triton_ms * 1000.0:.2f} us, "
        f"{gbps(bytes_est, triton_ms):.2f} GB/s, HIP speedup {triton_ms / hip_ms:.4f}x"
    )
    if correctness is not None:
        print(
            "Verify : "
            f"{'PASS' if correctness['pass'] else 'FAIL'} | "
            f"out_abs={correctness['out']['max_abs']:.6g} "
            f"out_rel={correctness['out']['max_rel']:.6g} "
            f"state_abs={correctness['final_state']['max_abs']:.6g} "
            f"state_rel={correctness['final_state']['max_rel']:.6g}"
        )
        if not correctness["pass"]:
            print(correctness["error"])
    return result


def main() -> None:
    parser = argparse.ArgumentParser(
        "Benchmark the B=32 BF16-input, FP32-state packed-decode case"
    )
    parser.add_argument("--warmup", type=int, default=25)
    parser.add_argument("--rep", type=int, default=100)
    parser.add_argument("--seed", type=int, default=0)
    parser.add_argument("--device-id", type=int, default=1)
    parser.add_argument("--atol", type=float, default=5.0e-2)
    parser.add_argument("--rtol", type=float, default=5.0e-2)
    parser.add_argument("--no-verify", action="store_true")
    parser.add_argument("--out-json", type=str, default="")
    args = parser.parse_args()

    if not torch.cuda.is_available():
        raise RuntimeError("ROCm/HIP CUDA-compatible device is required")
    torch.cuda.set_device(args.device_id)
    tensors = make_inputs(args.seed)
    result = run_benchmark(args, tensors)
    if args.out_json:
        Path(args.out_json).write_text(json.dumps(result, indent=2) + "\n")


if __name__ == "__main__":
    main()
