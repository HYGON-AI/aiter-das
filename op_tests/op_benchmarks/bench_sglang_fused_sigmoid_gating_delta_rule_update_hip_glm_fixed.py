# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

"""Benchmark the fixed SGLang target-verify KDA shape against Triton.

Run from the repository root:

    PYTHONPATH=. python \
      op_tests/op_benchmarks/bench_sglang_fused_sigmoid_gating_delta_rule_update_hip_glm.py

The fixed logical shape defaults to N=8, W=6, T=N*W=48 (also supports N=12):

    A_log                         [64]                      FP32
    a/raw_gate                    [T, 8192]                 BF16
    dt_bias                       [8192]                    FP32
    q/k/v/o                       [1, T, 64, 128]           BF16
    b/beta_raw                    [1, T, 64]                BF16
    h0_indices                    [N]                       INT32
    cu_seqlens                    [N+1] = [0, 6, ..., T]
    intermediate_state_indices    [N]                       INT32
    retrieve_parent_token         [N, 6]

The first dimension of state and intermediate cache is --num-cache-lines
(default: 97; 96 usable slots plus one padding slot). Input tensors default to
BF16 to match the table; --dtype also allows FP16 and FP32 for additional cases.
The state and intermediate-cache dtype is selected independently with
--ssm-dtype (FP32 or FP16). ReplaySSM staging defaults to enabled;
--no-cache-replayssm-inputs selects the original workload. The ReplaySSM buffers
use the same slot capacity (default: 97) and --replayssm-window-len (default: 6):

    replayssm_rawv/rawk            [slots, 64, window, 128]  input dtype
    replayssm_g                   [slots, 64, window, 128]  FP32
    replayssm_beta                [slots, 64, window]       FP32

Window=6 covers the existing six-token verify sequence; the production replay
window cannot be inferred from this case and can be set independently.
--lower-bound defaults to -5.0 to exercise the KDA safe gate. It is a scalar,
not a tensor shaped by H/K/V; its model value cannot be inferred from shapes.
The default is a synthetic test value giving g in [-5, 0]. Override it with
the model's actual value when available; --no-lower-bound tests the softplus
gate. --beta-scale still defaults to 1.0.
"""

import argparse
import json
from pathlib import Path
from typing import Any, Dict, Tuple

import torch
import torch.nn.functional as F
import triton

import aiter
from aiter.ops.triton.fla.fused_sigmoid_gating_recurrent import (
    fused_sigmoid_gating_delta_rule_update as triton_sglang_fused_sigmoid_gating_delta_rule_update,
)

DEFAULT_NUM_REQUESTS = 8
CACHE_STEPS = 6
NUM_HEADS = 64
HEAD_DIM = 128


def parse_dtype(name: str) -> torch.dtype:
    if name == "fp16":
        return torch.float16
    if name == "bf16":
        return torch.bfloat16
    if name == "fp32":
        return torch.float32
    raise ValueError("unsupported dtype={}".format(name))


def randn(shape: Tuple[int, ...], dtype: torch.dtype, scale: float) -> torch.Tensor:
    return (torch.randn(shape, device="cuda", dtype=dtype) * scale).contiguous()


REPLAY_NAMES = ("replayssm_rawv", "replayssm_rawk", "replayssm_g", "replayssm_beta")


