# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
import torch
import torch.nn.functional as F
import aiter
import argparse
from aiter.test_common import checkAllclose, perftest
from aiter import dtypes
from aiter.ops.enum import QuantType
from aiter.ops.quant import get_torch_quant
from aiter.jit.utils.chip_info import get_gfx


@perftest()
def run_torch(input, weight, eps, residual=None, x_scale=None, y_scale_dtype=None):
    if residual is None:
        residual_out = None
        output = F.rms_norm(
            input=input, normalized_shape=(input.shape[-1],), weight=weight, eps=eps
        )
    else:
        residual_out = input + residual
        output = F.rms_norm(
            input=residual_out,
            normalized_shape=(input.shape[-1],),
            weight=weight,
            eps=eps,
        )
    if y_scale_dtype is None:
        y_scale = None
        output_q = output
    else:
        output_q, y_scale = aiter.pertoken_quant(output, x_scale=x_scale)
    return output_q, residual_out, y_scale, output


@perftest()
def run_ck(input, weight, eps, residual=None, x_scale=None, y_scale_dtype=None):
    out_before_quant = None
    if y_scale_dtype is None:
        y_scale = None
        if residual is None:
            residual_out = None
            output = aiter.rms_norm(input, weight, eps)
        elif residual is not None:
            residual_out = torch.empty_like(input)
            output = torch.empty_like(input)
            aiter.rmsnorm2d_fwd_with_add(
                output, input, residual, residual_out, weight, eps
            )
    elif x_scale is None:
        y_scale = torch.empty(input.shape[0], 1, dtype=y_scale_dtype, device="cuda")
        output = torch.empty(input.shape, dtype=dtypes.i8, device="cuda")
        if residual is None:
            residual_out = None
            aiter.rmsnorm2d_fwd_with_dynamicquant(output, input, y_scale, weight, eps)
        elif residual is not None:
            residual_out = torch.empty_like(input)
            aiter.rmsnorm2d_fwd_with_add_dynamicquant(
                output, input, residual, residual_out, y_scale, weight, eps
            )
    else:
        y_scale = torch.empty(input.shape[0], 1, dtype=y_scale_dtype, device="cuda")
        output = torch.empty(input.shape, dtype=dtypes.i8, device="cuda")
        if residual is None:
            residual_out = None
            aiter.rmsnorm2d_fwd_with_smoothquant(
                output, input, x_scale, y_scale, weight, eps
            )
        elif residual is not None:
            residual_out = torch.empty_like(input)
            out_before_quant = torch.empty_like(input)
            aiter.rmsnorm2d_fwd_with_add_smoothquant(
                output,
                input,
                residual,
                residual_out,
                x_scale,
                y_scale,
                weight,
                eps,
                out_before_quant=out_before_quant,
            )

    return output, residual_out, y_scale, out_before_quant


def test_rmsnorm2d_instance(dtype, m, n):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    (a, *_), avg_a = run_torch(input, weight, 1e-5)
    (b, *_), avg_b = run_ck(input, weight, 1e-5)
    print(
        f"[perf] dim: {dim}, dtype: {dtype}, torch avg: {avg_a:<8.2f} us, ck avg: {avg_b:<8.2f} us, uplift: {avg_a/avg_b-1:<5.1%}"
    )
    checkAllclose(a, b)
    print("[passed~]")


def test_rmsnorm2d_fuseAdd_instance(dtype, m, n):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    res = torch.randn(dim, dtype=dtype, device="cuda")
    (a, res_a, *_), avg_a = run_torch(input, weight, 1e-5, residual=res)
    (b, res_b, *_), avg_b = run_ck(input, weight, 1e-5, residual=res)

    print(
        f"[perf] dim: {dim}, dtype: {dtype}, torch avg: {avg_a:<8.2f} us, ck avg: {avg_b:<8.2f} us, uplift: {avg_a/avg_b-1:<5.1%}"
    )
    checkAllclose(a, b, rtol=1e-2, atol=1e-1)
    checkAllclose(res_a, res_b)
    print(" [passed~]")


