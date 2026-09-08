# SPDX-License-Identifier: MIT
"""Benchmark HIP packed-decode fused recurrent gated delta rule against Triton.

Run from the repository root:

    PYTHONPATH=. python \
      op_tests/op_benchmarks/bench_aiter_fused_recurrent_gated_delta_rule_packed_decode_hip.py

The default cases mirror the two target packed-decode shapes:

    q/k [256, 2048], v [256, 4096], state [910, 32, 128, 128]
    q/k [256, 1024], v [256, 2048], state [3582, 16, 128, 128]

The public HIP wrapper keeps the Triton API shape: it accepts packed
``mixed_qkv`` plus ``a``/``b`` gating tensors and returns ``(out, initial_state)``.
Use ``--no-verify`` for profiling runs where only timing is needed.
"""

from __future__ import annotations

import argparse
import json
from dataclasses import asdict, dataclass
from pathlib import Path
from typing import Any

import torch
import triton

from aiter.ops.fla import (
    aiter_fused_recurrent_gated_delta_rule_packed_decode as hip_packed_decode,
)
from aiter.ops.triton.fla.fused_recurrent import (
    fused_recurrent_gated_delta_rule_packed_decode as triton_packed_decode,
)

HIP_IMPL = "schemeL:grid_hv_b_G4_T512_state_kpack8_coalesced"


@dataclass(frozen=True)
class PackedDecodeCase:
    name: str
    batch: int
    heads: int
    value_heads: int
    k_dim: int
    v_dim: int
    state_pool: int


DEFAULT_CASES = {
    "q2048_v4096_pool910": PackedDecodeCase(
        name="q2048_v4096_pool910",
        batch=256,
        heads=16,
        value_heads=32,
        k_dim=128,
        v_dim=128,
        state_pool=910,
    ),
    "q1024_v2048_pool3582": PackedDecodeCase(
        name="q1024_v2048_pool3582",
        batch=256,
        heads=8,
        value_heads=16,
        k_dim=128,
        v_dim=128,
        state_pool=3582,
    ),
}


def parse_dtype(name: str) -> torch.dtype:
    if name == "fp16":
        return torch.float16
    if name == "bf16":
        return torch.bfloat16
    if name == "fp32":
        return torch.float32
    raise ValueError(f"unsupported dtype={name}")


def estimate_packed_decode_flops(case: PackedDecodeCase) -> int:
    return 6 * case.batch * case.value_heads * case.v_dim * case.k_dim


def estimate_packed_decode_bytes(
    case: PackedDecodeCase,
    input_dtype: torch.dtype,
    state_dtype: torch.dtype,
) -> int:
    input_elem = torch.empty((), dtype=input_dtype).element_size()
    state_elem = torch.empty((), dtype=state_dtype).element_size()
    gate_elem = torch.empty((), dtype=torch.float32).element_size()
    qkv_elems = case.batch * (2 * case.heads * case.k_dim + case.value_heads * case.v_dim)
    bytes_mixed_qkv = qkv_elems * input_elem
    bytes_gates = (
        2 * case.batch * case.value_heads * gate_elem
        + 2 * case.value_heads * gate_elem
    )
    bytes_indices = case.batch * 4
    bytes_state_rw = 2 * case.batch * case.value_heads * case.v_dim * case.k_dim * state_elem
    bytes_out = case.batch * case.value_heads * case.v_dim * input_elem
    return bytes_mixed_qkv + bytes_gates + bytes_indices + bytes_state_rw + bytes_out


def tflops(flops: int, ms: float) -> float:
    return flops / (ms * 1e-3) / 1e12


def gbps(num_bytes: int, ms: float) -> float:
    return num_bytes / (ms * 1e-3) / 1e9


def bytes_to_mb(num_bytes: int) -> float:
    return num_bytes / 1e6


def tensor_stats(
    prefix: str,
    hip: torch.Tensor,
    tri: torch.Tensor,
    *,
    rtol: float | None = None,
    atol: float | None = None,
) -> dict[str, float | int | bool]:
    finite = torch.isfinite(hip) & torch.isfinite(tri)
    if finite.any():
        hip_f = hip[finite].float()
        tri_f = tri[finite].float()
        abs_diff = (hip_f - tri_f).abs()
        max_abs = float(abs_diff.max().item())
        if rtol is not None and atol is not None:
            denom = (atol + rtol * tri_f.abs()).clamp_min(1e-12)
        else:
            denom = tri_f.abs().clamp_min(1e-6)
        rel = abs_diff / denom
        max_rel = float(rel.max().item())
        mean_rel = float(rel.mean().item())
    else:
        max_abs = 0.0
        max_rel = 0.0
        mean_rel = 0.0

    stats: dict[str, float | int | bool] = {
        f"{prefix}_max_abs_finite": max_abs,
        f"{prefix}_max_rel_finite": max_rel,
        f"{prefix}_mean_rel_finite": mean_rel,
        f"{prefix}_hip_nan": int(torch.isnan(hip).sum().item()),
        f"{prefix}_triton_nan": int(torch.isnan(tri).sum().item()),
        f"{prefix}_hip_inf": int(torch.isinf(hip).sum().item()),
        f"{prefix}_triton_inf": int(torch.isinf(tri).sum().item()),
    }
    if rtol is not None and atol is not None:
        if finite.any():
            threshold = atol + rtol * tri_f.abs()
            within = abs_diff <= threshold
            stats[f"{prefix}_within_tol"] = bool(within.all().item())
            stats[f"{prefix}_max_violation"] = float(
                (abs_diff - threshold).clamp_min(0.0).max().item()
            )
        else:
            stats[f"{prefix}_within_tol"] = True
            stats[f"{prefix}_max_violation"] = 0.0
    return stats