def make_inputs(args: argparse.Namespace) -> Dict[str, Any]:
    num_requests = args.num_requests
    num_tokens = num_requests * CACHE_STEPS
    if args.num_cache_lines < num_requests:
        raise ValueError("--num-cache-lines must be at least {}".format(num_requests))

    torch.manual_seed(args.seed)
    dtype = parse_dtype(args.dtype)
    state_dtype = torch.float32 if args.ssm_dtype == "fp32" else torch.float16
    state_indices = torch.arange(num_requests, device="cuda", dtype=torch.int32)
    parent = torch.zeros((num_requests, CACHE_STEPS), device="cuda", dtype=torch.int32)
    parent[:, 1:] = torch.arange(CACHE_STEPS - 1, device="cuda", dtype=torch.int32)

    tensors = {
        "A_log": randn((NUM_HEADS,), torch.float32, args.input_scale),
        "a": randn((num_tokens, NUM_HEADS * HEAD_DIM), dtype, args.input_scale),
        "dt_bias": randn((NUM_HEADS * HEAD_DIM,), torch.float32, args.input_scale),
        "q": randn((1, num_tokens, NUM_HEADS, HEAD_DIM), dtype, args.input_scale),
        "k": randn((1, num_tokens, NUM_HEADS, HEAD_DIM), dtype, args.input_scale),
        "v": randn((1, num_tokens, NUM_HEADS, HEAD_DIM), dtype, args.input_scale),
        "b": randn((1, num_tokens, NUM_HEADS), dtype, args.input_scale),
        "initial_state": randn(
            (args.num_cache_lines, NUM_HEADS, HEAD_DIM, HEAD_DIM),
            state_dtype,
            args.state_scale,
        ),
        "initial_state_indices": state_indices,
        "cu_seqlens": torch.arange(
            0,
            num_tokens + 1,
            CACHE_STEPS,
            device="cuda",
            dtype=torch.int32,
        ).contiguous(),
        "intermediate_states_buffer": torch.empty(
            (args.num_cache_lines, CACHE_STEPS, NUM_HEADS, HEAD_DIM, HEAD_DIM),
            device="cuda",
            dtype=state_dtype,
        ),
        "intermediate_state_indices": state_indices.clone(),
        "retrieve_parent_token": parent.contiguous(),
    }
    for name in REPLAY_NAMES:
        tensors[name] = None
    if args.cache_replayssm_inputs:
        # These buffers are indexed by initial_state_indices, not cache indices.
        slots = tensors["initial_state"].shape[0]
        H, K = tensors["k"].shape[-2:]
        HV, V = tensors["v"].shape[-2:]
        window = args.replayssm_window_len
        shapes = ((slots, HV, window, V), (slots, H, window, K),
                  (slots, HV, window, K), (slots, HV, window))
        for name, shape, buffer_dtype in zip(
            REPLAY_NAMES, shapes, (dtype, dtype, torch.float32, torch.float32)
        ):
            tensors[name] = torch.empty(shape, device="cuda", dtype=buffer_dtype)
    return tensors


def clone_for_run(tensors: Dict[str, Any]) -> Dict[str, Any]:
    cloned = dict(tensors)
    cloned["initial_state"] = tensors["initial_state"].clone()
    cloned["intermediate_states_buffer"] = torch.empty_like(
        tensors["intermediate_states_buffer"]
    )
    for name in REPLAY_NAMES:
        if tensors[name] is not None:
            # Separate HIP/Triton buffers; NaNs expose missing staging writes.
            cloned[name] = torch.full_like(tensors[name], float("nan"))
    return cloned


def call_hip(args: argparse.Namespace, tensors: Dict[str, Any]) -> torch.Tensor:
    return aiter.sglang_fused_sigmoid_gating_delta_rule_update(
        A_log=tensors["A_log"],
        a=tensors["a"],
        dt_bias=tensors["dt_bias"],
        softplus_beta=args.softplus_beta,
        softplus_threshold=args.softplus_threshold,
        q=tensors["q"],
        k=tensors["k"],
        v=tensors["v"],
        b=tensors["b"],
        initial_state_source=tensors["initial_state"],
        initial_state_indices=tensors["initial_state_indices"],
        scale=args.scale,
        use_qk_l2norm_in_kernel=args.qk_l2norm,
        cu_seqlens=tensors["cu_seqlens"],
        is_kda=True,
        lower_bound=args.lower_bound,
        beta_scale=args.beta_scale,
        disable_state_update=True,
        intermediate_states_buffer=tensors["intermediate_states_buffer"],
        intermediate_state_indices=tensors["intermediate_state_indices"],
        cache_steps=CACHE_STEPS,
        retrieve_parent_token=tensors["retrieve_parent_token"],
        cache_replayssm_inputs=args.cache_replayssm_inputs,
        replayssm_rawv=tensors["replayssm_rawv"],
        replayssm_rawk=tensors["replayssm_rawk"],
        replayssm_g=tensors["replayssm_g"],
        replayssm_beta=tensors["replayssm_beta"],
    )


