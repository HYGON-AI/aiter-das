# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2025, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
 
from aiter.test_common import (
    checkAllclose,
    benchmark,
    run_perftest,
)
import torch
import aiter
from aiter import dtypes
from aiter import get_hip_quant, get_torch_quant, get_triton_quant
from aiter.jit.utils.chip_info import get_gfx
import itertools
import argparse

torch.set_default_device("cuda")


@benchmark()
def test_quant(m, n, q_type, q_dtype, h_dtype):
    dim = (m, n)

    input = torch.randn(dim, dtype=h_dtype)
    torch_quant = get_torch_quant(q_type)
    ref, ref_scale = torch_quant(input, quant_dtype=q_dtype)

    q_funcs = {
        "triton": get_triton_quant,
        "hip": get_hip_quant,
    }
    ret = {}
    for name, q_func in q_funcs.items():
        q_func = q_func(q_type)
        # q_fn = torch.compile(q_func, backend="inductor", fullgraph= True)
        # out,scale = q_fn(input, quant_dtype=q_dtype)
        (out, scale), us1 = run_perftest(q_func, input, quant_dtype=q_dtype)
        assert torch.isfinite(out.to(dtypes.fp32)).all(), (
            "Non-finite output in test_quant (dynamic output): "
            f"{m=}, {n=}, {dim=}, {q_type=}, {q_dtype=}, {h_dtype=}, "
            f"backend={name}"
        )
        assert torch.isfinite(scale.to(dtypes.fp32)).all(), (
            "Non-finite output in test_quant (dynamic scale): "
            f"{m=}, {n=}, {dim=}, {q_type=}, {q_dtype=}, {h_dtype=}, "
            f"backend={name}"
        )
        scale_err = checkAllclose(
            ref_scale.to(dtypes.fp32),
            scale.to(dtypes.fp32),
            rtol=1e-3,
            atol=1e-3,
            msg=f"{name}: dynamic quant scale",
        )
        assert scale_err <= 0.03, (
            "Accuracy check failed in test_quant (dynamic scale): "
            f"{m=}, {n=}, {dim=}, {q_type=}, {q_dtype=}, {h_dtype=}, "
            f"backend={name}, error_ratio={scale_err:.6f}, tolerance=0.03"
        )
        if q_type == aiter.QuantType.per_Tensor:
            dynamic_ref, _ = torch_quant(input, scale=scale, quant_dtype=q_dtype)
        else:
            dynamic_ref = ref
        err1 = checkAllclose(
            dynamic_ref.to(dtypes.fp32),
            out.to(dtypes.fp32),
            rtol=1e-3,
            atol=1e-3,
            msg=f"{name}: dynamic quant",
        )
        assert err1 <= 0.03, (
            "Accuracy check failed in test_quant (dynamic output): "
            f"{m=}, {n=}, {dim=}, {q_type=}, {q_dtype=}, {h_dtype=}, "
            f"backend={name}, error_ratio={err1:.6f}, tolerance=0.03"
        )
        ret[f"{name} dq"] = us1
        ret[f"{name} dq err"] = err1
        if q_type == aiter.QuantType.per_Tensor:
            # out,scale = q_fn(input, ref_scale, quant_dtype=q_dtype)
            (out, scale), us2 = run_perftest(
                q_func, input, ref_scale, quant_dtype=q_dtype
            )
            assert torch.isfinite(out.to(dtypes.fp32)).all(), (
                "Non-finite output in test_quant (static output): "
                f"{m=}, {n=}, {dim=}, {q_type=}, {q_dtype=}, {h_dtype=}, "
                f"backend={name}"
            )
            err2 = checkAllclose(
                ref.to(dtypes.fp32),
                out.to(dtypes.fp32),
                rtol=1e-3,
                atol=1e-3,
                msg=f"{name}: static  quant",
            )
            assert err2 <= 0.03, (
                "Accuracy check failed in test_quant (static output): "
                f"{m=}, {n=}, {dim=}, {q_type=}, {q_dtype=}, {h_dtype=}, "
                f"backend={name}, error_ratio={err2:.6f}, tolerance=0.03"
            )
            ret[f"{name} sq"] = us2
            ret[f"{name} sq err"] = err2

    return ret


