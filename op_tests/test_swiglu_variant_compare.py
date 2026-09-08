# SPDX-License-Identifier: Apache-2.0

import argparse
import sys
import time
from pathlib import Path

import torch
import torch.nn.functional as F

# Ensure repository root is importable.
ROOT = Path(__file__).resolve().parents[3]
sys.path.insert(0, str(ROOT))

from aiter import swiglu_variant
from aiter.ops.triton import moe_activation

# (mode, dtype, m, d, seed, alpha, limit, rows_per_block, vec_size)
DEFAULT_CASES: list[tuple[int, str, int, int, int, float, float, int, int]] = [
    (0, "bf16", 1, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 2, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 4, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 8, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 16, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 32, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 64, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 128, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 256, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 512, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 1024, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 2048, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 4096, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 8192, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 16384, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 32768, 2048, 1, 1.702, 7.0, 1, 2),
    (0, "bf16", 65536, 2048, 1, 1.702, 7.0, 1, 2),
]


def parse_dtype(dtype_str: str) -> torch.dtype:
    if dtype_str == "fp16":
        return torch.float16
    if dtype_str == "bf16":
        return torch.bfloat16
    raise ValueError(f"Unsupported dtype: {dtype_str}")


def torch_swiglu_variant(input: torch.Tensor, mode: int, alpha: float, limit: float) -> torch.Tensor:
    """Reference matching C/Triton: promote to float32, clamp, then activate."""
    D = input.shape[-1] // 2
    gate, up = input.split([D, D], dim=-1)
    gate_p = gate.float().clamp(max=limit)
    up_p = up.float().clamp(min=-limit, max=limit)

    if mode == 0:
        return (gate_p * torch.sigmoid(alpha * gate_p) * (up_p + 1.0)).to(input.dtype)
    elif mode == 1:
        return (gate_p * torch.sigmoid(gate_p) * up_p).to(input.dtype)
    elif mode == 2:
        silu_clamp = F.silu(gate.float()).clamp(max=limit)
        return (silu_clamp * up_p).to(input.dtype)
    else:
        raise ValueError(f"Unsupported mode: {mode}")


def get_close_tol(dtype: torch.dtype) -> tuple[float, float]:
    if dtype == torch.bfloat16:
        # bf16 ULP can reach ~0.0625; allow one ULP plus exp rounding slack.
        return 2e-2, 2e-2
    return 1e-2, 1e-2


def run_c_swiglu_variant(
    out: torch.Tensor,
    inp: torch.Tensor,
    mode: int,
    alpha: float,
    limit: float,
    rows_per_block: int = 1,
    vec_size: int = 2,
):
    swiglu_variant(out, inp, alpha, limit, mode, rows_per_block, vec_size)


def run_triton_swiglu_variant(
    out: torch.Tensor,
    inp: torch.Tensor,
    mode: int,
    alpha: float,
    limit: float,
):
    if mode == 0:
        moe_activation.triton_swiglu_gpt_oss_sigmoid_alpha(out, inp, alpha, limit)
    elif mode == 1:
        moe_activation.triton_swiglu_silu_clamp_mul(out, inp, limit)
    elif mode == 2:
        moe_activation.triton_swiglu_step_and_mul(out, inp, limit)
    else:
        raise ValueError(f"Unsupported mode: {mode}")


