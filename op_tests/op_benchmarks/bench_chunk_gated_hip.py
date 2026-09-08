# SPDX-License-Identifier: MIT
"""Benchmark HIP chunk_gated_delta_rule_fwd against Triton vLLM/SGLang.

Run from the repository root:

    export PYTHONPATH=/workspace/aiter_fla_dev/aiter/
    python op_tests/op_benchmarks/bench_chunk_gated_hip.py \
        --batch 1 --seqlen 9008 --heads 2 --grouped-heads 2 \
        --k-dim 128 --v-dim 128 --warmup 5 --rep 20 --frontend sglang

Use ``--frontend vllm`` or ``--frontend sglang`` to select the matching Triton
reference.  Use ``--no-verify`` for profiling runs where only timing is needed.
"""

from __future__ import annotations

import argparse
import json
import os
import statistics
from pathlib import Path
from typing import Any

import torch
import triton

import aiter
from aiter.ops.triton.fla.vllm.chunk_delta_h import (
    chunk_gated_delta_rule_fwd_h as triton_chunk_gated_delta_rule_fwd_h,
    prepare_chunk_indices,
)
from aiter.ops.triton.fla.sglang.chunk_delta_h import (
    chunk_gated_delta_rule_fwd_h as triton_chunk_gated_delta_rule_fwd_h_sglang,
)


def tensor_stats(
    prefix: str,
    hip: torch.Tensor,
    tri: torch.Tensor,
    *,
    rtol: float | None = None,
    atol: float | None = None,
) -> dict[str, float | int | bool]:
    """Absolute / relative error vs Triton (reference) on finite elements."""
    finite = torch.isfinite(hip) & torch.isfinite(tri)
    if finite.any():
        hip_f = hip[finite].float()
        tri_f = tri[finite].float()
        abs_diff = (hip_f - tri_f).abs()
        max_abs = float(abs_diff.max().item())
        if rtol is not None and atol is not None:
            # Same scale as torch.testing.assert_close: atol + rtol * |ref|.
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
        # Mirror torch.testing.assert_close: |a-b| <= atol + rtol * |b|.
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