def test_rmsnorm2d_fuseSmoothquant_instance(dtype, m, n, xscaleType, yscaleType):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    xscale = torch.randn(n, dtype=xscaleType, device="cuda")
    (a, _, yscale_a, _), avg_a = run_torch(
        input, weight, 1e-5, x_scale=xscale, y_scale_dtype=yscaleType
    )
    (b, _, yscale_b, _), avg_b = run_ck(
        input, weight, 1e-5, x_scale=xscale, y_scale_dtype=yscaleType
    )

    print(
        f"[perf] dim: {dim}, dtype: {dtype}, torch avg: {avg_a:<8.2f} us, ck avg: {avg_b:<8.2f} us, uplift: {avg_a/avg_b-1:<5.1%}"
    )
    checkAllclose(a, b, rtol=0, atol=1)
    checkAllclose(yscale_a, yscale_b, rtol=1e-3, atol=1e-3)
    print(" [passed~]")


def test_rmsnorm2d_fuseAdd_Smoothquant_instance(dtype, m, n, xscaleType, yscaleType):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    res = torch.randn(dim, dtype=dtype, device="cuda")
    xscale = torch.randn(n, dtype=xscaleType, device="cuda")
    (a, res_a, yscale_a, ynorm_a), avg_a = run_torch(
        input, weight, 1e-5, residual=res, x_scale=xscale, y_scale_dtype=yscaleType
    )
    (b, res_b, yscale_b, ynorm_b), avg_b = run_ck(
        input, weight, 1e-5, residual=res, x_scale=xscale, y_scale_dtype=yscaleType
    )

    print(
        f"[perf] dim: {dim}, dtype: {dtype}, torch avg: {avg_a:<8.2f} us, ck avg: {avg_b:<8.2f} us, uplift: {avg_a/avg_b-1:<5.1%}"
    )
    checkAllclose(a, b, rtol=0, atol=1)
    checkAllclose(res_a, res_b)
    checkAllclose(yscale_a, yscale_b, rtol=1e-3, atol=1e-3)
    checkAllclose(ynorm_a, ynorm_b)
    print(" [passed~]")


def test_rmsnorm2d_fuseDynamicquant_instance(dtype, m, n, yscaleType):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    (a, _, yscale_a, _), avg_a = run_torch(
        input, weight, 1e-5, y_scale_dtype=yscaleType
    )
    (b, _, yscale_b, _), avg_b = run_ck(input, weight, 1e-5, y_scale_dtype=yscaleType)

    print(
        f"[perf] dim: {dim}, dtype: {dtype}, torch avg: {avg_a:<8.2f} us, ck avg: {avg_b:<8.2f} us, uplift: {avg_a/avg_b-1:<5.1%}"
    )
    checkAllclose(a, b, rtol=0, atol=1)
    checkAllclose(yscale_a, yscale_b)
    print(" [passed~]")


def test_rmsnorm2d_fuseAdd_Dynamicquant_instance(dtype, m, n, yscaleType):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    res = torch.randn(dim, dtype=dtype, device="cuda")
    (a, res_a, yscale_a, _), avg_a = run_torch(
        input, weight, 1e-5, residual=res, y_scale_dtype=yscaleType
    )
    (b, res_b, yscale_b, _), avg_b = run_ck(
        input, weight, 1e-5, residual=res, y_scale_dtype=yscaleType
    )

    print(
        f"[perf] dim: {dim}, dtype: {dtype}, torch avg: {avg_a:<8.2f} us, ck avg: {avg_b:<8.2f} us, uplift: {avg_a/avg_b-1:<5.1%}"
    )
    checkAllclose(a, b, rtol=0, atol=1)
    checkAllclose(res_a, res_b)
    checkAllclose(yscale_a, yscale_b)
    print(" [passed~]")


def test_rmsnorm2d():
    print("\nstart rmsnorm2d test")
    for dtype in [dtypes.bf16]:
        for m in [1, 2, 4, 8, 16, 32, 64, 128, 256]:
            for n in [1024, 2048]:
                test_rmsnorm2d_instance(dtype, m, n)


def test_rmsnorm2d_fuseAdd():
    print("\nstart rmsnorm2d fuse add test")
    for dtype in [dtypes.bf16]:
        for m in [1, 2, 4, 8, 16, 32, 64, 128, 256]:
            for n in [1024, 2048]:
                test_rmsnorm2d_fuseAdd_instance(dtype, m, n)


def test_rmsnorm2d_fuseSmoothquant():
    print("\nstart rmsnorm2d fuse Smoothquant test")
    for scaleType in [dtypes.fp32]:
        for dtype in [dtypes.bf16]:
            for m in [1, 2, 4, 8, 16, 32, 64, 128, 256]:
                for n in [1024, 2048]:
                    test_rmsnorm2d_fuseSmoothquant_instance(
                        dtype, m, n, xscaleType=scaleType, yscaleType=scaleType
                    )