def benchmark_us(fn, *args, num_warmup: int = 5, num_iters: int = 30) -> float:
    for _ in range(num_warmup):
        fn(*args)
    torch.cuda.synchronize()

    times = []
    for _ in range(num_iters):
        t0 = time.perf_counter()
        fn(*args)
        torch.cuda.synchronize()
        times.append((time.perf_counter() - t0) * 1e6)
    times.sort()
    return times[len(times) // 2]


def check_close(
    a: torch.Tensor,
    b: torch.Tensor,
    rtol: float = 1e-2,
    atol: float = 1e-2,
    label: str = "",
) -> None:
    if not torch.allclose(a, b, rtol=rtol, atol=atol):
        diff = (a.to(torch.float32) - b.to(torch.float32)).abs()
        max_err = diff.max().item()
        prefix = f"{label}: " if label else ""
        raise AssertionError(
            f"{prefix}Tensors are not close: max_err={max_err:.6g}, "
            f"rtol={rtol}, atol={atol}"
        )


def format_tb_per_us(out_tensor: torch.Tensor, in_tensor: torch.Tensor, microseconds: float) -> float:
    bytes_moved = out_tensor.nbytes + in_tensor.nbytes
    return bytes_moved / microseconds / 1e6


def format_case(
    mode: int,
    dtype_str: str,
    m: int,
    d: int,
    alpha: float,
    limit: float,
    rows_per_block: int,
    vec_size: int,
) -> str:
    return (
        f"mode={mode} dtype={dtype_str} M={m} D={d} "
        f"alpha={alpha:g} limit={limit:g} rows={rows_per_block} vec={vec_size}"
    )


def run_correctness_case(
    *,
    mode: int,
    dtype: torch.dtype,
    m: int,
    d: int,
    seed: int,
    alpha: float,
    limit: float,
    rows_per_block: int,
    vec_size: int,
    device: torch.device,
) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor]:
    torch.manual_seed(seed)
    inp = torch.randn(m, d * 2, dtype=dtype, device=device)
    expected = torch_swiglu_variant(inp, mode, alpha, limit)

    out_c = torch.empty((m, d), dtype=dtype, device=device)
    out_triton = torch.empty((m, d), dtype=dtype, device=device)

    run_c_swiglu_variant(
        out_c,
        inp,
        mode,
        alpha,
        limit,
        rows_per_block,
        vec_size,
    )
    run_triton_swiglu_variant(out_triton, inp, mode, alpha, limit)

    rtol, atol = get_close_tol(dtype)
    check_close(out_c, expected, rtol=rtol, atol=atol, label="C vs ref")
    check_close(out_triton, expected, rtol=rtol, atol=atol, label="Triton vs ref")
    check_close(out_c, out_triton, rtol=rtol, atol=atol, label="C vs Triton")
    return inp, out_c, out_triton


def measure_perf(
    *,
    inp: torch.Tensor,
    out_c: torch.Tensor,
    out_triton: torch.Tensor,
    mode: int,
    alpha: float,
    limit: float,
    rows_per_block: int,
    vec_size: int,
    warmup: int,
    iters: int,
) -> dict[str, float]:
    c_us = benchmark_us(
        run_c_swiglu_variant,
        out_c,
        inp,
        mode,
        alpha,
        limit,
        rows_per_block,
        vec_size,
        num_warmup=warmup,
        num_iters=iters,
    )
    t_us = benchmark_us(
        run_triton_swiglu_variant,
        out_triton,
        inp,
        mode,
        alpha,
        limit,
        num_warmup=warmup,
        num_iters=iters,
    )
    return {
        "c_us": c_us,
        "triton_us": t_us,
        "ratio": c_us / t_us,
        "c_tbs": format_tb_per_us(out_c, inp, c_us),
        "triton_tbs": format_tb_per_us(out_triton, inp, t_us),
    }


def print_perf_result(label: str, perf: dict[str, float]) -> None:
    print(
        f"  Perf {label}: "
        f"C={perf['c_us']:.1f} us, Triton={perf['triton_us']:.1f} us, "
        f"ratio={perf['ratio']:.3f}, "
        f"C={perf['c_tbs']:.3f} TB/s, Triton={perf['triton_tbs']:.3f} TB/s"
    )


def run_perf_summary(
    *,
    inp: torch.Tensor,
    out_c: torch.Tensor,
    out_triton: torch.Tensor,
    mode: int,
    alpha: float,
    limit: float,
    rows_per_block: int,
    vec_size: int,
    warmup: int,
    iters: int,
    label: str = "",
) -> dict[str, float]:
    perf = measure_perf(
        inp=inp,
        out_c=out_c,
        out_triton=out_triton,
        mode=mode,
        alpha=alpha,
        limit=limit,
        rows_per_block=rows_per_block,
        vec_size=vec_size,
        warmup=warmup,
        iters=iters,
    )
    print("Performance summary:")
    print_perf_result(label or "result", perf)
    return perf


