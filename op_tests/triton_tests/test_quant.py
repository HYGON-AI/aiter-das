# SPDX-License-Identifier: MIT
 
import torch
import pytest

from aiter.ops.triton.quant import (
    static_per_tensor_quant_fp8_i8,
    dynamic_per_tensor_quant_fp8_i8,
    dynamic_per_token_quant_fp8_i8,
)
from aiter.ops.quant import per_token_quant_triton, pertoken_quant
from aiter.ops.triton.utils.arch_info import get_fp8_e4m3_dtype

DEBUG = False


def torch_static_per_tensor_quant_fp8_i8(out, x, scale, dtype_quant):
    out = x / scale
    if dtype_quant == torch.int8:
        out = out.round()
    out = out.to(dtype_quant)

    return out


@pytest.mark.parametrize(
    "M, N",
    [
        (1, 32),
        (32, 32),
        (2, 16),
        (10, 128),
        (32, 8192),
        (1024, 128),
        (2048, 1024),
        (193, 75),
    ],
)
@pytest.mark.parametrize("dtype_in", [torch.float16, torch.bfloat16, torch.float32])
@pytest.mark.parametrize("dtype_quant", [torch.int8, get_fp8_e4m3_dtype()])
def test_static_per_tensor_quant(M: int, N: int, dtype_in, dtype_quant):
    torch.manual_seed(20)
    x = torch.randn((M, N), dtype=dtype_in, device="cuda")
    scale = torch.randn(1, dtype=torch.float32, device="cuda")

    torch_out = torch.zeros((M, N), dtype=dtype_quant, device="cuda")
    torch_out = torch_static_per_tensor_quant_fp8_i8(torch_out, x, scale, dtype_quant)

    triton_out = torch.empty_like(x, dtype=dtype_quant, device="cuda")
    triton_out = static_per_tensor_quant_fp8_i8(triton_out, x, scale)

    # Note: Torch doesn't support comparing fp8 type
    torch.testing.assert_close(
        triton_out.to(dtype=torch.float32),
        torch_out.to(dtype=torch.float32),
        atol=1e-02,
        rtol=1e-02,
    )


def torch_dynamic_per_tensor_quant_fp8_i8(x, dtype_quant):
    # Triton does max and scale in f32 so we need to match precision here.
    x_f32 = x.to(torch.float32)
    x_max = torch.max(torch.abs(x_f32))
    dtype_max = (
        torch.iinfo(dtype_quant).max
        if dtype_quant == torch.int8
        else torch.finfo(dtype_quant).max
    )
    scale_out = x_max.to(torch.float32) / dtype_max

    out = x_f32 / scale_out
    if dtype_quant == torch.int8:
        out = out.round()
    out = out.to(dtype=dtype_quant)

    return out, torch.tensor([scale_out], dtype=torch.float32, device=x.device)


@pytest.mark.parametrize(
    "M, N", [(1, 32), (32, 32), (2, 16), (10, 128), (32, 8192), (93, 75)]
)
@pytest.mark.parametrize("dtype_in", [torch.float16, torch.bfloat16, torch.float32])
@pytest.mark.parametrize("dtype_quant", [torch.int8, get_fp8_e4m3_dtype()])
def test_dynamic_per_tensor_quant(M: int, N: int, dtype_in, dtype_quant):
    torch.manual_seed(20)
    x = torch.randn((M, N), dtype=dtype_in, device="cuda")

    torch_out, torch_scale_out = torch_dynamic_per_tensor_quant_fp8_i8(x, dtype_quant)

    triton_out = torch.empty_like(x, dtype=dtype_quant, device="cuda")
    triton_scale_out = torch.zeros(1, dtype=torch.float32, device="cuda")
    triton_out, triton_scale_out = dynamic_per_tensor_quant_fp8_i8(
        triton_out, x, triton_scale_out
    )

    torch.testing.assert_close(
        triton_scale_out,
        torch_scale_out,
        atol=1e-01,
        rtol=1e-01,
    )

    # Note: Torch doesn't support comparing fp8 type yet
    torch.testing.assert_close(
        triton_out.to(dtype=torch.float32),
        torch_out.to(dtype=torch.float32),
        atol=1e-01,
        rtol=1e-01,
    )


def torch_dynamic_per_token_quant_fp8_i8(x, dtype_quant):
    x_max, _ = torch.max(torch.abs(x), axis=-1)
    dtype_max = (
        torch.iinfo(dtype_quant).max
        if dtype_quant == torch.int8
        else torch.finfo(dtype_quant).max
    )
    scale_out = x_max.to(torch.float32).clamp(min=1.0e-10) / dtype_max

    scale_recip = 1 / scale_out[:, None]
    out = x * scale_recip
    if dtype_quant == torch.int8:
        out = out.round()
    out = out.to(dtype_quant)

    return out, scale_out