def test_rmsnorm2d_fuseAdd_Smoothquant():
    print("\nstart rmsnorm2d fuse add Smoothquant test")
    for scaleType in [dtypes.fp32]:
        for dtype in [dtypes.bf16]:
            for m in [1, 2, 4, 8, 16, 32, 64, 128, 256]:
                for n in [1024, 2048]:
                    test_rmsnorm2d_fuseAdd_Smoothquant_instance(
                        dtype, m, n, xscaleType=scaleType, yscaleType=scaleType
                    )


def test_rmsnorm2d_fuseDynamicquant():
    print("\nstart rmsnorm2d fuse Smoothquant test")
    for scaleType in [dtypes.fp32]:
        for dtype in [dtypes.fp16, dtypes.bf16]:
            for m in [1, 2, 4, 8, 16, 32, 64, 128, 256]:
                for n in [1024, 2048]:
                    test_rmsnorm2d_fuseDynamicquant_instance(
                        dtype, m, n, yscaleType=scaleType
                    )


def test_rmsnorm2d_fuseAdd_Dynamicquant():
    print("\nstart rmsnorm2d fuse add Smoothquant test")
    for scaleType in [dtypes.fp32]:
        for dtype in [dtypes.fp16, dtypes.bf16]:
            for m in [1, 2, 4, 8, 16, 32, 64, 128, 256]:
                for n in [1024, 2048]:
                    test_rmsnorm2d_fuseAdd_Dynamicquant_instance(
                        dtype, m, n, yscaleType=scaleType
                    )


# ============================================================================
# module_rmsnorm_quant: the fast HIP rmsnorm / add_rmsnorm / rmsnorm_quant /
# add_rmsnorm_quant entries ported from aiter-github (modes 7..14).
#
# Modes 1..6 above exercise the CK / opus rmsnorm2d_* path and are left exactly
# as they were -- they are the regression baseline for this file. The HIP
# entries are new API surface, not a replacement, so they get their own modes
# and their own comparison against both the torch reference and the CK path
# (the CK path is the performance gate: the HIP kernel must not be slower).
# ============================================================================

# fp8 arithmetic needs HW packed fp8 conversion, which gfx936 does not have;
# aiter.utility.dtypes falls dtypes.fp8 back to torch.uint8 there.
_FP8_ARCHS = ("gfx938", "gfx92a", "gfx946")


def hip_fp8_supported():
    return get_gfx() in _FP8_ARCHS


def _group_size_of(quant_type):
    if quant_type in (QuantType.No, QuantType.per_Token):
        return 0
    if quant_type == QuantType.per_1x128:
        return 128
    if quant_type == QuantType.per_1x32:
        return 32
    raise ValueError(f"unsupported quant type for module_rmsnorm_quant: {quant_type}")