def make_varlen(args: argparse.Namespace) -> tuple[torch.Tensor | None, torch.Tensor | None, int]:
    if not args.varlen:
        return None, None, args.batch
    if args.batch != 1:
        raise ValueError("varlen mode expects --batch 1 with flattened tokens")
    if args.varlen_splits:
        points = [int(x) for x in args.varlen_splits.split(",") if x.strip()]
        points = [x for x in points if 0 < x < args.seqlen]
        splits = [0] + sorted(points)
        if splits[-1] != args.seqlen:
            splits.append(args.seqlen)
    else:
        splits = [0, args.seqlen // 4, args.seqlen // 2, (3 * args.seqlen) // 4, args.seqlen]
    cu_dtype = torch.int32 if args.cu_seqlens_dtype == "int32" else torch.long
    indices_dtype = torch.int32 if args.chunk_indices_dtype == "int32" else torch.long
    cu_seqlens = torch.tensor(splits, device=torch.device("cuda"), dtype=cu_dtype)
    chunk_indices = prepare_chunk_indices(cu_seqlens, args.chunk_size).to(indices_dtype)
    return cu_seqlens, chunk_indices, len(splits) - 1


def make_state_indices(args: argparse.Namespace, n_seq: int) -> tuple[int, torch.Tensor | None]:
    device = torch.device("cuda")
    requested_rows = args.state_rows if args.state_rows > 0 else None
    if args.state_index_mode == "none":
        return requested_rows or n_seq, None
    if args.state_index_mode == "identity":
        state_rows = requested_rows or n_seq
        if state_rows < n_seq:
            raise ValueError("--state-rows must be >= number of sequences")
        return state_rows, torch.arange(n_seq, device=device, dtype=torch.int32)
    if args.state_index_mode == "reverse":
        state_rows = requested_rows or n_seq
        if state_rows < n_seq:
            raise ValueError("--state-rows must be >= number of sequences")
        return state_rows, torch.arange(n_seq - 1, -1, -1, device=device, dtype=torch.int32)
    if args.state_index_mode == "random":
        state_rows = requested_rows or max(n_seq * 2, n_seq + 8)
        if state_rows < n_seq:
            raise ValueError("--state-rows must be >= number of sequences")
        return state_rows, torch.randperm(state_rows, device=device, dtype=torch.int64)[:n_seq].to(torch.int32)
    raise ValueError(f"unsupported state_index_mode={args.state_index_mode}")


def make_inputs(args: argparse.Namespace) -> dict[str, Any]:
    torch.manual_seed(args.seed)
    device = torch.device("cuda")
    dtype = torch.bfloat16 if args.dtype == "bf16" else torch.float16

    k = torch.randn(
        (args.batch, args.seqlen, args.grouped_heads, args.k_dim),
        device=device,
        dtype=dtype,
    ) * args.input_scale
    w = torch.randn(
        (args.batch, args.seqlen, args.heads, args.k_dim),
        device=device,
        dtype=dtype,
    ) * args.input_scale
    u = torch.randn(
        (args.batch, args.seqlen, args.heads, args.v_dim),
        device=device,
        dtype=dtype,
    ) * args.input_scale
    g = torch.randn(
        (args.batch, args.seqlen, args.heads),
        device=device,
        dtype=torch.float32,
    ) * args.g_scale

    cu_seqlens, chunk_indices, n_seq = make_varlen(args)
    state_rows, initial_state_indices = make_state_indices(args, n_seq)
    state_dtype = torch.bfloat16 if args.state_dtype == "bf16" else torch.float32
    initial_state = torch.randn(
        (state_rows, args.heads, args.v_dim, args.k_dim),
        device=device,
        dtype=state_dtype,
    ) * args.state_scale

    chunk_offsets = None
    if args.cache_chunk_offsets and cu_seqlens is not None:
        chunk_counts = (
            (cu_seqlens[1:].to(torch.long) - cu_seqlens[:-1].to(torch.long))
            + args.chunk_size - 1
        ) // args.chunk_size
        chunk_offsets = torch.zeros_like(chunk_counts, dtype=torch.long)
        if chunk_offsets.numel() > 1:
            chunk_offsets[1:] = torch.cumsum(chunk_counts, dim=0)[:-1]

    return {
        "k": k,
        "w": w,
        "u": u,
        "g": g,
        "initial_state": initial_state,
        "initial_state_indices": initial_state_indices,
        "cu_seqlens": cu_seqlens,
        "chunk_indices": chunk_indices,
        "chunk_offsets": chunk_offsets,
        "n_seq": n_seq,
        "state_rows": state_rows,
    }


def clone_tensors_for_run(tensors: dict[str, Any]) -> dict[str, Any]:
    cloned = dict(tensors)
    cloned["initial_state"] = tensors["initial_state"].clone()
    return cloned


def run_hip(args: argparse.Namespace, tensors: dict[str, Any]):
    fn = (
        aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64
        if args.frontend == "sglang"
        else aiter.chunk_gated_delta_rule_fwd_vllm_hip_blockdim64
    )
    return fn(
        tensors["k"],
        tensors["w"],
        tensors["u"],
        tensors["g"],
        None,
        tensors["initial_state"],
        tensors["initial_state_indices"],
        True,
        args.chunk_size,
        True,
        tensors["cu_seqlens"],
        tensors["chunk_indices"],
        tensors["chunk_offsets"],
        False,
        True,
    )


def run_triton(args: argparse.Namespace, tensors: dict[str, Any]):
    fn = (
        triton_chunk_gated_delta_rule_fwd_h_sglang
        if args.frontend == "sglang"
        else triton_chunk_gated_delta_rule_fwd_h
    )
    return fn(
        k=tensors["k"],
        w=tensors["w"],
        u=tensors["u"],
        g=tensors["g"],
        gk=None,
        initial_state=tensors["initial_state"],
        initial_state_indices=tensors["initial_state_indices"],
        output_final_state=True,
        chunk_size=args.chunk_size,
        save_new_value=True,
        cu_seqlens=tensors["cu_seqlens"],
        chunk_indices=tensors["chunk_indices"],
        use_exp2=False,
        transpose_state_layout=True,
    )


def event_bench(fn, *, warmup: int, rep: int) -> dict[str, float]:
    """Measure one HIP callable with explicit device events per iteration."""
    for _ in range(warmup):
        fn()
    torch.cuda.synchronize()
    samples_ms: list[float] = []
    for _ in range(rep):
        start = torch.cuda.Event(enable_timing=True)
        end = torch.cuda.Event(enable_timing=True)
        start.record()
        fn()
        end.record()
        end.synchronize()
        samples_ms.append(float(start.elapsed_time(end)))
    return {
        "median_ms": float(statistics.median(samples_ms)),
        "mean_ms": float(statistics.mean(samples_ms)),
        "min_ms": float(min(samples_ms)),
        "max_ms": float(max(samples_ms)),
    }


class VerifyFailedError(AssertionError):
    """Raised when HIP vs Triton comparison fails; carries precomputed stats."""

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


def verify(args: argparse.Namespace, tensors: dict[str, Any]) -> dict[str, float | int | bool]:
    hip_tensors = clone_tensors_for_run(tensors)
    triton_tensors = clone_tensors_for_run(tensors)
    hip_out = run_hip(args, hip_tensors)
    triton_out = run_triton(args, triton_tensors)
    torch.cuda.synchronize()

    h_hip, v_hip = hip_out[0], hip_out[1]
    h_tri, v_tri = triton_out[0], triton_out[1]
    if args.frontend == "sglang":
        rows = hip_tensors["initial_state_indices"].to(torch.long)
        final_hip_rows = hip_tensors["initial_state"].index_select(0, rows)
        final_tri_rows = triton_tensors["initial_state"].index_select(0, rows)
    else:
        final_hip, final_tri = hip_out[2], triton_out[2]
        if tensors["initial_state_indices"] is None:
            rows = torch.arange(tensors["n_seq"], device=final_hip.device)
        else:
            rows = tensors["initial_state_indices"].to(torch.long)
        final_hip_rows = final_hip.index_select(0, rows)
        final_tri_rows = final_tri.index_select(0, rows)

    tol_kw = {"rtol": args.rtol, "atol": args.atol}
    stats: dict[str, float | int | bool] = {}
    stats.update(tensor_stats("h", h_hip, h_tri, **tol_kw))
    stats.update(tensor_stats("v_new", v_hip, v_tri, **tol_kw))
    stats.update(tensor_stats("final_state", final_hip_rows, final_tri_rows, **tol_kw))

    failures: list[str] = []
    _assert_tensor_close(
        "h", h_hip, h_tri, rtol=args.rtol, atol=args.atol,
        equal_nan=args.equal_nan, failures=failures,
    )
    _assert_tensor_close(
        "v_new", v_hip, v_tri, rtol=args.rtol, atol=args.atol,
        equal_nan=args.equal_nan, failures=failures,
    )
    _assert_tensor_close(
        "final_state", final_hip_rows, final_tri_rows,
        rtol=args.rtol, atol=args.atol, equal_nan=args.equal_nan, failures=failures,
    )
    stats["verify_pass"] = len(failures) == 0
    if failures:
        stats["verify_errors"] = failures
        raise VerifyFailedError(" | ".join(failures), stats)
    return stats


def main() -> None:
    parser = argparse.ArgumentParser("Benchmark HIP chunk_gated_delta_rule_fwd against Triton")
    parser.add_argument("--frontend", choices=("vllm", "sglang"), default="vllm")
    parser.add_argument("--batch", type=int, default=1)
    parser.add_argument("--seqlen", type=int, default=9008)
    parser.add_argument("--heads", type=int, default=2)
    parser.add_argument("--grouped-heads", type=int, default=2)
    parser.add_argument("--k-dim", type=int, default=128)
    parser.add_argument("--v-dim", type=int, default=128)
    parser.add_argument("--chunk-size", type=int, default=64)
    parser.add_argument("--dtype", choices=("fp16", "bf16"), default="fp16")
    parser.add_argument(
        "--state-dtype", choices=("fp32", "bf16"), default="fp32"
    )
    parser.add_argument(
        "--state-rows", type=int, default=0,
        help="Persistent state-pool rows; 0 chooses the benchmark default",
    )
    parser.add_argument("--warmup", type=int, default=5)
    parser.add_argument("--rep", type=int, default=20)
    parser.add_argument("--seed", type=int, default=42)
    parser.add_argument("--input-scale", type=float, default=0.01)
    parser.add_argument("--g-scale", type=float, default=0.01)
    parser.add_argument("--state-scale", type=float, default=0.0)
    parser.add_argument(
        "--state-index-mode",
        choices=("none", "identity", "reverse", "random"),
        default="identity",
    )
    parser.add_argument("--varlen", action="store_true")
    parser.add_argument(
        "--cache-chunk-offsets", action="store_true",
        help="Precompute int64 chunk_offsets outside the timed HIP call",
    )
    parser.add_argument("--varlen-splits", type=str, default="")
    parser.add_argument(
        "--cu-seqlens-dtype",
        choices=("int32", "int64"),
        default="int64",
        help="Element dtype for cu_seqlens in --varlen mode",
    )
    parser.add_argument(
        "--chunk-indices-dtype",
        choices=("int32", "int64"),
        default="int64",
        help="Element dtype for chunk_indices in --varlen mode (may differ from cu_seqlens)",
    )
    parser.add_argument("--skip-triton", action="store_true")
    parser.add_argument("--no-verify", action="store_true")
    parser.add_argument("--rtol", type=float, default=5e-2)
    parser.add_argument("--atol", type=float, default=5e-2)
    parser.add_argument("--equal-nan", action=argparse.BooleanOptionalAction, default=True)
    parser.add_argument("--out-json", type=str, default="")
    parser.add_argument(
        "--force-bv", choices=("auto", "16", "32", "64"), default="auto",
        help="Set the development AITER_FLA_FORCE_BV selector",
    )
    args = parser.parse_args()

    os.environ["AITER_FLA_FORCE_BV"] = args.force_bv

    if not torch.cuda.is_available():
        raise RuntimeError("ROCm/HIP CUDA-compatible device is required")
    if args.k_dim != 128 or args.v_dim != 128:
        raise ValueError("HIP chunk_gated kernel currently supports only K=128 and V=128")
    if args.frontend == "sglang" and args.state_index_mode == "none":
        raise ValueError("SGLang in-place state mode requires --state-index-mode identity/reverse/random")

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
            lambda: run_hip(args, hip_bench_tensors), warmup=args.warmup, rep=args.rep
        )
    )
    hip_event = event_bench(
        lambda: run_hip(args, hip_bench_tensors),
        warmup=args.warmup,
        rep=args.rep,
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

    result = {
        "shape": {
            "frontend": args.frontend,
            "batch": args.batch,
            "seqlen": args.seqlen,
            "heads": args.heads,
            "grouped_heads": args.grouped_heads,
            "k_dim": args.k_dim,
            "v_dim": args.v_dim,
            "chunk_size": args.chunk_size,
            "dtype": args.dtype,
            "state_dtype": args.state_dtype,
            "varlen": args.varlen,
            "cu_seqlens": tensors["cu_seqlens"].tolist() if tensors["cu_seqlens"] is not None else None,
            "state_index_mode": args.state_index_mode,
            "state_rows": tensors["state_rows"],
            "cache_chunk_offsets": args.cache_chunk_offsets,
            "force_bv": args.force_bv,
        },
        "bench": {
            "warmup": args.warmup,
            "rep": args.rep,
            "hip_ms": hip_ms,
            "hip_event": hip_event,
            "triton_ms": triton_ms,
            "speedup_vs_triton": triton_ms / hip_ms if triton_ms is not None else None,
        },
        "correctness": correctness,
    }

    print("=" * 100)
    print(
        f"HIP chunk_gated_delta_rule_fwd ({args.frontend}) vs Triton | "
        f"B={args.batch} T={args.seqlen} H={args.heads} Hg={args.grouped_heads} "
        f"K={args.k_dim} V={args.v_dim} BT={args.chunk_size} dtype={args.dtype}"
    )
    if tensors["cu_seqlens"] is not None:
        print(
            f"cu_seqlens={tensors['cu_seqlens'].tolist()} "
            f"dtype={tensors['cu_seqlens'].dtype} "
            f"chunk_indices.dtype={tensors['chunk_indices'].dtype}"
        )
    print("-" * 100)
    print(f"HIP    : {hip_ms:.4f} ms")
    print(
        "HIP event: "
        f"median={hip_event['median_ms']:.4f} ms, "
        f"mean={hip_event['mean_ms']:.4f} ms, "
        f"min={hip_event['min_ms']:.4f} ms, max={hip_event['max_ms']:.4f} ms"
    )
    if triton_ms is not None:
        print(f"Triton : {triton_ms:.4f} ms, HIP speedup {triton_ms / hip_ms:.4f}x")
    if correctness is not None:
        print(f"Verify : {correctness}")
        print(
            "Rel err: "
            f"h={correctness['h_max_rel_finite']:.4g} "
            f"v_new={correctness['v_new_max_rel_finite']:.4g} "
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
