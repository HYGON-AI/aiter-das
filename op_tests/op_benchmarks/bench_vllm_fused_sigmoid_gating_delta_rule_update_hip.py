# SPDX-License-Identifier: MIT
"""Benchmark HIP vllm_fused_sigmoid_gating_delta_rule_update against Triton.

Run from the repository root:

    PYTHONPATH=. python op_tests/op_benchmarks/bench_vllm_fused_sigmoid_gating_delta_rule_update_hip.py

The default shape mirrors the Triton fused-sigmoid-gating Qwen/spec case:
q/k [1, 8, 4, 128], v [1, 8, 16, 128], state [1639, 16, 128, 128].
Use ``--no-verify`` for profiling runs where only timing is needed.
"""

from __future__ import annotations

import argparse
import json
import os
from pathlib import Path
from typing import Any

import torch
import triton

import aiter
from aiter.ops.triton.fla.fused_sigmoid_gating import (
    fused_sigmoid_gating_delta_rule_update as triton_fused_sigmoid_gating_delta_rule_update,
)


def parse_dtype(name: str) -> torch.dtype:
    if name == "fp16":
        return torch.float16
    if name == "bf16":
        return torch.bfloat16
    if name == "fp32":
        return torch.float32
    raise ValueError(f"unsupported dtype={name}")


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


def estimate_bytes_from_inputs(tensors: dict[str, Any], args: argparse.Namespace) -> int:
    num_tokens = args.num_reqs * args.seq_len
    qkv_elem = tensors["q"].element_size()
    ab_elem = tensors["a"].element_size()
    state_elem = tensors["initial_state"].element_size()
    out_elem = tensors["v"].element_size()

    qkv_elems = num_tokens * (
        2 * args.num_k_heads * args.head_k_dim + args.num_v_heads * args.head_v_dim
    )
    bytes_qkv = qkv_elems * qkv_elem
    bytes_ab = 2 * num_tokens * args.num_v_heads * ab_elem
    bytes_gates = 2 * args.num_v_heads * ab_elem

    state_elems_per_slot = args.num_v_heads * args.head_v_dim * args.head_k_dim
    num_seqs = int(tensors["cu_seqlens"].numel() - 1)
    state_write_slots = int(tensors["ssm_state_indices"].numel())
    bytes_state_rw = (num_seqs + state_write_slots) * state_elems_per_slot * state_elem

    bytes_out = num_tokens * args.num_v_heads * args.head_v_dim * out_elem
    return bytes_qkv + bytes_ab + bytes_gates + bytes_state_rw + bytes_out


def gbps(num_bytes: int, ms: float) -> float:
    return num_bytes / (ms * 1e-3) / 1e9


def bytes_to_mb(num_bytes: int) -> float:
    return num_bytes / 1e6


def randn(shape: tuple[int, ...], dtype: torch.dtype, scale: float) -> torch.Tensor:
    return (torch.randn(shape, device="cuda", dtype=dtype) * scale).contiguous()


def make_inputs(args: argparse.Namespace) -> dict[str, Any]:
    if args.head_k_dim != 128:
        raise ValueError("HIP kernel currently supports only --head-k-dim 128")
    if args.head_v_dim not in (128, 256):
        raise ValueError("HIP kernel currently supports only --head-v-dim 128 or 256")
    if args.num_v_heads % args.num_k_heads != 0:
        raise ValueError("--num-v-heads must be divisible by --num-k-heads")
    if args.spec_tokens > 0 and args.seq_len != args.spec_tokens + 1:
        raise ValueError("--seq-len must equal --spec-tokens + 1 in speculative mode")

    torch.manual_seed(args.seed)
    dtype = parse_dtype(args.dtype)

    num_tokens = args.num_reqs * args.seq_len
    state_rows = max(args.state_pool, num_tokens * 2)
    ab_tokens = max(args.ab_tokens, num_tokens)
    mixed_qkv_dim = (
        2 * args.num_k_heads * args.head_k_dim
        + args.num_v_heads * args.head_v_dim
    )
    mixed_qkv = randn((num_tokens, mixed_qkv_dim), dtype, args.input_scale)
    q, k, v = torch.split(
        mixed_qkv,
        [
            args.num_k_heads * args.head_k_dim,
            args.num_k_heads * args.head_k_dim,
            args.num_v_heads * args.head_v_dim,
        ],
        dim=-1,
    )
    q = q.view(1, num_tokens, args.num_k_heads, args.head_k_dim).contiguous()
    k = k.view(1, num_tokens, args.num_k_heads, args.head_k_dim).contiguous()
    v = v.view(1, num_tokens, args.num_v_heads, args.head_v_dim).contiguous()

    A_log = randn((args.num_v_heads,), torch.float32, args.input_scale)
    a = randn((ab_tokens, args.num_v_heads), dtype, args.input_scale)
    b = randn((ab_tokens, args.num_v_heads), dtype, args.input_scale)
    dt_bias = randn((args.num_v_heads,), dtype, args.input_scale)

    initial_state = randn(
        (state_rows, args.num_v_heads, args.head_v_dim, args.head_k_dim),
        torch.float32,
        args.state_scale,
    )
    cu_seqlens = torch.arange(
        0,
        num_tokens + 1,
        args.seq_len,
        device="cuda",
        dtype=torch.int32,
    ).contiguous()

    if args.spec_tokens > 0:
        ssm_state_indices = torch.randperm(state_rows, device="cuda", dtype=torch.int64)[
            :num_tokens
        ].to(torch.int32)
        ssm_state_indices = ssm_state_indices.view(args.num_reqs, args.seq_len).contiguous()
        num_accepted_tokens = torch.randint(
            1,
            args.seq_len,
            (args.num_reqs,),
            device="cuda",
            dtype=torch.int32,
        ).contiguous()
    else:
        ssm_state_indices = torch.randperm(state_rows, device="cuda", dtype=torch.int64)[
            : args.num_reqs
        ].to(torch.int32).contiguous()
        num_accepted_tokens = None

    return {
        "A_log": A_log,
        "a": a,
        "b": b,
        "dt_bias": dt_bias,
        "q": q,
        "k": k,
        "v": v,
        "initial_state": initial_state,
        "cu_seqlens": cu_seqlens,
        "ssm_state_indices": ssm_state_indices,
        "num_accepted_tokens": num_accepted_tokens,
        "state_rows": state_rows,
        "ab_tokens": ab_tokens,
    }