def call_triton(args: argparse.Namespace, tensors: Dict[str, Any]) -> torch.Tensor:
    return triton_sglang_fused_sigmoid_gating_delta_rule_update(
        A_log=tensors["A_log"],
        a=tensors["a"],
        dt_bias=tensors["dt_bias"],
        softplus_beta=args.softplus_beta,
        softplus_threshold=args.softplus_threshold,
        q=tensors["q"],
        k=tensors["k"],
        v=tensors["v"],
        b=tensors["b"],
        initial_state_source=tensors["initial_state"],
        initial_state_indices=tensors["initial_state_indices"],
        scale=args.scale,
        use_qk_l2norm_in_kernel=args.qk_l2norm,
        cu_seqlens=tensors["cu_seqlens"],
        is_kda=True,
        lower_bound=args.lower_bound,
        beta_scale=args.beta_scale,
        disable_state_update=True,
        intermediate_states_buffer=tensors["intermediate_states_buffer"],
        intermediate_state_indices=tensors["intermediate_state_indices"],
        cache_steps=CACHE_STEPS,
        retrieve_parent_token=tensors["retrieve_parent_token"],
        cache_replayssm_inputs=args.cache_replayssm_inputs,
        replayssm_rawv=tensors["replayssm_rawv"],
        replayssm_rawk=tensors["replayssm_rawk"],
        replayssm_g=tensors["replayssm_g"],
        replayssm_beta=tensors["replayssm_beta"],
    )


def tensor_nbytes(tensor: torch.Tensor) -> int:
    return tensor.numel() * tensor.element_size()


def kernel_io_payload_bytes(tensors: Dict[str, Any]) -> Dict[str, int]:
    """Estimate the explicit global-memory I/O payload of one Triton call.

    This is not a profiler-derived HBM byte count.  It counts the tensor payload
    passed to the kernel (reads) plus the output and selected cache rows written
    by the kernel, then divides that total by the Triton benchmark time.
    """
    read_names = (
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
        "intermediate_state_indices",
        "retrieve_parent_token",
    )
    read_bytes = sum(tensor_nbytes(tensors[name]) for name in read_names
                     if name != "initial_state")
    # Only N selected state slots are read, regardless of pool capacity.
    num_requests = tensors["initial_state_indices"].numel()
    cache_steps = tensors["intermediate_states_buffer"].shape[1]
    read_bytes += num_requests * tensor_nbytes(tensors["initial_state"][0])

    # target-verify writes the cache rows selected by intermediate_state_indices.
    # The sequential parent chain [0, 0, 1, 2, 3, 4] does not add a separate
    # parent-state payload term to this interface-level estimate.
    cache_rows = selected_cache_rows(tensors)
    cache_row_bytes = (
        cache_steps * NUM_HEADS * HEAD_DIM * HEAD_DIM
        * tensors["intermediate_states_buffer"].element_size()
    )
    cache_write_bytes = cache_rows.numel() * cache_row_bytes
    output_write_bytes = tensor_nbytes(tensors["v"])
    replay_write_bytes = 0
    for name in REPLAY_NAMES:
        buffer = tensors[name]
        if buffer is not None:
            steps = min(cache_steps, buffer.shape[2])
            values_per_step = buffer.shape[1] * (buffer.shape[3] if buffer.ndim == 4 else 1)
            replay_write_bytes += num_requests * steps * values_per_step * buffer.element_size()
    write_bytes = output_write_bytes + cache_write_bytes + replay_write_bytes
    return {
        "read": read_bytes,
        "write": write_bytes,
        "total": read_bytes + write_bytes,
        "output_write": output_write_bytes,
        "cache_write": cache_write_bytes,
        "replay_write": replay_write_bytes,
    }


def gbps(num_bytes: int, ms: float) -> float:
    return num_bytes / (ms * 1e-3) / 1e9


def selected_cache_rows(tensors: Dict[str, Any]) -> torch.Tensor:
    return torch.unique(tensors["intermediate_state_indices"].to(torch.long))