def run_suite(
    cases: list[tuple[int, str, int, int, int, float, float, int, int]],
    device: torch.device,
    *,
    warmup: int,
    iters: int,
    skip_perf: bool,
) -> None:
    print(f"Running {len(cases)} swiglu_variant correctness cases...")
    perf_rows: list[tuple[str, dict[str, float]]] = []

    for idx, (mode, dtype_str, m, d, seed, alpha, limit, rows_per_block, vec_size) in enumerate(cases):
        dtype = parse_dtype(dtype_str)
        case_label = format_case(mode, dtype_str, m, d, alpha, limit, rows_per_block, vec_size)
        inp, out_c, out_triton = run_correctness_case(
            mode=mode,
            dtype=dtype,
            m=m,
            d=d,
            seed=seed,
            alpha=alpha,
            limit=limit,
            rows_per_block=rows_per_block,
            vec_size=vec_size,
            device=device,
        )
        print(f"  PASS [{idx + 1}/{len(cases)}] {case_label}")
        if not skip_perf:
            perf = measure_perf(
                inp=inp,
                out_c=out_c,
                out_triton=out_triton,
                mode=mode,
                alpha=alpha,
                limit=limit,
                rows_per_block=rows_per_block,
                vec_size=vec_size,
                warmup=warmup,
                iters=iters,
            )
            print_perf_result(f"[{idx + 1}/{len(cases)}]", perf)
            perf_rows.append((case_label, perf))

    print(f"All {len(cases)} cases passed.")

    if perf_rows:
        print("\nTiming summary (median, warmup={}, iters={}):".format(warmup, iters))
        print(f"{'Case':<60} {'C us':>8} {'Triton us':>10} {'Ratio':>7} {'C TB/s':>8} {'Triton TB/s':>12}")
        for case_label, perf in perf_rows:
            short_label = case_label if len(case_label) <= 60 else case_label[:57] + "..."
            print(
                f"{short_label:<60} "
                f"{perf['c_us']:8.1f} {perf['triton_us']:10.1f} "
                f"{perf['ratio']:7.3f} {perf['c_tbs']:8.3f} {perf['triton_tbs']:12.3f}"
            )


def main() -> None:
    parser = argparse.ArgumentParser(description="Compare C and Triton swiglu_variant implementations.")
    parser.add_argument(
        "--single",
        action="store_true",
        help="Run a single case from CLI flags instead of the default test suite.",
    )
    parser.add_argument("--mode", type=int, choices=[0, 1, 2], default=1)
    parser.add_argument("--dtype", type=str, choices=["fp16", "bf16"], default="fp16")
    parser.add_argument("--m", type=int, default=32)
    parser.add_argument("--d", type=int, default=1024)
    parser.add_argument("--seed", type=int, default=0)
    parser.add_argument("--alpha", type=float, default=1.702)
    parser.add_argument("--limit", type=float, default=7.0)
    parser.add_argument("--rows-per-block", type=int, choices=[1, 2, 4, 8], default=1)
    parser.add_argument("--vec-size", type=int, choices=[1, 2, 4], default=2)
    parser.add_argument("--warmup", type=int, default=5)
    parser.add_argument("--iters", type=int, default=30)
    parser.add_argument("--skip-perf", action="store_true", help="Skip performance benchmark.")
    args = parser.parse_args()

    if not torch.cuda.is_available():
        raise RuntimeError("CUDA is required to run this swiglu comparison test.")

    device = torch.device("cuda")

    if not args.single:
        run_suite(
            DEFAULT_CASES,
            device,
            warmup=args.warmup,
            iters=args.iters,
            skip_perf=args.skip_perf,
        )
        print("Done.")
        return

    dtype = parse_dtype(args.dtype)
    inp, out_c, out_triton = run_correctness_case(
        mode=args.mode,
        dtype=dtype,
        m=args.m,
        d=args.d,
        seed=args.seed,
        alpha=args.alpha,
        limit=args.limit,
        rows_per_block=args.rows_per_block,
        vec_size=args.vec_size,
        device=device,
    )
    print(
        "Correctness check passed for "
        f"{format_case(args.mode, args.dtype, args.m, args.d, args.alpha, args.limit, args.rows_per_block, args.vec_size)}"
    )

    if not args.skip_perf:
        case_label = format_case(
            args.mode, args.dtype, args.m, args.d,
            args.alpha, args.limit, args.rows_per_block, args.vec_size,
        )
        run_perf_summary(
            inp=inp,
            out_c=out_c,
            out_triton=out_triton,
            mode=args.mode,
            alpha=args.alpha,
            limit=args.limit,
            rows_per_block=args.rows_per_block,
            vec_size=args.vec_size,
            warmup=args.warmup,
            iters=args.iters,
            label=case_label,
        )

    print("Done.")


if __name__ == "__main__":
    main()