def clone_tensors_for_run(tensors: dict[str, Any]) -> dict[str, Any]:
    cloned = dict(tensors)
    cloned["initial_state"] = tensors["initial_state"].clone()
    return cloned


def run_hip(args: argparse.Namespace, tensors: dict[str, Any]) -> tuple[torch.Tensor, torch.Tensor]:
    return aiter.vllm_fused_sigmoid_gating_delta_rule_update(
        A_log=tensors["A_log"],
        a=tensors["a"],
        b=tensors["b"],
        dt_bias=tensors["dt_bias"],
        q=tensors["q"],
        k=tensors["k"],
        v=tensors["v"],
        beta=args.beta,
        threshold=args.threshold,
        scale=args.scale,
        initial_state=tensors["initial_state"],
        inplace_final_state=True,
        cu_seqlens=tensors["cu_seqlens"],
        ssm_state_indices=tensors["ssm_state_indices"],
        num_accepted_tokens=tensors["num_accepted_tokens"],
        use_qk_l2norm_in_kernel=args.qk_l2norm,
        is_kda=False,
    )


def run_triton(args: argparse.Namespace, tensors: dict[str, Any]) -> tuple[torch.Tensor, torch.Tensor]:
    return triton_fused_sigmoid_gating_delta_rule_update(
        A_log=tensors["A_log"],
        a=tensors["a"],
        b=tensors["b"],
        dt_bias=tensors["dt_bias"],
        q=tensors["q"],
        k=tensors["k"],
        v=tensors["v"],
        beta=args.beta,
        threshold=args.threshold,
        scale=args.scale,
        initial_state=tensors["initial_state"],
        inplace_final_state=True,
        cu_seqlens=tensors["cu_seqlens"],
        ssm_state_indices=tensors["ssm_state_indices"],
        num_accepted_tokens=tensors["num_accepted_tokens"],
        use_qk_l2norm_in_kernel=args.qk_l2norm,
        is_kda=False,
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


def main() -> None:
    parser = argparse.ArgumentParser(
        "Benchmark HIP vllm_fused_sigmoid_gating_delta_rule_update against Triton"
    )
    parser.add_argument("--num-reqs", type=int, default=2)
    parser.add_argument("--seq-len", type=int, default=4)
    parser.add_argument("--num-k-heads", type=int, default=4)
    parser.add_argument("--num-v-heads", type=int, default=16)
    parser.add_argument("--head-k-dim", type=int, default=128)
    parser.add_argument("--head-v-dim", type=int, default=128)
    parser.add_argument("--state-pool", type=int, default=1639)
    parser.add_argument("--spec-tokens", type=int, default=3, help="0 means non-spec")
    parser.add_argument("--ab-tokens", type=int, default=13628)
    parser.add_argument("--dtype", choices=("fp16", "bf16", "fp32"), default="bf16")
    parser.add_argument("--input-scale", type=float, default=0.2)
    parser.add_argument("--state-scale", type=float, default=0.02)
    parser.add_argument("--beta", type=float, default=1.0)
    parser.add_argument("--threshold", type=float, default=20.0)
    parser.add_argument("--scale", type=float, default=None)
    parser.add_argument("--qk-l2norm", action=argparse.BooleanOptionalAction, default=True)
    parser.add_argument("--kernel-variant", choices=("4", "8", "16"), default="")
    parser.add_argument("--warmup", type=int, default=5)
    parser.add_argument("--rep", type=int, default=20)
    parser.add_argument("--seed", type=int, default=0)
    parser.add_argument("--skip-triton", action="store_true")
    parser.add_argument("--no-verify", action="store_true")
    parser.add_argument("--rtol", type=float, default=5e-2)
    parser.add_argument("--atol", type=float, default=5e-2)
    parser.add_argument("--equal-nan", action=argparse.BooleanOptionalAction, default=True)
    parser.add_argument("--out-json", type=str, default="")
    args = parser.parse_args()

    if not torch.cuda.is_available():
        raise RuntimeError("ROCm/HIP CUDA-compatible device is required")
    if args.kernel_variant:
        os.environ["AITER_FSG_KERNEL_VARIANT"] = args.kernel_variant

    tensors = make_inputs(args)
    correctness: dict[str, Any] | None = None
    if not args.no_verify and not args.skip_triton:
        try:
            correctness = verify(args, tensors)
        except VerifyFailedError as exc:
            correctness = exc.stats

    hip_bench_tensors = clone_tensors_for_run(tensors)
    triton_bench_tensors = clone_tensors_for_run(tensors)

    run_hip(args, hip_bench_tensors)
    if not args.skip_triton:
        run_triton(args, triton_bench_tensors)
    torch.cuda.synchronize()

    hip_ms = float(
        triton.testing.do_bench(
            lambda: run_hip(args, hip_bench_tensors),
            warmup=args.warmup,
            rep=args.rep,
        )
    )
    triton_ms = None
    if not args.skip_triton:
        triton_ms = float(
            triton.testing.do_bench(
                lambda: run_triton(args, triton_bench_tensors),
                warmup=args.warmup,
                rep=args.rep,
            )
        )

    bytes_est = estimate_bytes_from_inputs(tensors, args)
    result = {
        "shape": {
            "num_reqs": args.num_reqs,
            "seq_len": args.seq_len,
            "num_k_heads": args.num_k_heads,
            "num_v_heads": args.num_v_heads,
            "head_k_dim": args.head_k_dim,
            "head_v_dim": args.head_v_dim,
            "state_rows": tensors["state_rows"],
            "ab_tokens": tensors["ab_tokens"],
            "spec_tokens": args.spec_tokens,
            "dtype": args.dtype,
            "cu_seqlens": tensors["cu_seqlens"].tolist(),
            "ssm_state_indices_shape": list(tensors["ssm_state_indices"].shape),
            "num_accepted_tokens": (
                tensors["num_accepted_tokens"].tolist()
                if tensors["num_accepted_tokens"] is not None
                else None
            ),
        },
        "bench": {
            "warmup": args.warmup,
            "rep": args.rep,
            "hip_ms": hip_ms,
            "triton_ms": triton_ms,
            "speedup_vs_triton": triton_ms / hip_ms if triton_ms is not None else None,
            "bytes_est": bytes_est,
            "hip_gbps": gbps(bytes_est, hip_ms),
            "triton_gbps": gbps(bytes_est, triton_ms) if triton_ms is not None else None,
        },
        "correctness": correctness,
    }

    print("=" * 100)
    print(
        "HIP vllm_fused_sigmoid_gating_delta_rule_update vs Triton | "
        f"reqs={args.num_reqs} seq={args.seq_len} spec={args.spec_tokens} "
        f"H={args.num_k_heads} HV={args.num_v_heads} K={args.head_k_dim} "
        f"V={args.head_v_dim} dtype={args.dtype} "
        f"variant={args.kernel_variant or 'default'}"
    )
    print(
        f"cu_seqlens={tensors['cu_seqlens'].tolist()} "
        f"ssm_state_indices.shape={tuple(tensors['ssm_state_indices'].shape)} "
        f"bytes_est={bytes_to_mb(bytes_est):.3f} MB"
    )
    print("-" * 100)
    print(f"HIP    : {hip_ms:.4f} ms, {hip_ms * 1000:.2f} us, {gbps(bytes_est, hip_ms):.2f} GB/s")
    if triton_ms is not None:
        print(
            f"Triton : {triton_ms:.4f} ms, {triton_ms * 1000:.2f} us, "
            f"{gbps(bytes_est, triton_ms):.2f} GB/s, HIP speedup {triton_ms / hip_ms:.4f}x"
        )
    if correctness is not None:
        print(f"Verify : {correctness}")
        print(
            "Rel err: "
            f"out={correctness['out_max_rel_finite']:.4g} "
            f"state={correctness['final_state_max_rel_finite']:.4g} "
            f"(rtol={args.rtol:g}, atol={args.atol:g}) | "
            f"tol {'PASS' if correctness.get('verify_pass', False) else 'FAIL'}"
        )
        if not correctness.get("verify_pass", True):
            for err in correctness.get("verify_errors", []):
                print(f"  - {err}")
            raise VerifyFailedError(
                " | ".join(correctness.get("verify_errors", [])),
                correctness,
            )
    print("=" * 100)

    if args.out_json:
        out_path = Path(args.out_json)
        out_path.parent.mkdir(parents=True, exist_ok=True)
        out_path.write_text(json.dumps(result, indent=2, sort_keys=True) + "\n", encoding="utf-8")


if __name__ == "__main__":
    main()