def verify(args: argparse.Namespace, tensors: Dict[str, Any]) -> Dict[str, Any]:
    hip_tensors = clone_for_run(tensors)
    triton_tensors = clone_for_run(tensors)
    hip_out = call_hip(args, hip_tensors)
    triton_out = call_triton(args, triton_tensors)
    torch.cuda.synchronize()

    rows = selected_cache_rows(tensors)
    torch.testing.assert_close(
        hip_out.float(),
        triton_out.float(),
        rtol=args.rtol,
        atol=args.atol,
        equal_nan=True,
    )
    torch.testing.assert_close(hip_tensors["initial_state"], tensors["initial_state"], rtol=0, atol=0)
    torch.testing.assert_close(
        triton_tensors["initial_state"], tensors["initial_state"], rtol=0, atol=0
    )
    torch.testing.assert_close(
        hip_tensors["intermediate_states_buffer"].index_select(0, rows),
        triton_tensors["intermediate_states_buffer"].index_select(0, rows),
        rtol=args.rtol,
        atol=args.atol,
        equal_nan=True,
    )
    stats = {
        "verify_pass": True,
        "out_max_abs": float((hip_out.float() - triton_out.float()).abs().max().item()),
    }
    if args.cache_replayssm_inputs:
        state_rows = tensors["initial_state_indices"].to(torch.long)
        num_requests = tensors["initial_state_indices"].numel()
        cache_steps = tensors["intermediate_states_buffer"].shape[1]
        steps = min(cache_steps, args.replayssm_window_len)
        # Independent expectations catch wrong token addresses or missing beta_scale.
        def token_rows(tensor: torch.Tensor) -> torch.Tensor:
            return tensor.float().reshape(num_requests, cache_steps, *tensor.shape[2:])

        a_rows = tensors["a"].float().reshape(
            num_requests, cache_steps, NUM_HEADS, HEAD_DIM
        )
        x = a_rows + tensors["dt_bias"].float().reshape(1, 1, NUM_HEADS, HEAD_DIM)
        A = tensors["A_log"].float().reshape(1, 1, NUM_HEADS, 1).exp()
        g = (args.lower_bound * torch.sigmoid(A * x) if args.lower_bound is not None
             else -A * F.softplus(x, beta=args.softplus_beta, threshold=args.softplus_threshold))
        beta = args.beta_scale * torch.sigmoid(token_rows(tensors["b"]))
        expected = {
            "replayssm_rawv": token_rows(tensors["v"]).permute(0, 2, 1, 3),
            "replayssm_rawk": token_rows(tensors["k"]).permute(0, 2, 1, 3),
            "replayssm_g": g.permute(0, 2, 1, 3),
            "replayssm_beta": beta.permute(0, 2, 1),
        }
        for name in REPLAY_NAMES:
            hip_buffer = hip_tensors[name].index_select(0, state_rows)[:, :, :steps]
            triton_buffer = triton_tensors[name].index_select(0, state_rows)[:, :, :steps]
            raw = name in ("replayssm_rawv", "replayssm_rawk")
            rtol, atol = (0, 0) if raw else (args.rtol, args.atol)
            for actual in (hip_buffer, triton_buffer):
                torch.testing.assert_close(
                    actual.float(), expected[name][:, :, :steps],
                    rtol=rtol, atol=atol, equal_nan=False,
                )
            torch.testing.assert_close(
                hip_buffer.float(), triton_buffer.float(),
                rtol=rtol, atol=atol, equal_nan=False,
            )
            stats[name + "_max_abs"] = float(
                (hip_buffer.float() - triton_buffer.float()).abs().max().item()
            )
    return stats


def shape_dict(tensors: Dict[str, Any]) -> Dict[str, Any]:
    shapes = {name: list(tensor.shape) if tensor is not None else None
              for name, tensor in tensors.items()}
    shapes["o"] = list(tensors["v"].shape)
    return shapes


