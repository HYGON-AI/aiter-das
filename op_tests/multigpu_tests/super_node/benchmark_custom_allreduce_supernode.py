# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Benchmark multi-node CustomAllreduce Fabric against RCCL all-reduce."""

import argparse
import ctypes
import json
import math
import os
import socket
import statistics
from collections.abc import Callable
from pathlib import Path

import torch
import torch.distributed as dist


DTYPES = {
    "fp16": torch.float16,
    "bf16": torch.bfloat16,
    "fp32": torch.float32,
}


def parse_args() -> argparse.Namespace:
    parser = argparse.ArgumentParser()
    parser.add_argument("--transport", choices=("fabric", "auto"), default="fabric")
    parser.add_argument("--expect-world-size", type=int, required=True)
    parser.add_argument("--dtype", choices=tuple(DTYPES), default="fp16")
    parser.add_argument(
        "--size-kib",
        type=int,
        action="append",
        default=None,
        help="message size in KiB; repeatable (default: 16,64,256,1024,2048,4096)",
    )
    parser.add_argument("--warmup", type=int, default=10)
    parser.add_argument("--iters", type=int, default=50)
    parser.add_argument("--direct-max-size-mib", type=int, default=8)
    parser.add_argument(
        "--mode",
        choices=("custom", "rccl", "both"),
        default="both",
        help="benchmark CustomAllreduce, RCCL, or both",
    )
    parser.add_argument(
        "--rccl-semantics",
        choices=("inplace", "out-of-place", "both"),
        default="inplace",
        help=(
            "RCCL timing contract: raw in-place all_reduce, an out-of-place "
            "clone+all_reduce emulation, or both (default: inplace for "
            "backward-compatible historical results)"
        ),
    )
    parser.add_argument(
        "--output-json",
        default=None,
        help="optional rank-0 JSON output path containing summary and raw critical-path samples",
    )
    parser.add_argument(
        "--run-label",
        default="",
        help="optional label stored in --output-json for multi-round comparisons",
    )
    parser.add_argument(
        "--diagnose-copy-in",
        action="store_true",
        help="also time the eager D2D copy into CustomAR's uncached registered input buffer",
    )
    parser.add_argument(
        "--diagnose-output-allocation",
        action="store_true",
        help=(
            "also time caller-preallocated out-of-place CustomAR and RCCL paths "
            "to isolate per-call output allocation overhead"
        ),
    )
    return parser.parse_args()


def percentile(values: list[float], fraction: float) -> float:
    ordered = sorted(values)
    index = max(0, math.ceil(fraction * len(ordered)) - 1)
    return ordered[index]


def summarize(
    local_ms: list[float],
    *,
    backend: str,
    num_bytes: int,
    world_size: int,
    dtype_name: str,
) -> dict[str, float | list[float]] | None:
    gathered: list[list[float] | None] = [None] * world_size
    dist.all_gather_object(gathered, local_ms)
    if dist.get_rank() != 0:
        return None

    if any(item is None or len(item) != len(local_ms) for item in gathered):
        raise RuntimeError("incomplete latency samples from one or more ranks")
    critical_ms = [max(item[i] for item in gathered if item is not None) for i in range(len(local_ms))]
    mean_us = statistics.fmean(critical_ms) * 1000.0
    p50_us = statistics.median(critical_ms) * 1000.0
    p95_us = percentile(critical_ms, 0.95) * 1000.0
    p99_us = percentile(critical_ms, 0.99) * 1000.0
    min_us = min(critical_ms) * 1000.0
    algbw_gbps = num_bytes / (mean_us * 1.0e-6) / 1.0e9
    busbw_gbps = algbw_gbps * 2.0 * (world_size - 1) / world_size
    result = {
        "mean_us": mean_us,
        "p50_us": p50_us,
        "p95_us": p95_us,
        "p99_us": p99_us,
        "min_us": min_us,
        "algbw_gbps": algbw_gbps,
        "busbw_gbps": busbw_gbps,
        "critical_path_samples_us": [sample * 1000.0 for sample in critical_ms],
    }
    print(
        "PERF "
        f"world_size={world_size} backend={backend} dtype={dtype_name} "
        f"bytes={num_bytes} mean_us={mean_us:.3f} p50_us={p50_us:.3f} "
        f"p95_us={p95_us:.3f} p99_us={p99_us:.3f} min_us={min_us:.3f} "
        f"algbw_gbps={algbw_gbps:.3f} busbw_gbps={busbw_gbps:.3f}",
        flush=True,
    )
    return result