@pytest.mark.parametrize("M, N", [(2, 128), (257, 128), (1281, 1232)])
@pytest.mark.parametrize("dtype_quant", [torch.int8, get_fp8_e4m3_dtype()])
def test_dynamic_per_token_quant_zero_rows(M: int, N: int, dtype_quant):
    """Zero rows stay finite on the 1-D, N=128, and four-row paths."""
    torch.manual_seed(20)
    x = torch.randn((M, N), dtype=torch.bfloat16, device="cuda")
    zero_rows = torch.tensor(
        sorted({0, M // 2, M - 1}), dtype=torch.long, device="cuda"
    )
    x[zero_rows] = 0

    torch_out, torch_scale_out = torch_dynamic_per_token_quant_fp8_i8(
        x, dtype_quant
    )
    triton_out = torch.empty_like(x, dtype=dtype_quant)
    triton_scale_out = torch.empty(M, dtype=torch.float32, device="cuda")
    dynamic_per_token_quant_fp8_i8(triton_out, x, triton_scale_out)

    assert torch.isfinite(triton_scale_out).all()
    assert torch.isfinite(triton_out.float()).all()
    torch.testing.assert_close(triton_scale_out, torch_scale_out)
    torch.testing.assert_close(
        triton_out[zero_rows].float(), torch_out[zero_rows].float()
    )


@pytest.mark.parametrize("tensor_name", ["x_in", "qx", "scale_out"])
def test_dynamic_per_token_quant_rejects_noncontiguous_tensors(tensor_name):
    x = torch.randn((4, 128), dtype=torch.float16, device="cuda")
    triton_out = torch.empty(x.shape, dtype=get_fp8_e4m3_dtype(), device="cuda")
    triton_scale_out = torch.empty(4, dtype=torch.float32, device="cuda")
    if tensor_name == "x_in":
        x = torch.randn((4, 256), dtype=x.dtype, device=x.device)[:, ::2]
    elif tensor_name == "qx":
        triton_out = torch.empty(
            (4, 256), dtype=triton_out.dtype, device=triton_out.device
        )[:, ::2]
    else:
        triton_scale_out = torch.empty(
            8, dtype=triton_scale_out.dtype, device=triton_scale_out.device
        )[::2]

    with pytest.raises(AssertionError, match=f"{tensor_name} must be contiguous"):
        dynamic_per_token_quant_fp8_i8(triton_out, x, triton_scale_out)


def _int8_rounding_input(rows, cols):
    values = torch.zeros((rows, cols), device="cuda", dtype=torch.float16)
    values[:, :6] = torch.tensor(
        [0.5, -0.5, 1.5, -1.5, 126.5, 127.0],
        device="cuda",
        dtype=torch.float16,
    )
    return values


@pytest.mark.parametrize("M, N", [(1, 8), (256, 128)])
def test_dynamic_per_token_int8_rounds_to_nearest(M, N):
    x = _int8_rounding_input(M, N)
    triton_out = torch.empty_like(x, dtype=torch.int8)
    triton_scale_out = torch.empty(M, dtype=torch.float32, device="cuda")

    dynamic_per_token_quant_fp8_i8(triton_out, x, triton_scale_out)

    torch.testing.assert_close(triton_scale_out, torch.ones_like(triton_scale_out))
    torch.testing.assert_close(triton_out, x.round().to(torch.int8))


def test_dynamic_per_token_int8_tiled_path_rounds_to_nearest():
    num_cus = torch.cuda.get_device_properties("cuda").multi_processor_count
    M = max(1025, 16 * num_cus)
    x = _int8_rounding_input(M, 8)
    triton_out = torch.empty_like(x, dtype=torch.int8)
    triton_scale_out = torch.empty(M, dtype=torch.float32, device="cuda")

    dynamic_per_token_quant_fp8_i8(triton_out, x, triton_scale_out)

    torch.testing.assert_close(triton_scale_out, torch.ones_like(triton_scale_out))
    torch.testing.assert_close(triton_out, x.round().to(torch.int8))


def test_dynamic_per_token_fp8_keeps_fractional_values():
    x = torch.tensor(
        [[0.5, 1.5, 2.5, 448.0]], device="cuda", dtype=torch.float16
    )
    triton_out = torch.empty_like(x, dtype=get_fp8_e4m3_dtype())
    triton_scale_out = torch.empty(1, dtype=torch.float32, device="cuda")

    dynamic_per_token_quant_fp8_i8(triton_out, x, triton_scale_out)

    torch.testing.assert_close(triton_scale_out, torch.ones_like(triton_scale_out))
    torch.testing.assert_close(triton_out.float(), x.float())


def test_static_per_tensor_int8_rounds_to_nearest():
    x = _int8_rounding_input(2, 8)
    triton_out = torch.empty_like(x, dtype=torch.int8)
    scale = torch.ones(1, dtype=torch.float32, device="cuda")

    static_per_tensor_quant_fp8_i8(triton_out, x, scale)

    torch.testing.assert_close(triton_out, x.round().to(torch.int8))


def test_pertoken_quant_int8_rounds_to_nearest():
    x = _int8_rounding_input(2, 8)
    scale = torch.ones((2, 1), dtype=torch.float32, device="cuda")

    quantized, actual_scale = pertoken_quant(x, scale=scale, quant_dtype=torch.int8)

    torch.testing.assert_close(actual_scale, scale)
    torch.testing.assert_close(quantized, x.round().to(torch.int8))


@pytest.mark.parametrize("M, N", [(2, 128), (257, 128), (1281, 1232)])
@pytest.mark.parametrize("dtype_in", [torch.float16, torch.bfloat16])
@pytest.mark.parametrize("dtype_quant", [torch.int8, get_fp8_e4m3_dtype()])
def test_per_token_quant_triton_public_api(M, N, dtype_in, dtype_quant):
    torch.manual_seed(20)
    x = torch.randn((M, N), dtype=dtype_in, device="cuda")
    x[0] = 0

    torch_out, torch_scale = torch_dynamic_per_token_quant_fp8_i8(x, dtype_quant)
    triton_out, triton_scale = per_token_quant_triton(x, quant_dtype=dtype_quant)

    assert torch.isfinite(triton_out.float()).all()
    assert torch.isfinite(triton_scale).all()
    torch.testing.assert_close(triton_scale, torch_scale.reshape(M, 1))
    torch_error = (
        torch_out.float() * torch_scale.reshape(M, 1) - x.float()
    ).abs()
    triton_error = (triton_out.float() * triton_scale - x.float()).abs()
    quant_step = 1 if dtype_quant == torch.int8 else 32
    assert triton_error.mean() <= torch_error.mean() + 1.0e-6
    assert (
        triton_error.max()
        <= torch_error.max() + triton_scale.max() * quant_step
    )


@pytest.mark.parametrize(
    "M, N",
    [
        (256, 13),
        (2, 16),
        (1, 32),
        (32, 32),
        (192, 96),
        (1024, 128),
        (48, 96),
        (400, 400),
        (32, 4096),
    ],
)
@pytest.mark.parametrize("dtype_in", [torch.float16, torch.bfloat16, torch.float32])
@pytest.mark.parametrize("dtype_quant", [torch.int8, get_fp8_e4m3_dtype()])
def test_dynamic_per_token_quant(M: int, N: int, dtype_in, dtype_quant):
    torch.manual_seed(20)
    torch.set_printoptions(precision=7, threshold=4000)
    x = torch.rand((M, N), dtype=dtype_in, device="cuda")

    torch_out, torch_scale_out = torch_dynamic_per_token_quant_fp8_i8(x, dtype_quant)

    triton_scale_out = torch.zeros(M, dtype=torch.float32, device="cuda")
    triton_out = torch.empty_like(x, dtype=dtype_quant, device="cuda")
    triton_out, triton_scale_out = dynamic_per_token_quant_fp8_i8(
        triton_out, x, triton_scale_out
    )

    if DEBUG:
        print(f"Torch_Scale={torch_scale_out}")
        print(f"Triton_Scale={triton_scale_out}")

        print(f"x={x}")
        print(f"Torch_out={torch_out}")
        print(f"Triton_out={triton_out}")

    torch.testing.assert_close(
        triton_scale_out,
        torch_scale_out,
        atol=1e-01,
        rtol=1e-01,
    )

    # Note: Torch doesn't support comparing fp8 type yet
    torch.testing.assert_close(
        triton_out.to(dtype=torch.float32),
        torch_out.to(dtype=torch.float32),
        atol=1e-01,
        rtol=1e-01,
    )


@pytest.mark.parametrize(
    "M, N",
    [
        (257, 128),
        (1025, 1232),
        (4480, 1232),
        (4480, 1536),
        (4480, 2048),
        (8960, 2048),
        (12800, 2048),
    ],
)
def test_dynamic_per_token_quant_dispatch(M: int, N: int):
    """Cover the specialized and CU-scaled dispatch paths used by MoE."""
    torch.manual_seed(20)
    x = torch.rand((M, N), dtype=torch.float16, device="cuda")
    dtype_quant = get_fp8_e4m3_dtype()

    torch_out, torch_scale_out = torch_dynamic_per_token_quant_fp8_i8(x, dtype_quant)
    triton_out = torch.empty_like(x, dtype=dtype_quant, device="cuda")
    triton_scale_out = torch.empty(M, dtype=torch.float32, device="cuda")
    dynamic_per_token_quant_fp8_i8(triton_out, x, triton_scale_out)

    torch.testing.assert_close(
        triton_scale_out,
        torch_scale_out,
        atol=1e-01,
        rtol=1e-01,
    )
    torch.testing.assert_close(
        triton_out.to(dtype=torch.float32),
        torch_out.to(dtype=torch.float32),
        atol=1e-01,
        rtol=1e-01,
    )