def randn(shape: tuple[int, ...], dtype: torch.dtype, scale: float) -> torch.Tensor:
    return (torch.randn(shape, device="cuda", dtype=dtype) * scale).contiguous()


def make_inputs(args: argparse.Namespace, case: PackedDecodeCase) -> dict[str, Any]:
    if case.value_heads % case.heads != 0:
        raise ValueError("value_heads must be divisible by heads")
    if case.state_pool < case.batch and not args.allow_duplicate_indices:
        raise ValueError("state_pool must cover batch when duplicate indices are disabled")

    torch.manual_seed(args.seed)
    input_dtype = parse_dtype(args.dtype)
    state_dtype = parse_dtype(args.state_dtype)

    q = randn((case.batch, case.heads * case.k_dim), input_dtype, args.input_scale)
    k = randn((case.batch, case.heads * case.k_dim), input_dtype, args.input_scale)
    v = randn((case.batch, case.value_heads * case.v_dim), input_dtype, args.input_scale)
    mixed_qkv = torch.cat((q, k, v), dim=-1).contiguous()

    a = randn((case.batch, case.value_heads), torch.float32, args.gate_scale)
    b = randn((case.batch, case.value_heads), torch.float32, args.gate_scale)
    A_log = randn((case.value_heads,), torch.float32, args.gate_scale)
    dt_bias = randn((case.value_heads,), torch.float32, args.gate_scale)
    initial_state = randn(
        (case.state_pool, case.value_heads, case.v_dim, case.k_dim),
        state_dtype,
        args.state_scale,
    )
    out = torch.empty(
        (case.batch, 1, case.value_heads, case.v_dim),
        device="cuda",
        dtype=input_dtype,
    )

    if args.allow_duplicate_indices:
        ssm_state_indices = torch.randint(
            0, case.state_pool, (case.batch,), device="cuda", dtype=torch.int32
        )
    else:
        ssm_state_indices = torch.randperm(case.state_pool, device="cuda", dtype=torch.int64)[
            : case.batch
        ].to(torch.int32)
    if args.pad_slots > 0:
        ssm_state_indices[: min(args.pad_slots, case.batch)] = -1
    ssm_state_indices = ssm_state_indices.contiguous()

    return {
        "mixed_qkv": mixed_qkv,
        "a": a,
        "b": b,
        "A_log": A_log,
        "dt_bias": dt_bias,
        "scale": args.scale if args.scale is not None else case.k_dim**-0.5,
        "initial_state": initial_state,
        "out": out,
        "ssm_state_indices": ssm_state_indices,
        "input_dtype": input_dtype,
        "state_dtype": state_dtype,
    }


def clone_tensors_for_run(tensors: dict[str, Any]) -> dict[str, Any]:
    cloned = dict(tensors)
    cloned["initial_state"] = tensors["initial_state"].clone()
    cloned["out"] = torch.empty_like(tensors["out"])
    return cloned


def run_hip(args: argparse.Namespace, tensors: dict[str, Any]) -> tuple[torch.Tensor, torch.Tensor]:
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
        use_qk_l2norm_in_kernel=args.qk_l2norm,
    )


def run_triton(
    args: argparse.Namespace,
    tensors: dict[str, Any],
) -> tuple[torch.Tensor, torch.Tensor]:
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
        use_qk_l2norm_in_kernel=args.qk_l2norm,
    )


class VerifyFailedError(AssertionError):
    def __init__(self, message: str, stats: dict[str, Any]):
        super().__init__(message)
        self.stats = stats


def _assert_tensor_close(
    name: str,
    hip: torch.Tensor,
    tri: torch.Tensor,
    *,
    rtol: float,
    atol: float,
    equal_nan: bool,
    failures: list[str],
) -> None:
    try:
        torch.testing.assert_close(hip, tri, rtol=rtol, atol=atol, equal_nan=equal_nan)
    except AssertionError as exc:
        failures.append(f"{name}: {exc}")


