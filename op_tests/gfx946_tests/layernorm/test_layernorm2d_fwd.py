# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Small correctness-only tests for aiter.layernorm2d_fwd.

Run in an environment with AITER and its PyTorch/HIP dependencies installed:
    python op_tests/gfx946_tests/layernorm/test_layernorm2d_fwd.py --mode quick
    python op_tests/gfx946_tests/layernorm/test_layernorm2d_fwd.py --mode full
Optional: --dtypes bf16 --device 0 --require-arch gfx946 --json result.json
Physical GPUs require no Perf Model variables. For simulation, configure the
model externally and use GPU_ARCHS=gfx946 when native compiler discovery fails.

Only Python's standard library, torch and AITER's public operator are used.
No CK checkout/generator, other test scripts, previous results or temporary
files are needed. Inputs/reference/checks run on CPU; each case launches the
DUT once, without warmup or timing loops. quick: 6 cases; full: 56 cases.
"""

import argparse
import json
from pathlib import Path
import sys

import torch
import torch.nn.functional as F


# (N, M): all 13 current N buckets, vector alignment, row/column tails.
SHAPES = [
    (10, 5),
    (64, 9),
    (126, 5),
    (128, 5),
    (256, 5),
    (512, 5),
    (768, 5),
    (1000, 3),
    (1024, 3),
    (1027, 1),
    (1152, 5),
    (1280, 5),
    (1536, 5),
    (2048, 1),
    (3072, 1),
    (3584, 1),
    (4096, 1),
    (5120, 1),
    (6144, 1),
    (8192, 1),
    (8200, 1),
    (8204, 1),
    (8194, 1),
    (8193, 1),
    (12288, 1),
]
DTYPES = {"bf16": torch.bfloat16, "fp16": torch.float16}
TOLERANCES = {"bf16": (1e-2, 1e-2), "fp16": (1e-3, 1e-3)}  # rtol, atol


def make_cases(mode, dtypes):
    cases = []
    for dtype_index, name in enumerate(DTYPES):
        if name not in dtypes:
            continue
        for shape_index, (n, m) in enumerate(SHAPES):
            if mode == "quick" and n not in (128, 1024, 12288):
                continue
            cases.append(
                dict(
                    id=f"{name}_{m}x{n}_random",
                    dtype=name,
                    m=m,
                    n=n,
                    eps=1e-6 if (shape_index + dtype_index) % 2 == 0 else 1e-5,
                    seed=20261023 + shape_index,
                    pattern="random",
                    three_d=n == 128,
                )
            )
        if mode == "full":
            for n, pattern in (
                (64, "constant"),
                (1024, "constant"),
                (8200, "near_constant"),
            ):
                cases.append(
                    dict(
                        id=f"{name}_1x{n}_{pattern}",
                        dtype=name,
                        m=1,
                        n=n,
                        eps=1e-6,
                        seed=20261099,
                        pattern=pattern,
                        three_d=False,
                    )
                )
    return cases


def run_case(layer_norm, case, device):
    dtype = DTYPES[case["dtype"]]
    m, n = case["m"], case["n"]
    generator = torch.Generator(device="cpu").manual_seed(case["seed"])
    if case["pattern"] == "constant":
        x = torch.full((m, n), 3.0, dtype=dtype)
    elif case["pattern"] == "near_constant":
        scale = 0.25 if dtype == torch.bfloat16 else 0.01
        x = (32.0 + scale * torch.randn(m, n, generator=generator)).to(dtype)
    else:
        x = (2.0 * torch.randn(m, n, generator=generator) + 3.0).to(dtype)
    weight = torch.randn(n, generator=generator).to(dtype)
    bias = torch.randn(n, generator=generator).to(dtype)
    reference = F.layer_norm(
        x.float(), (n,), weight.float(), bias.float(), case["eps"]
    )
    x_device = x.to(device)
    weight_device, bias_device = weight.to(device), bias.to(device)
    if case["three_d"]:
        x_device = x_device.view(1, m, n).reshape(-1, n)
    output = layer_norm(x_device, weight_device, bias_device, case["eps"])
    torch.cuda.synchronize(device)
    errors = []
    if output.shape != x.shape or output.dtype != dtype or output.device != device:
        raise AssertionError("incorrect output shape, dtype or device")
    if output.data_ptr() in (
        x_device.data_ptr(), weight_device.data_ptr(), bias_device.data_ptr()
    ):
        errors.append("output aliases an input")
    for name, actual, expected in (
        ("input", x_device, x),
        ("weight", weight_device, weight),
        ("bias", bias_device, bias),
    ):
        if not torch.equal(actual.cpu(), expected):
            errors.append(f"{name} was modified")
    output_cpu = output.cpu().float()
    rtol, atol = TOLERANCES[case["dtype"]]
    difference = (output_cpu - reference).abs()
    bound = atol + rtol * reference.abs()
    mismatch = int((~(difference <= bound)).sum())
    finite = bool(torch.isfinite(output_cpu).all())
    if mismatch or not finite:
        errors.append(f"{mismatch}/{m*n} mismatched elements, finite={finite}")
    return dict(
        case,
        status="FAIL" if errors else "PASS",
        errors=errors,
        finite=finite,
        mismatch=mismatch,
        max_abs_error=float(difference.max()),
        max_error_fraction=float((difference / bound).max()),
        rtol=rtol,
        atol=atol,
    )


def save_result(path, result):
    if path is not None:
        path.write_text(json.dumps(result, indent=2) + "\n", encoding="utf-8")


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument("--mode", choices=("quick", "full"), default="quick")
    parser.add_argument(
        "--dtypes", nargs="+", choices=tuple(DTYPES), default=list(DTYPES)
    )
    parser.add_argument("--device", type=int, default=0)
    parser.add_argument(
        "--require-arch", help="fail unless device architecture matches, e.g. gfx946"
    )
    parser.add_argument(
        "--json", type=Path, help="optional result output; no input files are read"
    )
    args = parser.parse_args()
    if not torch.cuda.is_available():
        raise RuntimeError("a working HIP/CUDA runtime is required")
    torch.set_num_threads(1)
    torch.cuda.set_device(args.device)
    device = torch.device("cuda", args.device)
    props = torch.cuda.get_device_properties(device)
    arch = getattr(props, "gcnArchName", "unknown")
    if args.require_arch and arch.split(":")[0] != args.require_arch:
        raise RuntimeError(f"expected {args.require_arch}, got {arch}")
    from aiter import layernorm2d_fwd

    cases = make_cases(args.mode, args.dtypes)
    result = dict(
        environment=dict(
            torch=torch.__version__, hip=torch.version.hip, arch=arch, device=args.device
        ),
        mode=args.mode,
        cases=[],
        summary=dict(
            planned=len(cases), completed=0, passed=0, failed=0, complete=False
        ),
    )
    save_result(args.json, result)
    print("[env] " + json.dumps(result["environment"]), flush=True)
    for case in cases:
        print(f"[start] {case['id']}", flush=True)
        try:
            record = run_case(layernorm2d_fwd, case, device)
        except Exception as error:
            record = dict(case, status="ERROR", errors=[repr(error)])
        result["cases"].append(record)
        records = result["cases"]
        result["summary"] = dict(
            planned=len(cases),
            completed=len(records),
            passed=sum(r["status"] == "PASS" for r in records),
            failed=sum(r["status"] != "PASS" for r in records),
            complete=len(records) == len(cases),
        )
        save_result(args.json, result)
        print(
            f"[{record['status']}] {case['id']} "
            f"max_abs_error={record.get('max_abs_error')} {record.get('errors')}",
            flush=True,
        )
        if record["status"] == "ERROR":
            break  # Runtime errors can leave the device unusable.
    print("[summary] " + json.dumps(result["summary"]), flush=True)
    return 0 if result["summary"]["complete"] and not result["summary"]["failed"] else 1


if __name__ == "__main__":
    sys.exit(main())