def main() -> None:
    parser = argparse.ArgumentParser(
        "Benchmark fixed SGLang target-verify KDA HIP path against Triton"
    )
    parser.add_argument("--num-requests", type=int, choices=(8, 12),
                        default=DEFAULT_NUM_REQUESTS,
                        help="Number of requests from the shape table; each has W=6 tokens.")
    parser.add_argument("--num-cache-lines", type=int, default=97)
    parser.add_argument("--dtype", choices=("fp16", "bf16", "fp32"), default="bf16",
                        help="Input dtype; BF16 matches the table's listed test case.")
    parser.add_argument("--ssm-dtype", choices=("fp32", "fp16"), default="fp32",
                        help="Dtype of initial_state and intermediate_states_buffer.")
    parser.add_argument("--input-scale", type=float, default=0.2)
    parser.add_argument("--state-scale", type=float, default=0.02)
    parser.add_argument("--softplus-beta", type=float, default=1.0)
    parser.add_argument("--softplus-threshold", type=float, default=20.0)
    parser.add_argument(
        "--lower-bound", type=float, default=-5.0,
        help="KDA safe-gate scalar; default -5.0 is a synthetic test value, not inferred from shapes.",
    )
    parser.add_argument(
        "--no-lower-bound", dest="lower_bound", action="store_const", const=None,
        help="Disable the KDA safe gate and use the original softplus gate.",
    )
    parser.add_argument("--beta-scale", type=float, default=1.0)
    parser.add_argument(
        "--cache-replayssm-inputs", action=argparse.BooleanOptionalAction, default=True,
        help="Stage ReplaySSM inputs; disable to measure the original workload.",
    )
    parser.add_argument(
        "--replayssm-window-len", type=int, default=CACHE_STEPS,
        help="Replay window only; does not change the existing input/cache shapes.",
    )
    parser.add_argument("--scale", type=float, default=None)
    parser.add_argument("--qk-l2norm", action=argparse.BooleanOptionalAction, default=True)
    parser.add_argument(
        "--kernel-bv",
        choices=(0, 16, 32),
        type=int,
        default=0,
        help="Legacy compatibility option; ignored by the current HIP wrapper.",
    )
    parser.add_argument(
        "--kernel-num-warps",
        type=int,
        default=1,
        help="Legacy compatibility option; ignored by the current HIP wrapper.",
    )
    parser.add_argument("--triton-bv", choices=(16, 32, 64), type=int, default=32,
                        help="Legacy compatibility option; current Triton uses BV=32.")
    parser.add_argument("--triton-num-warps", type=int, default=1,
                        help="Legacy compatibility option; current Triton uses one warp.")
    parser.add_argument("--warmup", type=int, default=10)
    parser.add_argument("--rep", type=int, default=50)
    parser.add_argument("--seed", type=int, default=0)
    parser.add_argument("--skip-triton", action="store_true")
    parser.add_argument("--no-verify", action="store_true")
    parser.add_argument("--rtol", type=float, default=6e-2)
    parser.add_argument("--atol", type=float, default=6e-2)
    parser.add_argument("--out-json", type=str, default="")
    args = parser.parse_args()
    if args.cache_replayssm_inputs and args.replayssm_window_len <= 0:
        parser.error("--replayssm-window-len must be positive when ReplaySSM staging is enabled")

    if not torch.cuda.is_available():
        raise RuntimeError("ROCm/HIP CUDA-compatible device is required")

    tensors = make_inputs(args)
    correctness = None
    if not args.no_verify and not args.skip_triton:
        correctness = verify(args, tensors)

    hip_tensors = clone_for_run(tensors)
    triton_tensors = clone_for_run(tensors)
    call_hip(args, hip_tensors)
    if not args.skip_triton:
        call_triton(args, triton_tensors)
    torch.cuda.synchronize()

    hip_ms = float(
        triton.testing.do_bench(
            lambda: call_hip(args, hip_tensors), warmup=args.warmup, rep=args.rep
        )
    )
    triton_ms = None
    if not args.skip_triton:
        triton_ms = float(
            triton.testing.do_bench(
                lambda: call_triton(args, triton_tensors),
                warmup=args.warmup,
                rep=args.rep,
            )
        )

    io_payload = kernel_io_payload_bytes(tensors)
    result = {
        "case": "sglang_target_verify_kda_{}x{}_h64_k128".format(
            args.num_requests, CACHE_STEPS
        ),
        "shapes": shape_dict(tensors),
        "dtypes": {name: str(tensor.dtype) for name, tensor in tensors.items()
                   if tensor is not None},
        "config": {
            "dtype": args.dtype,
            "ssm_dtype": args.ssm_dtype,
            "num_requests": args.num_requests,
            "num_cache_lines": args.num_cache_lines,
            "is_kda": True,
            "target_verify": True,
            "disable_state_update": True,
            "lower_bound": args.lower_bound,
            "beta_scale": args.beta_scale,
            "cache_replayssm_inputs": args.cache_replayssm_inputs,
            "replayssm_window_len": args.replayssm_window_len,
            "qk_l2norm": args.qk_l2norm,
            "launch_controls": "HIP: SGLANG_GDN_VROWS; Triton: fixed BV=32, num_warps=1",
        },
        "bench": {
            "hip_ms": hip_ms,
            "triton_ms": triton_ms,
            "speedup_vs_triton": triton_ms / hip_ms if triton_ms is not None else None,
            "kernel_io_payload_read_bytes": io_payload["read"],
            "kernel_io_payload_write_bytes": io_payload["write"],
            "kernel_io_payload_total_bytes": io_payload["total"],
            "kernel_io_payload_output_write_bytes": io_payload["output_write"],
            "kernel_io_payload_cache_write_bytes": io_payload["cache_write"],
            "kernel_io_payload_replay_write_bytes": io_payload["replay_write"],
            "hip_io_payload_gbps": gbps(io_payload["total"], hip_ms),
            "triton_io_payload_gbps": (
                gbps(io_payload["total"], triton_ms) if triton_ms is not None else None
            ),
        },
        "correctness": correctness,
    }

    print("=" * 110)
    print(
        "SGLang target-verify KDA | N={} W={} T={} H=HV=64 K=V=128 "
        "vs Triton | cache_lines={} input_dtype={} ssm_dtype={} ReplaySSM={} window={} "
        "lower_bound={} beta_scale={}".format(
            args.num_requests,
            CACHE_STEPS,
            args.num_requests * CACHE_STEPS,
            args.num_cache_lines,
            args.dtype,
            args.ssm_dtype,
            args.cache_replayssm_inputs,
            args.replayssm_window_len,
            args.lower_bound,
            args.beta_scale,
        )
    )
    print("A_log={} a={} dt_bias={} q={} o={} state={} cache={} parent={}".format(
        tuple(tensors["A_log"].shape),
        tuple(tensors["a"].shape),
        tuple(tensors["dt_bias"].shape),
        tuple(tensors["q"].shape),
        tuple(tensors["v"].shape),
        tuple(tensors["initial_state"].shape),
        tuple(tensors["intermediate_states_buffer"].shape),
        tuple(tensors["retrieve_parent_token"].shape),
    ))
    if args.cache_replayssm_inputs:
        for name in REPLAY_NAMES:
            print("{}: shape={} dtype={}".format(
                name, tuple(tensors[name].shape), tensors[name].dtype
            ))
    print("Launch controls: HIP=SGLANG_GDN_VROWS; Triton=BV32/1 warp. Legacy tuning flags are ignored.")
    print("-" * 110)
    print(
        "Kernel I/O payload: read={} bytes, write={} bytes (o={}, cache={}, replay={}), total={} bytes".format(
            io_payload["read"],
            io_payload["write"],
            io_payload["output_write"],
            io_payload["cache_write"],
            io_payload["replay_write"],
            io_payload["total"],
        )
    )
    print("HIP    : {:.4f} ms, {:.2f} us, {:.2f} I/O-payload GB/s".format(
        hip_ms, hip_ms * 1000.0, gbps(io_payload["total"], hip_ms)
    ))
    if triton_ms is not None:
        print(
            "Triton : {:.4f} ms, {:.2f} us, {:.2f} I/O-payload GB/s, HIP speedup {:.4f}x".format(
                triton_ms,
                triton_ms * 1000.0,
                gbps(io_payload["total"], triton_ms),
                triton_ms / hip_ms,
            )
        )
    if correctness is not None:
        print("Verify : {}".format(correctness))
    print("=" * 110)

    if args.out_json:
        out_path = Path(args.out_json)
        out_path.parent.mkdir(parents=True, exist_ok=True)
        out_path.write_text(json.dumps(result, indent=2, sort_keys=True) + "\n", encoding="utf-8")


if __name__ == "__main__":
    main()