def time_collective(
    op: Callable[[torch.Tensor], torch.Tensor],
    inp: torch.Tensor,
    rank: int,
    warmup: int,
    iters: int,
) -> list[float]:
    for _ in range(warmup):
        inp.fill_(rank + 1)
        op(inp)
    torch.cuda.synchronize()
    dist.barrier()

    samples_ms = []
    for _ in range(iters):
        inp.fill_(rank + 1)
        start = torch.cuda.Event(enable_timing=True)
        end = torch.cuda.Event(enable_timing=True)
        start.record()
        op(inp)
        end.record()
        end.synchronize()
        samples_ms.append(start.elapsed_time(end))
    dist.barrier()
    return samples_ms


def make_hip_copy_op(
    destination: int,
    num_bytes: int,
) -> Callable[[torch.Tensor], torch.Tensor]:
    """Build a diagnostic-only asynchronous D2D copy."""
    try:
        hip = ctypes.CDLL("libamdhip64.so")
    except OSError:
        try:
            hip = ctypes.CDLL("libamdhip64.so.6")
        except OSError:
            # Keep real CDLL names above; only sanitize the user-facing error.
            raise RuntimeError(
                "Failed to load HCU HIP runtime library (libhip64)"
            ) from None
    hip.hipMemcpyAsync.argtypes = (
        ctypes.c_void_p,
        ctypes.c_void_p,
        ctypes.c_size_t,
        ctypes.c_int,
        ctypes.c_void_p,
    )
    hip.hipMemcpyAsync.restype = ctypes.c_int
    stream = torch.cuda.current_stream().cuda_stream

    def copy_to_registered_input(inp: torch.Tensor) -> torch.Tensor:
        status = hip.hipMemcpyAsync(
            ctypes.c_void_p(destination),
            ctypes.c_void_p(inp.data_ptr()),
            ctypes.c_size_t(num_bytes),
            3,  # hipMemcpyDeviceToDevice
            ctypes.c_void_p(stream),
        )
        if status != 0:
            raise RuntimeError(f"hipMemcpyAsync diagnostic failed with status={status}")
        return inp

    return copy_to_registered_input