@perftest()
def run_hip(
    input,
    weight,
    eps,
    residual=None,
    q_dtype=None,
    quant_type=QuantType.No,
    shuffle_scale=False,
):
    group_size = _group_size_of(quant_type)
    m, n = input.shape
    if quant_type == QuantType.No:
        scale = None
        output = torch.empty_like(input)
        if residual is None:
            residual_out = None
            aiter.rmsnorm(output, input, weight, eps)
        else:
            residual_out = torch.empty_like(input)
            aiter.add_rmsnorm(output, input, residual, residual_out, weight, eps)
    else:
        output = torch.empty(input.shape, dtype=q_dtype, device="cuda")
        if group_size == 0:
            scale_shape = (m, 1)
        elif shuffle_scale:
            # shuffle_scale with an fp32 scale stores scale[y][x], i.e. the
            # (m, n//group_size) table transposed.
            scale_shape = (n // group_size, m)
        else:
            scale_shape = (m, n // group_size)
        scale = torch.empty(scale_shape, dtype=dtypes.fp32, device="cuda")
        if residual is None:
            residual_out = None
            aiter.rmsnorm_quant(
                output, input, scale, weight, eps, group_size, shuffle_scale
            )
        else:
            residual_out = torch.empty_like(input)
            aiter.add_rmsnorm_quant(
                output,
                input,
                residual,
                residual_out,
                scale,
                weight,
                eps,
                group_size,
                shuffle_scale,
            )
    return output, residual_out, scale


@perftest()
def run_torch_quant(
    input, weight, eps, residual=None, q_dtype=None, quant_type=QuantType.No
):
    if residual is None:
        residual_out = None
        norm_in = input
    else:
        residual_out = input + residual
        norm_in = residual_out
    output = F.rms_norm(
        input=norm_in, normalized_shape=(input.shape[-1],), weight=weight, eps=eps
    )
    if quant_type == QuantType.No:
        return output, residual_out, None
    output_q, y_scale = get_torch_quant(quant_type)(output, quant_dtype=q_dtype)
    return output_q, residual_out, y_scale


def test_rmsnorm2d_hip_instance(
    dtype,
    m,
    n,
    add_residual=False,
    quant_dtype=None,
    quant_type=QuantType.No,
    shuffle_scale=False,
):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    res = torch.randn(dim, dtype=dtype, device="cuda") if add_residual else None

    (a, res_a, yscale_a), avg_a = run_torch_quant(
        input, weight, 1e-5, residual=res, q_dtype=quant_dtype, quant_type=quant_type
    )
    (c, res_c, yscale_c), avg_c = run_hip(
        input,
        weight,
        1e-5,
        residual=res,
        q_dtype=quant_dtype,
        quant_type=quant_type,
        shuffle_scale=shuffle_scale,
    )

    # The CK / opus path only covers per-token i8 dynamic quant and the
    # unquantized norm, so it is the perf reference only for those shapes.
    avg_b = None
    if quant_type == QuantType.No or (
        quant_type == QuantType.per_Token and quant_dtype == dtypes.i8
    ):
        (_, _, _, _), avg_b = run_ck(
            input,
            weight,
            1e-5,
            residual=res,
            y_scale_dtype=dtypes.fp32 if quant_type != QuantType.No else None,
        )

    qd = "none" if quant_dtype is None else str(quant_dtype).replace("torch.", "")
    tag = (
        f"quant={'no' if quant_type == QuantType.No else quant_type.name}/{qd}"
        f"{'/shuffle' if shuffle_scale else ''}"
    )
    ck_txt = "    n/a" if avg_b is None else f"{avg_b:<8.2f}"
    uplift = "" if avg_b is None else f", hip/ck uplift: {avg_b/avg_c-1:<5.1%}"
    print(
        f"[perf] dim: {dim}, dtype: {dtype}, {tag}, torch avg: {avg_a:<8.2f} us, "
        f"ck avg: {ck_txt} us, hip avg: {avg_c:<8.2f} us{uplift}"
    )

    atol = 1 if quant_dtype == dtypes.i8 else 1e-2
    checkAllclose(
        a.to(dtypes.fp32), c.to(dtypes.fp32), rtol=0, atol=atol, msg="check hip out"
    )
    if add_residual:
        checkAllclose(res_a, res_c, msg="check hip res")
    if quant_type != QuantType.No:
        ref_scale = yscale_a
        if shuffle_scale:
            # hip wrote the transposed table; compare against the same layout.
            ref_scale = yscale_a.t().contiguous()
        checkAllclose(
            ref_scale.reshape(-1).to(dtypes.fp32),
            yscale_c.reshape(-1).to(dtypes.fp32),
            msg="check hip scale",
        )
    print(" [passed~]")


def test_rmsnorm2d_hip(
    args, add_residual, quant_type, quant_dtype=None, shuffle_scale=False
):
    if quant_dtype == dtypes.fp8 and not hip_fp8_supported():
        print(f"\nskip: fp8 output needs one of {_FP8_ARCHS}, running on {get_gfx()}")
        return
    print(
        f"\nstart module_rmsnorm_quant test "
        f"(residual={add_residual}, quant_type={quant_type}, "
        f"quant_dtype={quant_dtype}, shuffle_scale={shuffle_scale})"
    )
    for n in args.n:
        for m in args.m:
            for dtype in args.dtype:
                test_rmsnorm2d_hip_instance(
                    dtype,
                    m,
                    n,
                    add_residual=add_residual,
                    quant_dtype=quant_dtype,
                    quant_type=quant_type,
                    shuffle_scale=shuffle_scale,
                )


if __name__ == "__main__":
    parser = argparse.ArgumentParser(
        prog="test_rmsnorm2dFusedSQuant",
        description="Test ck rmsnorm2d Fused add and SmoothQuant",
    )
    parser.add_argument(
        "--mode",
        type=int,
        choices=[1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14],
        help="--- CK / opus rmsnorm2d_* path (module_rmsnorm) ---\n"
        + "1: test_rmsnorm2d, \n2:test_rmsnorm2d_fuseAdd, \n"
        + "3:test_rmsnorm2d_fuseSmoothquant, \n4:test_rmsnorm2d_fuseAdd_Smoothquant"
        + "5:test_rmsnorm2d_fuseDynamicquant, \n6:test_rmsnorm2d_fuseAdd_Dynamicquant\n"
        + "--- fast HIP path (module_rmsnorm_quant), honours -m/-n/-d/-q ---\n"
        + "7:hip rmsnorm, \n8:hip add_rmsnorm, \n"
        + "9:hip rmsnorm_quant per_Token, \n10:hip add_rmsnorm_quant per_Token, \n"
        + "11:hip rmsnorm_quant per_1x128, \n12:hip add_rmsnorm_quant per_1x128, \n"
        + "13:hip rmsnorm_quant per_1x128 + shuffle_scale, \n"
        + "14:hip add_rmsnorm_quant per_1x128 + shuffle_scale",
        default=1,
    )
    # The arguments below only affect the HIP modes (7..14). Modes 1..6 keep
    # their own fixed shape loops so this file stays a stable regression
    # baseline for the CK path.
    parser.add_argument(
        "-m",
        type=int,
        default=[1, 8, 128, 2048],
        nargs="*",
        help="M (rows). HIP modes only. e.g.: -m 1 128",
    )
    parser.add_argument(
        "-n",
        type=int,
        # 5120 and 6144 cover the n in (4096, 6144] band, which dispatches to
        # thread_data_size=24; a grouped quant there cannot use that shape
        # (neither 32 nor 128 divides 24) and must fall back to 512x16.
        default=[1024, 2048, 4096, 5120, 6144, 8192],
        nargs="*",
        help="N (hidden). HIP modes only, must be <= 8192. e.g.: -n 4096",
    )
    parser.add_argument(
        "-d",
        "--dtype",
        type=lambda v: dtypes.d_dtypes[v],
        default=[dtypes.bf16],
        nargs="*",
        help="input dtype: bf16 | fp16. HIP modes only.",
    )
    parser.add_argument(
        "-q",
        "--quant_dtype",
        type=lambda v: dtypes.d_dtypes[v],
        default=dtypes.i8,
        help="quant output dtype: i8 | fp8 (fp8 needs gfx938/gfx946). "
        "HIP modes only.",
    )
    # parser.add_argument(
    #     "--GPUID",
    #     type=str,
    #     help="This script uses single GPU. Specify the GPU to use for tuning",
    #     default="0",
    # )
    args = parser.parse_args()
    if args.mode == 1:
        test_rmsnorm2d()
    elif args.mode == 2:
        test_rmsnorm2d_fuseAdd()
    elif args.mode == 3:
        test_rmsnorm2d_fuseSmoothquant()
    elif args.mode == 4:
        test_rmsnorm2d_fuseAdd_Smoothquant()
    elif args.mode == 5:
        test_rmsnorm2d_fuseDynamicquant()
    elif args.mode == 6:
        test_rmsnorm2d_fuseAdd_Dynamicquant()
    elif args.mode == 7:
        test_rmsnorm2d_hip(args, add_residual=False, quant_type=QuantType.No)
    elif args.mode == 8:
        test_rmsnorm2d_hip(args, add_residual=True, quant_type=QuantType.No)
    elif args.mode == 9:
        test_rmsnorm2d_hip(
            args,
            add_residual=False,
            quant_type=QuantType.per_Token,
            quant_dtype=args.quant_dtype,
        )
    elif args.mode == 10:
        test_rmsnorm2d_hip(
            args,
            add_residual=True,
            quant_type=QuantType.per_Token,
            quant_dtype=args.quant_dtype,
        )
    elif args.mode == 11:
        test_rmsnorm2d_hip(
            args,
            add_residual=False,
            quant_type=QuantType.per_1x128,
            quant_dtype=args.quant_dtype,
        )
    elif args.mode == 12:
        test_rmsnorm2d_hip(
            args,
            add_residual=True,
            quant_type=QuantType.per_1x128,
            quant_dtype=args.quant_dtype,
        )
    elif args.mode == 13:
        test_rmsnorm2d_hip(
            args,
            add_residual=False,
            quant_type=QuantType.per_1x128,
            quant_dtype=args.quant_dtype,
            shuffle_scale=True,
        )
    elif args.mode == 14:
        test_rmsnorm2d_hip(
            args,
            add_residual=True,
            quant_type=QuantType.per_1x128,
            quant_dtype=args.quant_dtype,
            shuffle_scale=True,
        )