def selected_state_rows(tensors: dict[str, Any]) -> torch.Tensor:
    rows = tensors["ssm_state_indices"].reshape(-1).to(torch.long)
    rows = rows[rows >= 0]
    return torch.unique(rows)


def verify(args: argparse.Namespace, tensors: dict[str, Any]) -> dict[str, Any]:
    hip_tensors = clone_tensors_for_run(tensors)
    triton_tensors = clone_tensors_for_run(tensors)
    hip_out, hip_final_state = run_hip(args, hip_tensors)
    triton_out, triton_final_state = run_triton(args, triton_tensors)
    torch.cuda.synchronize()

    rows = selected_state_rows(tensors)
    hip_state_rows = hip_final_state.index_select(0, rows)
    triton_state_rows = triton_final_state.index_select(0, rows)

    tol_kw = {"rtol": args.rtol, "atol": args.atol}
    stats: dict[str, Any] = {}
    stats.update(tensor_stats("out", hip_out, triton_out, **tol_kw))
    stats.update(tensor_stats("final_state", hip_state_rows, triton_state_rows, **tol_kw))

    failures: list[str] = []
    _assert_tensor_close(
        "out",
        hip_out.float(),
        triton_out.float(),
        rtol=args.rtol,
        atol=args.atol,
        equal_nan=args.equal_nan,
        failures=failures,
    )
    _assert_tensor_close(
        "final_state",
        hip_state_rows.float(),
        triton_state_rows.float(),
        rtol=args.rtol,
        atol=args.atol,
        equal_nan=args.equal_nan,
        failures=failures,
    )
    stats["verify_pass"] = len(failures) == 0
    if failures:
        stats["verify_errors"] = failures
        raise VerifyFailedError(" | ".join(failures), stats)
    return stats


def bench_case(args: argparse.Namespace, case: PackedDecodeCase) -> dict[str, Any]:
    tensors = make_inputs(args, case)
    correctness: dict[str, Any] | None = None
    if not args.no_verify:
        try:
            correctness = verify(args, tensors)
        except VerifyFailedError as exc:
            correctness = exc.stats

    torch.cuda.empty_cache()
    hip_bench_tensors = clone_tensors_for_run(tensors)
    triton_bench_tensors = clone_tensors_for_run(tensors)

    run_hip(args, hip_bench_tensors)
    run_triton(args, triton_bench_tensors)
    torch.cuda.synchronize()

    hip_ms = float(
        triton.testing.do_bench(
            lambda: run_hip(args, hip_bench_tensors),
            warmup=args.warmup,
            rep=args.rep,
        )
    )
    triton_ms = float(
        triton.testing.do_bench(
            lambda: run_triton(args, triton_bench_tensors),
            warmup=args.warmup,
            rep=args.rep,
        )
    )

    flops = estimate_packed_decode_flops(case)
    bytes_est = estimate_packed_decode_bytes(
        case, tensors["input_dtype"], tensors["state_dtype"]
    )
    result = {
        "case": asdict(case),
        "shape": {
            "mixed_qkv": list(tensors["mixed_qkv"].shape),
            "q": [case.batch, case.heads * case.k_dim],
            "k": [case.batch, case.heads * case.k_dim],
            "v": [case.batch, case.value_heads * case.v_dim],
            "a": [case.batch, case.value_heads],
            "b": [case.batch, case.value_heads],
            "initial_state": [case.state_pool, case.value_heads, case.v_dim, case.k_dim],
            "out": list(tensors["out"].shape),
            "dtype": args.dtype,
            "gate_dtype": "fp32",
            "state_dtype": args.state_dtype,
            "pad_slots": args.pad_slots,
            "duplicate_indices": args.allow_duplicate_indices,
            "qk_l2norm": args.qk_l2norm,
        },
        "bench": {
            "warmup": args.warmup,
            "rep": args.rep,
            "hip_impl": HIP_IMPL,
            "hip_ms": hip_ms,
            "triton_ms": triton_ms,
            "speedup_vs_triton": triton_ms / hip_ms,
            "flops_est": flops,
            "bytes_est": bytes_est,
            "hip_tflops": tflops(flops, hip_ms),
            "triton_tflops": tflops(flops, triton_ms),
            "hip_gbps": gbps(bytes_est, hip_ms),
            "triton_gbps": gbps(bytes_est, triton_ms),
        },
        "correctness": correctness,
    }

    print("=" * 100)
    print(
        f"{case.name} | "
        "HIP aiter_fused_recurrent_gated_delta_rule_packed_decode vs Triton | "
        f"B={case.batch} H={case.heads} HV={case.value_heads} "
        f"K={case.k_dim} V={case.v_dim} pool={case.state_pool} "
        f"dtype={args.dtype} state={args.state_dtype} l2norm={args.qk_l2norm} "
        f"hip_impl={HIP_IMPL}"
    )
    print(
        f"mixed_qkv={tuple(tensors['mixed_qkv'].shape)} "
        f"bytes_est={bytes_to_mb(bytes_est):.3f} MB"
    )
    print(
        f"HIP    : {hip_ms:.4f} ms, {hip_ms * 1000:.2f} us, "
        f"{tflops(flops, hip_ms):.3f} TF, {gbps(bytes_est, hip_ms):.2f} GB/s"
    )
    print(
        f"Triton : {triton_ms:.4f} ms, {triton_ms * 1000:.2f} us, "
        f"{tflops(flops, triton_ms):.3f} TF, {gbps(bytes_est, triton_ms):.2f} GB/s, "
        f"HIP speedup {triton_ms / hip_ms:.4f}x"
    )
    if correctness is not None:
        print(
            "Verify : "
            f"{'PASS' if correctness.get('verify_pass', False) else 'FAIL'} | "
            f"out_abs={correctness['out_max_abs_finite']:.4g} "
            f"out_rel={correctness['out_max_rel_finite']:.4g} "
            f"state_abs={correctness['final_state_max_abs_finite']:.4g} "
            f"state_rel={correctness['final_state_max_rel_finite']:.4g}"
        )
        if not correctness.get("verify_pass", True):
            for err in correctness.get("verify_errors", []):
                print(f"  - {err}")
            raise VerifyFailedError(
                " | ".join(correctness.get("verify_errors", [])), correctness
            )
    return result


