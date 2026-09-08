#!/usr/bin/env python
# SPDX-License-Identifier: MIT
"""Benchmark the B=192, H=HV=16, K=V=128 packed-decode case.

Run from the repository root:

    PYTHONPATH=. python \
      op_tests/op_benchmarks/bench_aiter_fused_recurrent_gated_delta_rule_packed_decode_hip_b192.py

The prefill input length is intentionally not used here.  This benchmark
covers one decode step per request:

    Q/K/V:         [192, 16, 128]      bf16
    mixed_qkv:     [192, 6144]         bf16
    a/b:           [192, 16]          bf16
    A_log:         [16]               fp32
    dt_bias:       [16]               bf16
    initial_state: [192, 16, 128, 128] bf16 by default
    out:           [192, 1, 16, 128]  bf16

Use ``--state-dtype fp32`` when the production state cache is FP32.
The benchmark timing uses explicit warmup + repeat loops so HIP and Triton
are exercised with the same number of operator invocations.
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


B = 192
H = 16
HV = 16
K = 128
V = 128
PREFILL_INPUT_LEN = 3343
DEFAULT_STATE_POOL = B
SCALE = K**-0.5
INPUT_DTYPE = torch.bfloat16
TRITON_KERNEL_CFG = {"BV": 32, "num_warps": 1, "num_stages": 2}


def parse_dtype(name: str) -> torch.dtype:
    if name == "bf16":
        return torch.bfloat16
    if name == "fp16":
        return torch.float16
    if name == "fp32":
        return torch.float32
    raise ValueError(f"unsupported dtype={name}")


def randn(
    shape: Tuple[int, ...],
    dtype: torch.dtype,
    scale: float,
    device: torch.device,
) -> torch.Tensor:
    return (torch.randn(shape, device=device, dtype=dtype) * scale).contiguous()


def make_inputs(args: argparse.Namespace) -> Dict[str, Any]:
    if args.state_pool < B:
        raise ValueError("--state-pool must be at least B=192")

    torch.manual_seed(args.seed)
    device = torch.device("cuda")
    state_dtype = parse_dtype(args.state_dtype)

    q = randn((B, H * K), INPUT_DTYPE, args.input_scale, device)
    k = randn((B, H * K), INPUT_DTYPE, args.input_scale, device)
    v = randn((B, HV * V), INPUT_DTYPE, args.input_scale, device)

    return {
        "mixed_qkv": torch.cat((q, k, v), dim=-1).contiguous(),
        "a": randn((B, HV), INPUT_DTYPE, args.gate_scale, device),
        "b": randn((B, HV), INPUT_DTYPE, args.gate_scale, device),
        "A_log": randn((HV,), torch.float32, args.gate_scale, device),
        "dt_bias": randn((HV,), INPUT_DTYPE, args.gate_scale, device),
        "initial_state": randn(
            (args.state_pool, HV, V, K), state_dtype, args.state_scale, device
        ),
        "out": torch.empty(
            (B, 1, HV, V), device=device, dtype=INPUT_DTYPE
        ),
        # Distinct rows avoid concurrent updates to one recurrent state slot.
        "ssm_state_indices": torch.arange(B, device=device, dtype=torch.int32),
        "scale": SCALE,
        "state_dtype": state_dtype,
        "state_pool": args.state_pool,
        "qk_l2norm": args.qk_l2norm,
    }


def clone_for_run(tensors: Dict[str, Any]) -> Dict[str, Any]:
    cloned = dict(tensors)
    cloned["initial_state"] = tensors["initial_state"].clone()
    cloned["out"] = torch.empty_like(tensors["out"])
    return cloned


def run_hip(tensors: Dict[str, Any]) -> Tuple[torch.Tensor, torch.Tensor]:
    return hip_packed_decode(
        mixed_qkv=tensors["mixed_qkv"],
        a=tensors["a"],
        b=tensors["b"],
        A_log=tensors["A_log"],
        dt_bias=tensors["dt_bias"],
        scale=tensors["scale"],
        initial_state=tensors["initial_state"],
        out=tensors["out"],
        ssm_state_indices=tensors["ssm_state_indices"],
        use_qk_l2norm_in_kernel=tensors["qk_l2norm"],
    )


def run_triton(tensors: Dict[str, Any]) -> Tuple[torch.Tensor, torch.Tensor]:
    return triton_packed_decode(
        mixed_qkv=tensors["mixed_qkv"],
        a=tensors["a"],
        b=tensors["b"],
        A_log=tensors["A_log"],
        dt_bias=tensors["dt_bias"],
        scale=tensors["scale"],
        initial_state=tensors["initial_state"],
        out=tensors["out"],
        ssm_state_indices=tensors["ssm_state_indices"],
        use_qk_l2norm_in_kernel=tensors["qk_l2norm"],
        kernel_cfg=TRITON_KERNEL_CFG,
    )


def compare_tensor(
    name: str,
    hip: torch.Tensor,
    triton_result: torch.Tensor,
    atol: float,
    rtol: float,
) -> Dict[str, Any]:
    hip_f = hip.float()
    triton_f = triton_result.float()
    diff = (hip_f - triton_f).abs()
    threshold = atol + rtol * triton_f.abs()
    finite = torch.isfinite(hip_f) & torch.isfinite(triton_f)
    finite_diff = diff[finite]
    finite_threshold = threshold[finite]

    if finite_diff.numel() == 0:
        max_abs = 0.0
        max_rel = 0.0
        within_tol = True
    else:
        max_abs = float(finite_diff.max().item())
        max_rel = float(
            (finite_diff / triton_f[finite].abs().clamp_min(1.0e-12)).max().item()
        )
        within_tol = bool((finite_diff <= finite_threshold).all().item())

    return {
        "name": name,
        "shape": list(hip.shape),
        "max_abs": max_abs,
        "max_rel": max_rel,
        "within_tol": within_tol,
        "mismatched": int((finite_diff > finite_threshold).sum().item()),
        "hip_nan": int(torch.isnan(hip_f).sum().item()),
        "triton_nan": int(torch.isnan(triton_f).sum().item()),
        "hip_inf": int(torch.isinf(hip_f).sum().item()),
        "triton_inf": int(torch.isinf(triton_f).sum().item()),
    }


def verify(
    tensors: Dict[str, Any],
    atol: float,
    rtol: float,
) -> Dict[str, Any]:
    hip_tensors = clone_for_run(tensors)
    triton_tensors = clone_for_run(tensors)
    hip_out, hip_state = run_hip(hip_tensors)
    triton_out, triton_state = run_triton(triton_tensors)
    torch.cuda.synchronize()

    rows = tensors["ssm_state_indices"].to(dtype=torch.long)
    hip_state_rows = hip_state.index_select(0, rows)
    triton_state_rows = triton_state.index_select(0, rows)
    out_stats = compare_tensor("out", hip_out, triton_out, atol, rtol)
    state_stats = compare_tensor(
        "final_state", hip_state_rows, triton_state_rows, atol, rtol
    )
    passed = (
        out_stats["within_tol"]
        and state_stats["within_tol"]
        and out_stats["hip_nan"] == 0
        and out_stats["triton_nan"] == 0
        and out_stats["hip_inf"] == 0
        and out_stats["triton_inf"] == 0
        and state_stats["hip_nan"] == 0
        and state_stats["triton_nan"] == 0
        and state_stats["hip_inf"] == 0
        and state_stats["triton_inf"] == 0
    )
    result = {
        "pass": passed,
        "out": out_stats,
        "final_state": state_stats,
    }
    if not passed:
        try:
            torch.testing.assert_close(
                hip_out.float(), triton_out.float(), atol=atol, rtol=rtol
            )
            torch.testing.assert_close(
                hip_state_rows.float(),
                triton_state_rows.float(),
                atol=atol,
                rtol=rtol,
            )
        except AssertionError as exc:
            result["error"] = str(exc)
    return result


def benchmark(fn: Callable[[], Any], warmup: int, rep: int) -> float:
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


def logical_bytes(state_dtype: torch.dtype) -> int:
    input_bytes = torch.empty((), dtype=INPUT_DTYPE).element_size()
    state_bytes = torch.empty((), dtype=state_dtype).element_size()
    return (
        B * (2 * H * K + HV * V) * input_bytes
        + 2 * B * HV * input_bytes
        + HV * 4
        + HV * input_bytes
        + B * 4
        + 2 * B * HV * V * K * state_bytes
        + B * HV * V * input_bytes
    )


def gbps(num_bytes: int, ms: float) -> float:
    return num_bytes / (ms * 1.0e-3) / 1.0e9


def tflops(flops: int, ms: float) -> float:
    return flops / (ms * 1.0e-3) / 1.0e12


def main() -> None:
    parser = argparse.ArgumentParser(
        "Benchmark HIP packed decode against Triton for B=192, H=HV=16"
    )
    parser.add_argument("--state-dtype", choices=("bf16", "fp16", "fp32"), default="bf16")
    parser.add_argument("--state-pool", type=int, default=DEFAULT_STATE_POOL)
    parser.add_argument("--input-scale", type=float, default=0.2)
    parser.add_argument("--gate-scale", type=float, default=0.2)
    parser.add_argument("--state-scale", type=float, default=0.05)
    parser.add_argument("--qk-l2norm", dest="qk_l2norm", action="store_true")
    parser.add_argument("--no-qk-l2norm", dest="qk_l2norm", action="store_false")
    parser.set_defaults(qk_l2norm=True)
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

    tensors = make_inputs(args)
    correctness = None
    if not args.no_verify:
        correctness = verify(tensors, args.atol, args.rtol)

    torch.cuda.empty_cache()
    hip_tensors = clone_for_run(tensors)
    triton_tensors = clone_for_run(tensors)
    run_hip(hip_tensors)
    run_triton(triton_tensors)
    torch.cuda.synchronize()

    hip_ms = benchmark(lambda: run_hip(hip_tensors), args.warmup, args.rep)
    triton_ms = benchmark(
        lambda: run_triton(triton_tensors), args.warmup, args.rep
    )

    flops = 6 * B * HV * V * K
    bytes_est = logical_bytes(tensors["state_dtype"])
    result = {
        "shape": {
            "prefill_input_len": PREFILL_INPUT_LEN,
            "B": B,
            "H": H,
            "HV": HV,
            "K": K,
            "V": V,
            "state_pool": tensors["state_pool"],
            "q": [B, H, K],
            "k": [B, H, K],
            "v": [B, HV, V],
            "mixed_qkv": list(tensors["mixed_qkv"].shape),
            "a": list(tensors["a"].shape),
            "b": list(tensors["b"].shape),
            "A_log": list(tensors["A_log"].shape),
            "dt_bias": list(tensors["dt_bias"].shape),
            "initial_state": list(tensors["initial_state"].shape),
            "out": list(tensors["out"].shape),
            "ssm_state_indices": list(tensors["ssm_state_indices"].shape),
            "mixed_qkv_dtype": str(tensors["mixed_qkv"].dtype),
            "gate_dtype": str(tensors["a"].dtype),
            "A_log_dtype": str(tensors["A_log"].dtype),
            "dt_bias_dtype": str(tensors["dt_bias"].dtype),
            "state_dtype": str(tensors["initial_state"].dtype),
            "out_dtype": str(tensors["out"].dtype),
            "indices_dtype": str(tensors["ssm_state_indices"].dtype),
            "qk_l2norm": tensors["qk_l2norm"],
            "scale": SCALE,
        },
        "triton": {
            "kernel_cfg": TRITON_KERNEL_CFG,
            "grid": [V // TRITON_KERNEL_CFG["BV"], B * HV],
        },
        "benchmark": {
            "warmup": args.warmup,
            "rep": args.rep,
            "hip_ms": hip_ms,
            "triton_ms": triton_ms,
            "hip_speedup_vs_triton": triton_ms / hip_ms,
            "flops_est": flops,
            "logical_bytes": bytes_est,
            "hip_tflops": tflops(flops, hip_ms),
            "triton_tflops": tflops(flops, triton_ms),
            "hip_gbps": gbps(bytes_est, hip_ms),
            "triton_gbps": gbps(bytes_est, triton_ms),
        },
        "correctness": correctness,
    }

    print("=" * 100)
    print(
        "HIP aiter_fused_recurrent_gated_delta_rule_packed_decode vs Triton | "
        f"prefill_input_len={PREFILL_INPUT_LEN} (decode metadata only) | "
        f"B={B} H={H} HV={HV} K={K} V={V} "
        f"state_pool={tensors['state_pool']} "
        f"state_dtype={tensors['initial_state'].dtype} device_id={args.device_id}"
    )
    print(
        f"mixed_qkv={tuple(tensors['mixed_qkv'].shape)} "
        f"q/k/v=({B}, {H}, {K}) "
        f"logical_bytes={bytes_est / 1.0e6:.3f} MB"
    )
    print(
        f"HIP    : {hip_ms:.4f} ms, {hip_ms * 1000.0:.2f} us, "
        f"{tflops(flops, hip_ms):.3f} TF, {gbps(bytes_est, hip_ms):.2f} GB/s"
    )
    print(
        f"Triton : {triton_ms:.4f} ms, {triton_ms * 1000.0:.2f} us, "
        f"{tflops(flops, triton_ms):.3f} TF, {gbps(bytes_est, triton_ms):.2f} GB/s, "
        f"HIP speedup {triton_ms / hip_ms:.4f}x"
    )
    if correctness is not None:
        print(
            "Verify : "
            f"{'PASS' if correctness['pass'] else 'FAIL'} | "
            f"out_abs={correctness['out']['max_abs']:.6g} "
            f"out_rel={correctness['out']['max_rel']:.6g} | "
            f"state_abs={correctness['final_state']['max_abs']:.6g} "
            f"state_rel={correctness['final_state']['max_rel']:.6g}"
        )
    print("=" * 100)

    if args.out_json:
        out_path = Path(args.out_json)
        out_path.parent.mkdir(parents=True, exist_ok=True)
        out_path.write_text(
            json.dumps(result, indent=2, sort_keys=True) + "\n", encoding="utf-8"
        )


if __name__ == "__main__":
    main()