def main() -> None:
    args = parse_args()
    from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
    if args.expect_world_size not in (8, 16, 32):
        raise ValueError("performance runner supports world sizes 8, 16, and 32")
    if args.warmup < 0 or args.iters <= 0:
        raise ValueError("--warmup must be non-negative and --iters must be positive")
    if args.direct_max_size_mib <= 0:
        raise ValueError("--direct-max-size-mib must be positive")
    if (
        args.mode == "both"
        and args.diagnose_output_allocation
        and args.rccl_semantics == "inplace"
    ):
        raise ValueError(
            "--diagnose-output-allocation with --mode both requires "
            "--rccl-semantics out-of-place or both"
        )

    sizes_kib = args.size_kib or [16, 64, 256, 1024, 2048, 4096]
    if any(size <= 0 for size in sizes_kib):
        raise ValueError("--size-kib values must be positive")

    rank = int(os.environ["RANK"])
    local_rank = int(os.environ["LOCAL_RANK"])
    world_size = int(os.environ["WORLD_SIZE"])
    if world_size != args.expect_world_size:
        raise RuntimeError(f"expected world_size={args.expect_world_size}, got {world_size}")

    os.environ["AITER_AR_TRANSPORT"] = args.transport
    os.environ["AITER_AR_ENABLE_REG_CAPTURE"] = "0"
    torch.cuda.set_device(local_rank)
    dist.init_process_group(backend="gloo", init_method="env://")

    ca = None
    rccl_group = None
    try:
        if args.mode in ("custom", "both"):
            ca = CustomAllreduce(
                group=dist.group.WORLD,
                device=torch.device(f"cuda:{local_rank}"),
                max_size=args.direct_max_size_mib * 1024 * 1024,
                enable_register_for_capturing=False,
            )
            if ca.disabled or ca.transport != "fabric":
                raise RuntimeError(
                    f"CustomAllreduce unavailable: disabled={ca.disabled}, transport={ca.transport!r}"
                )
        if args.mode in ("rccl", "both"):
            rccl_group = dist.new_group(
                ranks=list(range(world_size)),
                backend="nccl",
            )

        dtype = DTYPES[args.dtype]
        element_size = torch.empty((), dtype=dtype).element_size()
        max_bytes = args.direct_max_size_mib * 1024 * 1024
        results: dict[tuple[str, int], dict[str, float | list[float]]] = {}

        gathered_hostnames: list[str | None] = [None] * world_size
        dist.all_gather_object(gathered_hostnames, socket.gethostname())
        hostnames = list(dict.fromkeys(name for name in gathered_hostnames if name is not None))

        if rank == 0:
            print(
                "PERF_CONFIG "
                f"world_size={world_size} dtype={args.dtype} sizes_kib={','.join(map(str, sizes_kib))} "
                f"warmup={args.warmup} iters={args.iters} mode={args.mode} transport={args.transport} "
                f"rccl_semantics={args.rccl_semantics} "
                f"block_limit={os.environ.get('AITER_AR_BLOCK_LIMIT', '<default>')}",
                flush=True,
            )

        for size_kib in sizes_kib:
            num_bytes = size_kib * 1024
            if num_bytes > max_bytes:
                raise ValueError(
                    f"message {size_kib} KiB exceeds direct buffer {args.direct_max_size_mib} MiB"
                )
            if num_bytes % element_size != 0 or num_bytes % 16 != 0:
                raise ValueError(f"message size {num_bytes} is not valid for dtype/custom AR")
            inp = torch.empty(num_bytes // element_size, dtype=dtype, device=f"cuda:{local_rank}")
            expected = world_size * (world_size + 1) / 2

            if ca is not None:
                if args.diagnose_copy_in:
                    def noop(tensor: torch.Tensor) -> torch.Tensor:
                        return tensor

                    local_ms = time_collective(noop, inp, rank, args.warmup, args.iters)
                    summary = summarize(
                        local_ms,
                        backend="event_overhead",
                        num_bytes=num_bytes,
                        world_size=world_size,
                        dtype_name=args.dtype,
                    )
                    if summary is not None:
                        results[("event_overhead", num_bytes)] = summary

                    cached_copy_destination = torch.empty_like(inp)
                    cached_copy_op = make_hip_copy_op(
                        cached_copy_destination.data_ptr(), num_bytes
                    )
                    local_ms = time_collective(
                        cached_copy_op, inp, rank, args.warmup, args.iters
                    )
                    summary = summarize(
                        local_ms,
                        backend="copy_to_cached",
                        num_bytes=num_bytes,
                        world_size=world_size,
                        dtype_name=args.dtype,
                    )
                    if summary is not None:
                        results[("copy_to_cached", num_bytes)] = summary

                    uncached_copy_op = make_hip_copy_op(
                        ca._pool["input"].data_ptr, num_bytes
                    )
                    local_ms = time_collective(
                        uncached_copy_op, inp, rank, args.warmup, args.iters
                    )
                    summary = summarize(
                        local_ms,
                        backend="copy_to_uncached",
                        num_bytes=num_bytes,
                        world_size=world_size,
                        dtype_name=args.dtype,
                    )
                    if summary is not None:
                        results[("copy_to_uncached", num_bytes)] = summary

                inp.fill_(rank + 1)
                out = ca.custom_all_reduce(inp)
                if out is None:
                    raise RuntimeError(f"CustomAllreduce rejected {size_kib} KiB")
                torch.cuda.synchronize()
                torch.testing.assert_close(
                    out,
                    torch.full_like(out, expected),
                    rtol=1e-3,
                    atol=1e-3,
                )

                def custom_op(tensor: torch.Tensor) -> torch.Tensor:
                    result = ca.custom_all_reduce(tensor)
                    if result is None:
                        raise RuntimeError("CustomAllreduce unexpectedly rejected input")
                    return result

                local_ms = time_collective(custom_op, inp, rank, args.warmup, args.iters)
                summary = summarize(
                    local_ms,
                    backend="custom_fabric",
                    num_bytes=num_bytes,
                    world_size=world_size,
                    dtype_name=args.dtype,
                )
                if summary is not None:
                    results[("custom_fabric", num_bytes)] = summary

                if rank == 0 and args.diagnose_copy_in:
                    overhead_summary = results[("event_overhead", num_bytes)]
                    cached_summary = results[("copy_to_cached", num_bytes)]
                    copy_summary = results[("copy_to_uncached", num_bytes)]
                    custom_summary = results[("custom_fabric", num_bytes)]
                    print(
                        "COPY_BREAKDOWN "
                        f"world_size={world_size} dtype={args.dtype} bytes={num_bytes} "
                        f"p50_noop_us={float(overhead_summary['p50_us']):.3f} "
                        f"p50_cached_copy_us={float(cached_summary['p50_us']):.3f} "
                        f"p50_uncached_copy_us={float(copy_summary['p50_us']):.3f} "
                        f"p50_uncached_fraction={float(copy_summary['p50_us']) / float(custom_summary['p50_us']):.3f} "
                        f"p95_uncached_fraction={float(copy_summary['p95_us']) / float(custom_summary['p95_us']):.3f} "
                        f"mean_uncached_fraction={float(copy_summary['mean_us']) / float(custom_summary['mean_us']):.3f}",
                        flush=True,
                    )

                if args.diagnose_output_allocation:
                    custom_out = torch.empty_like(inp)
                    inp.fill_(rank + 1)
                    ca.all_reduce(inp, out=custom_out)
                    torch.cuda.synchronize()
                    torch.testing.assert_close(
                        inp,
                        torch.full_like(inp, rank + 1),
                        rtol=0,
                        atol=0,
                    )
                    torch.testing.assert_close(
                        custom_out,
                        torch.full_like(custom_out, expected),
                        rtol=1e-3,
                        atol=1e-3,
                    )

                    def custom_preallocated_out_op(
                        tensor: torch.Tensor,
                    ) -> torch.Tensor:
                        return ca.all_reduce(tensor, out=custom_out)

                    local_ms = time_collective(
                        custom_preallocated_out_op,
                        inp,
                        rank,
                        args.warmup,
                        args.iters,
                    )
                    summary = summarize(
                        local_ms,
                        backend="custom_fabric_preallocated_out",
                        num_bytes=num_bytes,
                        world_size=world_size,
                        dtype_name=args.dtype,
                    )
                    if summary is not None:
                        results[("custom_fabric_preallocated_out", num_bytes)] = summary

            if rccl_group is not None:
                if args.rccl_semantics in ("inplace", "both"):
                    inp.fill_(rank + 1)
                    dist.all_reduce(inp, group=rccl_group)
                    torch.cuda.synchronize()
                    torch.testing.assert_close(
                        inp,
                        torch.full_like(inp, expected),
                        rtol=1e-3,
                        atol=1e-3,
                    )

                    def rccl_op(tensor: torch.Tensor) -> torch.Tensor:
                        dist.all_reduce(tensor, group=rccl_group)
                        return tensor

                    local_ms = time_collective(
                        rccl_op, inp, rank, args.warmup, args.iters
                    )
                    summary = summarize(
                        local_ms,
                        backend="rccl",
                        num_bytes=num_bytes,
                        world_size=world_size,
                        dtype_name=args.dtype,
                    )
                    if summary is not None:
                        results[("rccl", num_bytes)] = summary

                if args.rccl_semantics in ("out-of-place", "both"):
                    inp.fill_(rank + 1)
                    rccl_out = inp.clone()
                    dist.all_reduce(rccl_out, group=rccl_group)
                    torch.cuda.synchronize()
                    torch.testing.assert_close(
                        inp,
                        torch.full_like(inp, rank + 1),
                        rtol=0,
                        atol=0,
                    )
                    torch.testing.assert_close(
                        rccl_out,
                        torch.full_like(rccl_out, expected),
                        rtol=1e-3,
                        atol=1e-3,
                    )

                    def rccl_out_of_place_op(tensor: torch.Tensor) -> torch.Tensor:
                        result = tensor.clone()
                        dist.all_reduce(result, group=rccl_group)
                        return result

                    local_ms = time_collective(
                        rccl_out_of_place_op,
                        inp,
                        rank,
                        args.warmup,
                        args.iters,
                    )
                    summary = summarize(
                        local_ms,
                        backend="rccl_out_of_place",
                        num_bytes=num_bytes,
                        world_size=world_size,
                        dtype_name=args.dtype,
                    )
                    if summary is not None:
                        results[("rccl_out_of_place", num_bytes)] = summary

                if args.diagnose_output_allocation:
                    rccl_work = torch.empty_like(inp)
                    inp.fill_(rank + 1)
                    rccl_work.copy_(inp)
                    dist.all_reduce(rccl_work, group=rccl_group)
                    torch.cuda.synchronize()
                    torch.testing.assert_close(
                        inp,
                        torch.full_like(inp, rank + 1),
                        rtol=0,
                        atol=0,
                    )
                    torch.testing.assert_close(
                        rccl_work,
                        torch.full_like(rccl_work, expected),
                        rtol=1e-3,
                        atol=1e-3,
                    )

                    def rccl_preallocated_out_op(
                        tensor: torch.Tensor,
                    ) -> torch.Tensor:
                        rccl_work.copy_(tensor)
                        dist.all_reduce(rccl_work, group=rccl_group)
                        return rccl_work

                    local_ms = time_collective(
                        rccl_preallocated_out_op,
                        inp,
                        rank,
                        args.warmup,
                        args.iters,
                    )
                    summary = summarize(
                        local_ms,
                        backend="rccl_out_of_place_preallocated_out",
                        num_bytes=num_bytes,
                        world_size=world_size,
                        dtype_name=args.dtype,
                    )
                    if summary is not None:
                        results[
                            ("rccl_out_of_place_preallocated_out", num_bytes)
                        ] = summary

            if (
                rank == 0
                and args.mode == "both"
                and args.rccl_semantics in ("inplace", "both")
            ):
                custom = results[("custom_fabric", num_bytes)]
                rccl = results[("rccl", num_bytes)]
                print(
                    "PERF_COMPARE "
                    f"world_size={world_size} dtype={args.dtype} bytes={num_bytes} "
                    f"mean_speedup_vs_rccl={rccl['mean_us'] / custom['mean_us']:.3f} "
                    f"p50_speedup_vs_rccl={rccl['p50_us'] / custom['p50_us']:.3f} "
                    f"p95_speedup_vs_rccl={rccl['p95_us'] / custom['p95_us']:.3f} "
                    f"p99_speedup_vs_rccl={rccl['p99_us'] / custom['p99_us']:.3f}",
                    flush=True,
                )

            if (
                rank == 0
                and args.mode == "both"
                and args.diagnose_output_allocation
            ):
                custom = results[("custom_fabric", num_bytes)]
                custom_preallocated = results[
                    ("custom_fabric_preallocated_out", num_bytes)
                ]
                rccl_out_of_place = results[("rccl_out_of_place", num_bytes)]
                rccl_preallocated = results[
                    ("rccl_out_of_place_preallocated_out", num_bytes)
                ]
                print(
                    "OUTPUT_ALLOCATION_BREAKDOWN "
                    f"world_size={world_size} dtype={args.dtype} bytes={num_bytes} "
                    f"custom_p50_alloc_us={custom['p50_us']:.3f} "
                    f"custom_p50_preallocated_us={custom_preallocated['p50_us']:.3f} "
                    f"custom_p50_speedup={custom['p50_us'] / custom_preallocated['p50_us']:.3f} "
                    f"rccl_p50_alloc_us={rccl_out_of_place['p50_us']:.3f} "
                    f"rccl_p50_preallocated_us={rccl_preallocated['p50_us']:.3f} "
                    f"rccl_p50_speedup={rccl_out_of_place['p50_us'] / rccl_preallocated['p50_us']:.3f}",
                    flush=True,
                )

            if (
                rank == 0
                and args.mode == "both"
                and args.rccl_semantics in ("out-of-place", "both")
            ):
                custom = results[("custom_fabric", num_bytes)]
                rccl_out_of_place = results[("rccl_out_of_place", num_bytes)]
                print(
                    "PERF_COMPARE_OUT_OF_PLACE "
                    f"world_size={world_size} dtype={args.dtype} bytes={num_bytes} "
                    f"mean_speedup_vs_rccl={rccl_out_of_place['mean_us'] / custom['mean_us']:.3f} "
                    f"p50_speedup_vs_rccl={rccl_out_of_place['p50_us'] / custom['p50_us']:.3f} "
                    f"p95_speedup_vs_rccl={rccl_out_of_place['p95_us'] / custom['p95_us']:.3f} "
                    f"p99_speedup_vs_rccl={rccl_out_of_place['p99_us'] / custom['p99_us']:.3f}",
                    flush=True,
                )

            del inp
            if args.diagnose_copy_in and ca is not None:
                del cached_copy_destination
            if args.diagnose_output_allocation:
                if ca is not None:
                    del custom_preallocated_out_op, custom_out
                if rccl_group is not None:
                    del rccl_preallocated_out_op, rccl_work
            torch.cuda.empty_cache()

        if rank == 0 and args.output_json:
            output_path = Path(args.output_json).expanduser().resolve()
            output_path.parent.mkdir(parents=True, exist_ok=True)
            report = {
                "schema_version": 2,
                "run_label": args.run_label,
                "world_size": world_size,
                "hostnames": hostnames,
                "dtype": args.dtype,
                "sizes_kib": sizes_kib,
                "warmup": args.warmup,
                "iters": args.iters,
                "mode": args.mode,
                "rccl_semantics": args.rccl_semantics,
                "transport": args.transport,
                "diagnose_copy_in": args.diagnose_copy_in,
                "diagnose_output_allocation": args.diagnose_output_allocation,
                "block_limit": os.environ.get("AITER_AR_BLOCK_LIMIT"),
                "results": [
                    {"backend": backend, "bytes": num_bytes, **summary}
                    for (backend, num_bytes), summary in results.items()
                ],
            }
            with output_path.open("w", encoding="utf-8") as output_file:
                json.dump(report, output_file, ensure_ascii=False, indent=2)
                output_file.write("\n")
            print(f"PERF_JSON path={output_path}", flush=True)

        dist.barrier()
        if rank == 0:
            print(
                f"SUPERNODE_CUSTOM_AR_PERF_PASS world_size={world_size} mode={args.mode}",
                flush=True,
            )
    finally:
        if ca is not None:
            ca.close()
        if rccl_group is not None:
            dist.destroy_process_group(rccl_group)
        if dist.is_initialized():
            dist.destroy_process_group()


if __name__ == "__main__":
    main()