def parse_case_names(value: str) -> list[str]:
    if value == "all":
        return list(DEFAULT_CASES)
    names = [name.strip() for name in value.split(",") if name.strip()]
    unknown = [name for name in names if name not in DEFAULT_CASES]
    if unknown:
        raise ValueError(f"unknown case(s): {unknown}; choices={list(DEFAULT_CASES)} or all")
    return names


def main() -> None:
    parser = argparse.ArgumentParser(
        "Benchmark HIP aiter_fused_recurrent_gated_delta_rule_packed_decode against Triton"
    )
    parser.add_argument("--cases", type=str, default="all", help="Comma list or all")
    parser.add_argument("--dtype", choices=("fp16", "bf16", "fp32"), default="bf16")
    parser.add_argument("--state-dtype", choices=("fp16", "bf16", "fp32"), default="bf16")
    parser.add_argument("--input-scale", type=float, default=0.2)
    parser.add_argument("--gate-scale", type=float, default=0.2)
    parser.add_argument("--state-scale", type=float, default=0.05)
    parser.add_argument("--scale", type=float, default=None)
    parser.add_argument("--qk-l2norm", dest="qk_l2norm", action="store_true")
    parser.add_argument("--no-qk-l2norm", dest="qk_l2norm", action="store_false")
    parser.set_defaults(qk_l2norm=False)
    parser.add_argument("--pad-slots", type=int, default=0)
    parser.add_argument("--allow-duplicate-indices", action="store_true", default=False)
    parser.add_argument("--warmup", type=int, default=25)
    parser.add_argument("--rep", type=int, default=100)
    parser.add_argument("--seed", type=int, default=0)
    parser.add_argument("--device-id", type=int, default=1)
    parser.add_argument("--no-verify", action="store_true")
    parser.add_argument("--rtol", type=float, default=5e-2)
    parser.add_argument("--atol", type=float, default=5e-2)
    parser.add_argument("--equal-nan", dest="equal_nan", action="store_true")
    parser.add_argument("--no-equal-nan", dest="equal_nan", action="store_false")
    parser.set_defaults(equal_nan=True)
    parser.add_argument("--out-json", type=str, default="")
    args = parser.parse_args()

    if not torch.cuda.is_available():
        raise RuntimeError("ROCm/HIP CUDA-compatible device is required")
    torch.cuda.set_device(args.device_id)

    selected = parse_case_names(args.cases)
    print("=" * 100)
    print(
        "HIP aiter_fused_recurrent_gated_delta_rule_packed_decode vs Triton | "
        f"cases={selected} dtype={args.dtype} state_dtype={args.state_dtype} "
        f"device_id={args.device_id} warmup={args.warmup} rep={args.rep} "
        f"verify={not args.no_verify} hip_impl={HIP_IMPL}"
    )

    results = [bench_case(args, DEFAULT_CASES[name]) for name in selected]
    print("=" * 100)

    if args.out_json:
        out_path = Path(args.out_json)
        out_path.parent.mkdir(parents=True, exist_ok=True)
        out_path.write_text(json.dumps(results, indent=2, sort_keys=True) + "\n", encoding="utf-8")


if __name__ == "__main__":
    main()