d_quant = {
    "fp8_tensor": (aiter.QuantType.per_Tensor, dtypes.fp8),
    "fp8_token": (aiter.QuantType.per_Token, dtypes.fp8),
    "fp8_1x128": (aiter.QuantType.per_1x128, dtypes.fp8),
    "i8_token": (aiter.QuantType.per_Token, dtypes.i8),
    # "i8_1x128": (aiter.QuantType.per_1x128, dtypes.i8),
    # 'fp4x2-1x32': (aiter.QuantType.per_1x32, dtypes.fp4x2),
}
list_dtype = ["fp16", "bf16"]
l_n = [4096, 8192]
l_m = [1, 2, 16, 32, 64, 128, 192, 256, 512, 1024, 16384, 163840]
import pandas as pd

parser = argparse.ArgumentParser(
    formatter_class=argparse.RawTextHelpFormatter,
    description="config input of test",
)
parser.add_argument(
    "-d",
    "--dtype",
    type=str,
    choices=list_dtype,
    nargs="?",
    const=None,
    default=None,
    help="""Data type.
    e.g.: -d bf16""",
)
parser.add_argument(
    "-n",
    "--n",
    type=int,
    nargs="*",
    default=None,
    help="""N of mnk.
    e.g.: -n 1024""",
)
parser.add_argument(
    "-m",
    "--m",
    type=int,
    nargs="*",
    default=None,
    help="""M of mnk.
    e.g.: -m 32""",
)
parser.add_argument(
    "-q",
    "--quant",
    type=str,
    choices=list(d_quant.keys()),
    nargs="*",
    default=list(d_quant.keys()),
    help="""Quantization type.
    e.g.: -q fp8_tensor""",
)

args = parser.parse_args()
arch = get_gfx().lower()
if arch in {"gfx920", "gfx936"}:
    unsupported_quant_tests = [
        quant_name for quant_name in args.quant if "fp8" in quant_name.lower()
    ]
    for quant_name in unsupported_quant_tests:
        aiter.logger.info(
            f"SKIP {quant_name}: architecture {arch} does not support fp8"
        )
    args.quant = [
        quant_name
        for quant_name in args.quant
        if quant_name not in unsupported_quant_tests
    ]

if args.dtype is None:
    list_dtype = [dtypes.d_dtypes[key] for key in list_dtype]
else:
    list_dtype = [dtypes.d_dtypes[args.dtype]]
list_quant = [d_quant[key] for key in args.quant]
failed_cases = []


def run_accuracy_case(test_func, *args, **kwargs):
    try:
        return test_func(*args, **kwargs)
    except AssertionError as exc:
        failed_cases.append(str(exc))
        print(f"[ACCURACY FAILED] {exc}", flush=True)
        return None
if args.n is not None:
    l_n = args.n
if args.m is not None:
    l_m = args.m

for (
    (q_type, q_dtype),
    h_dtype,
) in itertools.product(list_quant, list_dtype):
    df = []
    for n in l_n:
        for m in l_m:
            ret = run_accuracy_case(
                test_quant, m, n, q_type, q_dtype, h_dtype
            )
            if ret is not None:
                df.append(ret)
    df = pd.DataFrame(df)
    q_type_name = getattr(q_type, 'name', str(q_type)).split('.')[-1]
    q_dtype_name = str(q_dtype).split('.')[-1]
    h_dtype_name = str(h_dtype).split('.')[-1]
    
    csv_filename = f"quant_{q_type_name}_{q_dtype_name}_{h_dtype_name}.csv"
    
    df.to_csv(csv_filename, index=False)
    aiter.logger.info(f"summary:\n{df}")

if failed_cases:
    details = "\n".join(
        f"[{index}] {message}"
        for index, message in enumerate(failed_cases, start=1)
    )
    raise AssertionError(
        f"{len(failed_cases)} accuracy case(s) failed:\n{details}"
    )
