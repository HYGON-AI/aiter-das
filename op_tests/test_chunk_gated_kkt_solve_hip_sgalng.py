# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""HIP SGLang KKT-solve tests against the Triton SGLang reference.

Run from the repository root:

    TRITON_CACHE_DIR=./cache PYTHONPATH=. pytest op_tests/test_chunk_gated_kkt_solve_hip_sgalng.py

The standalone KKT solve returns only the solved ``A`` tensor with shape
``[B, T, H, chunk_size]``. Gate values are intentionally not limited to tiny
random numbers; the suite includes larger negative cumulative-style gates that
cover the NaN/dump regressions seen in SGLang traces.
"""

from __future__ import annotations

from dataclasses import dataclass, replace
import pytest
import torch

import aiter
from aiter.ops.triton.fla.sglang.chunk_fwd import (
    chunk_gated_delta_rule_fwd_kkt_solve as triton_kkt_solve,
    prepare_chunk_indices,
)
from op_tests.chunk_gated_coverage import (
    CoverageShape,
    DTYPES,
    LONG_STRESS_SHAPES,
    MODEL_SHAPES,
    SHORT_MEDIUM_SHAPES,
)


GATE_MODES = [
    "random",
    "logsigmoid",
    "linear_negative",
    "dump_like_cumsum",
    "dump_like_block_cliff",
]

STRESS_GATE_MODES = [
    "random",
    "linear_negative",
]

COVERAGE_GATE_MODES = [
    "random",
    "linear_negative",
]

DENSE_BATCH_SHAPES = [
    (2, 64, 4, 2, torch.float16),
    (2, 65, 4, 2, torch.bfloat16),
    (3, 128, 8, 4, torch.float16),
    (4, 130, 8, 4, torch.bfloat16),
    (2, 256, 8, 8, torch.bfloat16),
    (3, 512, 16, 4, torch.float16),
]

DUMP_LIKE_SPECS = [
    (43, 2082.0),
    (80, 5861.0),
    (81, 5861.0),
]

NO_GATE_SHORT_MEDIUM_SPECS = [
    (SHORT_MEDIUM_SHAPES[0], torch.float16),
    (SHORT_MEDIUM_SHAPES[3], torch.bfloat16),
    (SHORT_MEDIUM_SHAPES[5], torch.bfloat16),
    (SHORT_MEDIUM_SHAPES[7], torch.float16),
]

@dataclass(frozen=True)
class KktSolveCase:
    batch: int = 1
    seqlen: int = 130
    valid_seqlen: int | None = None
    heads: int = 4
    grouped_heads: int = 2
    k_dim: int = 128
    chunk_size: int = 64
    dtype: torch.dtype = torch.float16
    beta_dtype: torch.dtype | None = torch.float32
    input_scale: float = 0.02
    beta_scale: float = 0.2
    beta_mode: str = "normal"
    g_scale: float = 0.5
    g_min: float = -128.0
    g_mode: str = "random"
    varlen: bool = False
    cu_mode: str = "multi"
    seq_count: int | None = None
    seq_len_each: int | None = None
    use_g: bool = True
    seed: int = 47

    @property
    def compare_seqlen(self) -> int:
        return self.valid_seqlen or self.seqlen


def _multi_split_cu_seqlens(seqlen: int, device: torch.device) -> torch.Tensor:
    return torch.tensor(
        [0, max(1, seqlen // 3), max(2, (2 * seqlen) // 3), seqlen],
        device=device,
        dtype=torch.long,
    )


def _build_gate(case: KktSolveCase, device: torch.device) -> torch.Tensor | None:
    if not case.use_g:
        return None

    shape = (case.batch, case.seqlen, case.heads)
    if case.g_mode == "random":
        return (
            torch.randn(shape, device=device, dtype=torch.float32) * case.g_scale
        ).contiguous()

    if case.g_mode == "logsigmoid":
        raw = (
            torch.randn(shape, device=device, dtype=torch.float32)
            * max(case.g_scale, 1.0)
        )
        return torch.nn.functional.logsigmoid(raw).contiguous()

    if case.g_mode == "linear_negative":
        if case.seqlen <= 1:
            base = torch.zeros((case.seqlen,), device=device, dtype=torch.float32)
        else:
            base = torch.linspace(0.0, case.g_min, case.seqlen, device=device)
        jitter = torch.rand(shape, device=device, dtype=torch.float32) * case.g_scale
        return (base.view(1, case.seqlen, 1) - jitter).clamp_max(0.0).contiguous()

    if case.g_mode == "dump_like_cumsum":
        steps = torch.rand(shape, device=device, dtype=torch.float32)
        steps = -steps * (abs(case.g_min) / max(case.seqlen, 1)) * 0.2
        cliff_mask = torch.rand_like(steps) < 0.12
        cliffs = -torch.rand_like(steps) * abs(case.g_min) * 0.25
        steps = steps + torch.where(cliff_mask, cliffs, torch.zeros_like(cliffs))
        g = torch.cumsum(steps, dim=1)
        min_abs = (-g.amin(dim=1, keepdim=True)).clamp_min(1.0e-6)
        target = abs(case.g_min) * (
            0.35
            + 0.65
            * torch.rand(
                (case.batch, 1, case.heads),
                device=device,
                dtype=torch.float32,
            )
        )
        g = g * (target / min_abs)
        g = g - g.amax(dim=1, keepdim=True)
        tail = torch.rand((case.batch, 1, case.heads), device=device) * 1.0e-3
        return (g - tail).contiguous()

    if case.g_mode == "dump_like_block_cliff":
        g = torch.zeros(shape, device=device, dtype=torch.float32)
        for boundary in (16, 32, 48, 64):
            if boundary >= case.seqlen:
                continue
            drop = (
                torch.rand((case.batch, 1, case.heads), device=device)
                * abs(case.g_min)
                * 0.35
            )
            g[:, boundary:, :] -= drop
        noise = -torch.rand_like(g) * (abs(case.g_min) / max(case.seqlen, 1)) * 0.05
        g = g + torch.cumsum(noise, dim=1)
        min_abs = (-g.amin(dim=1, keepdim=True)).clamp_min(1.0e-6)
        g = g * (abs(case.g_min) / min_abs)
        g = g - g.amax(dim=1, keepdim=True)
        tail = torch.rand((case.batch, 1, case.heads), device=device) * 1.0e-3
        return (g - tail).contiguous()

    raise ValueError(f"unsupported g_mode: {case.g_mode}")


def _build_case(case: KktSolveCase) -> dict[str, object]:
    torch.manual_seed(case.seed)
    device = torch.device("cuda")

    k = (
        torch.randn(
            (case.batch, case.seqlen, case.grouped_heads, case.k_dim),
            device=device,
            dtype=case.dtype,
        )
        * case.input_scale
    ).contiguous()

    beta_dtype = case.beta_dtype or case.dtype
    beta_random = torch.randn(
        (case.batch, case.seqlen, case.heads),
        device=device,
        dtype=beta_dtype,
    )
    if case.beta_mode == "normal":
        beta = beta_random * case.beta_scale
    elif case.beta_mode == "sigmoid":
        beta = torch.sigmoid(beta_random).to(dtype=beta_dtype)
    else:
        raise ValueError(f"unsupported beta_mode: {case.beta_mode}")
    beta = beta.contiguous()

    cu_seqlens = None
    chunk_indices = None
    if case.varlen:
        if case.batch != 1:
            raise ValueError("SGLang varlen KKT tests use batch=1 packed inputs")
        if case.cu_mode == "captured":
            if case.seq_count is None or case.seq_len_each is None:
                raise ValueError("captured cu_mode requires seq_count and seq_len_each")
            cu_end = case.seq_count * case.seq_len_each
            if cu_end != case.compare_seqlen:
                raise ValueError(
                    f"captured cu_seqlens ends at {cu_end}, expected {case.compare_seqlen}"
                )
            cu_seqlens = torch.arange(
                case.seq_count + 1,
                device=device,
                dtype=torch.long,
            ) * case.seq_len_each
        elif case.cu_mode == "single":
            cu_seqlens = torch.tensor(
                [0, case.compare_seqlen], device=device, dtype=torch.long
            )
        elif case.cu_mode == "multi":
            cu_seqlens = _multi_split_cu_seqlens(case.compare_seqlen, device)
        else:
            raise ValueError(f"unsupported cu_mode: {case.cu_mode}")
        chunk_indices = prepare_chunk_indices(cu_seqlens, case.chunk_size)

    return {
        "k": k,
        "beta": beta,
        "g": _build_gate(case, device),
        "cu_seqlens": cu_seqlens,
        "chunk_indices": chunk_indices,
    }


def _run_hip(case: KktSolveCase, tensors: dict[str, object]) -> torch.Tensor:
    return aiter.chunk_gated_delta_rule_fwd_kkt_solve_hip(
        k=tensors["k"],
        beta=tensors["beta"],
        g=tensors["g"],
        cu_seqlens=tensors["cu_seqlens"],
        chunk_size=case.chunk_size,
        chunk_indices=tensors["chunk_indices"],
    )


def _run_triton(case: KktSolveCase, tensors: dict[str, object]) -> torch.Tensor:
    cu_seqlens = tensors["cu_seqlens"]
    chunk_indices = tensors["chunk_indices"]
    if isinstance(cu_seqlens, torch.Tensor) and (
        chunk_indices is None
        or (isinstance(chunk_indices, torch.Tensor) and chunk_indices.numel() == 0)
    ):
        chunk_indices = prepare_chunk_indices(cu_seqlens, case.chunk_size)

    return triton_kkt_solve(
        k=tensors["k"],
        g=tensors["g"],
        beta=tensors["beta"],
        cu_seqlens=cu_seqlens,
        chunk_size=case.chunk_size,
        chunk_indices=chunk_indices,
    )


def _tolerances(dtype: torch.dtype) -> tuple[float, float]:
    if dtype == torch.float16:
        return 6e-2, 6e-2
    if dtype == torch.bfloat16:
        return 8e-2, 8e-2
    raise AssertionError(f"unexpected dtype: {dtype}")


def _assert_case_close(
    case: KktSolveCase,
    tensors: dict[str, object],
    *,
    repeats: int = 1,
    valid_seqlen: int | None = None,
) -> None:
    rtol, atol = _tolerances(case.dtype)
    compare_seqlen = valid_seqlen or case.compare_seqlen
    for _ in range(repeats):
        a_hip = _run_hip(case, tensors)
        a_tri = _run_triton(case, tensors)
        torch.cuda.synchronize()

        a_hip = a_hip[:, :compare_seqlen]
        a_tri = a_tri[:, :compare_seqlen]

        assert a_hip.shape == a_tri.shape
        assert a_hip.dtype == a_tri.dtype == case.dtype
        assert torch.isfinite(a_hip.float()).all()
        assert torch.isfinite(a_tri.float()).all()
        torch.testing.assert_close(
            a_hip, a_tri, rtol=rtol, atol=atol, equal_nan=False
        )


def _apply_varlen_index_dtypes(
    tensors: dict[str, object],
    *,
    cu_dtype: torch.dtype,
    indices_dtype: torch.dtype,
    chunk_size: int,
) -> None:
    cu = tensors["cu_seqlens"]
    assert isinstance(cu, torch.Tensor)
    cu = cu.to(dtype=cu_dtype)
    tensors["cu_seqlens"] = cu
    tensors["chunk_indices"] = prepare_chunk_indices(cu, chunk_size).to(
        dtype=indices_dtype
    )


def _build_coverage_case(
    shape: CoverageShape,
    *,
    dtype: torch.dtype,
    g_mode: str,
) -> tuple[KktSolveCase, dict[str, object]]:
    case = KktSolveCase(
        seqlen=shape.buf_seqlen or shape.seqlen,
        valid_seqlen=shape.seqlen if shape.buf_seqlen is not None else None,
        heads=shape.heads,
        grouped_heads=shape.grouped_heads,
        dtype=dtype,
        input_scale=0.001 if shape.seqlen >= 2048 else 0.01,
        g_mode=g_mode,
        g_min=-512.0 if g_mode != "random" else -128.0,
        varlen=shape.varlen,
        cu_mode="single" if shape.buf_seqlen is not None else "multi",
    )
    return case, _build_case(case)


@pytest.mark.parametrize(
    "case",
    [
        pytest.param(
            KktSolveCase(
                seqlen=16,
                heads=4,
                grouped_heads=2,
                dtype=torch.float16,
                g_mode="logsigmoid",
            ),
            id="short_less_than_chunk_fp16",
        ),
        pytest.param(
            KktSolveCase(
                seqlen=32,
                heads=4,
                grouped_heads=2,
                dtype=torch.bfloat16,
                g_mode="linear_negative",
                g_min=-128.0,
            ),
            id="short_half_chunk_bf16_large_g",
        ),
        pytest.param(
            KktSolveCase(seqlen=64, heads=4, grouped_heads=2, dtype=torch.float16),
            id="aligned_one_chunk_fp16",
        ),
        pytest.param(
            KktSolveCase(seqlen=65, heads=4, grouped_heads=2, dtype=torch.float16),
            id="tail_one_token_fp16",
        ),
        pytest.param(
            KktSolveCase(
                seqlen=130,
                heads=4,
                grouped_heads=2,
                dtype=torch.bfloat16,
                varlen=True,
            ),
            id="varlen_tail_bf16",
        ),
    ],
)
def test_kkt_solve_boundary_cases_match_triton_sglang(
    case: KktSolveCase,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize(
    "case",
    [
        pytest.param(KktSolveCase(seqlen=65, use_g=False), id="without_g"),
        pytest.param(
            KktSolveCase(seqlen=65, beta_dtype=None),
            id="beta_same_dtype_as_k",
        ),
    ],
)
def test_kkt_solve_optional_arguments_match_triton_sglang(
    case: KktSolveCase,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("use_varlen", [False, True])
@pytest.mark.parametrize("use_g", [False, True])
@pytest.mark.parametrize("dtype", DTYPES)
def test_kkt_solve_matches_triton_sglang(
    use_varlen: bool,
    use_g: bool,
    dtype: torch.dtype,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(dtype=dtype, varlen=use_varlen, use_g=use_g)
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("g_mode", GATE_MODES)
def test_kkt_solve_gate_ranges_match_triton_sglang(
    g_mode: str,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(
        seqlen=80,
        heads=16,
        grouped_heads=8,
        dtype=torch.bfloat16,
        g_mode=g_mode,
        g_min=-1024.0,
    )
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("cu_dtype", [torch.int32, torch.int64])
@pytest.mark.parametrize("indices_dtype", [torch.int32, torch.int64])
def test_kkt_solve_varlen_index_dtypes_sglang(
    cu_dtype: torch.dtype,
    indices_dtype: torch.dtype,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(dtype=torch.float16, varlen=True)
    tensors = _build_case(case)
    _apply_varlen_index_dtypes(
        tensors,
        cu_dtype=cu_dtype,
        indices_dtype=indices_dtype,
        chunk_size=case.chunk_size,
    )
    assert tensors["cu_seqlens"].dtype == cu_dtype
    assert tensors["chunk_indices"].dtype == indices_dtype
    _assert_case_close(case, tensors)


def test_kkt_solve_rebuilds_empty_chunk_indices_sglang() -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(dtype=torch.float16, varlen=True)
    tensors = _build_case(case)
    tensors["chunk_indices"] = torch.empty(
        (0, 2), device=torch.device("cuda"), dtype=torch.long
    )
    _assert_case_close(case, tensors)


@pytest.mark.parametrize("g_mode", COVERAGE_GATE_MODES)
@pytest.mark.parametrize("shape", SHORT_MEDIUM_SHAPES)
@pytest.mark.parametrize("dtype", DTYPES)
def test_kkt_solve_coverage_short_medium_sglang(
    g_mode: str,
    shape: CoverageShape,
    dtype: torch.dtype,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case, tensors = _build_coverage_case(shape, dtype=dtype, g_mode=g_mode)
    _assert_case_close(case, tensors)


@pytest.mark.parametrize("g_mode", STRESS_GATE_MODES)
@pytest.mark.parametrize("shape", LONG_STRESS_SHAPES)
def test_kkt_solve_coverage_long_stress_sglang(
    g_mode: str,
    shape: CoverageShape,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case, tensors = _build_coverage_case(
        shape,
        dtype=torch.float16,
        g_mode=g_mode,
    )
    _assert_case_close(case, tensors, repeats=2, valid_seqlen=shape.seqlen)


@pytest.mark.parametrize("shape,dtype", NO_GATE_SHORT_MEDIUM_SPECS)
def test_kkt_solve_coverage_short_medium_no_gate_sglang(
    shape: CoverageShape,
    dtype: torch.dtype,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(
        seqlen=shape.buf_seqlen or shape.seqlen,
        valid_seqlen=shape.seqlen if shape.buf_seqlen is not None else None,
        heads=shape.heads,
        grouped_heads=shape.grouped_heads,
        dtype=dtype,
        varlen=shape.varlen,
        cu_mode="single" if shape.buf_seqlen is not None else "multi",
        use_g=False,
    )
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("g_mode", COVERAGE_GATE_MODES)
@pytest.mark.parametrize("batch,seqlen,heads,grouped_heads,dtype", DENSE_BATCH_SHAPES)
def test_kkt_solve_coverage_batch_dense_sglang(
    g_mode: str,
    batch: int,
    seqlen: int,
    heads: int,
    grouped_heads: int,
    dtype: torch.dtype,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(
        batch=batch,
        seqlen=seqlen,
        heads=heads,
        grouped_heads=grouped_heads,
        dtype=dtype,
        input_scale=0.001 if seqlen >= 256 else 0.01,
        g_mode=g_mode,
        g_min=-512.0 if g_mode == "linear_negative" else -128.0,
    )
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("batch,seqlen,heads,grouped_heads,dtype", DENSE_BATCH_SHAPES)
def test_kkt_solve_coverage_batch_dense_no_gate_sglang(
    batch: int,
    seqlen: int,
    heads: int,
    grouped_heads: int,
    dtype: torch.dtype,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(
        batch=batch,
        seqlen=seqlen,
        heads=heads,
        grouped_heads=grouped_heads,
        dtype=dtype,
        input_scale=0.001 if seqlen >= 256 else 0.01,
        use_g=False,
    )
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("varlen", [False, True])
@pytest.mark.parametrize(
    "case",
    [
        pytest.param(
            KktSolveCase(
                seqlen=43,
                heads=16,
                grouped_heads=8,
                dtype=torch.bfloat16,
                input_scale=0.2,
                beta_mode="sigmoid",
                g_mode="linear_negative",
            ),
            id="T43_bf16",
        ),
        pytest.param(
            KktSolveCase(
                seqlen=80,
                heads=16,
                grouped_heads=8,
                dtype=torch.bfloat16,
                input_scale=0.2,
                beta_mode="sigmoid",
                g_mode="linear_negative",
            ),
            id="T80_bf16",
        ),
    ],
)
def test_kkt_solve_benchmark_nan_repro_sglang(
    case: KktSolveCase,
    varlen: bool,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = replace(case, varlen=varlen, cu_mode="single")
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("varlen", [False, True])
@pytest.mark.parametrize("g_mode", ["dump_like_cumsum", "dump_like_block_cliff"])
@pytest.mark.parametrize("seqlen,g_min_abs", DUMP_LIKE_SPECS)
def test_kkt_solve_benchmark_dump_like_sglang(
    varlen: bool,
    g_mode: str,
    seqlen: int,
    g_min_abs: float,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(
        seqlen=seqlen,
        heads=16,
        grouped_heads=8,
        dtype=torch.bfloat16,
        input_scale=0.09,
        beta_mode="sigmoid",
        g_mode=g_mode,
        g_min=-g_min_abs,
        varlen=varlen,
        cu_mode="single",
        seed=1701 + seqlen + int(varlen) * 17,
    )
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("dtype", DTYPES)
def test_kkt_solve_benchmark_captured_input_size_sglang(dtype: torch.dtype) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(
        seqlen=38912,
        heads=32,
        grouped_heads=16,
        dtype=dtype,
        input_scale=0.02,
        g_scale=0.02,
        varlen=True,
        cu_mode="captured",
        seq_count=32,
        seq_len_each=1216,
    )
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("seqlen,_state_index", MODEL_SHAPES)
def test_kkt_solve_coverage_model_shape_sglang(
    seqlen: int,
    _state_index: int,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(
        seqlen=seqlen,
        heads=8,
        grouped_heads=2,
        dtype=torch.bfloat16,
        input_scale=0.001,
        g_mode="dump_like_cumsum",
        g_min=-2048.0,
        varlen=True,
        cu_mode="single",
    )
    _assert_case_close(case, _build_case(case), repeats=2)


def test_kkt_solve_extreme_gate_regression_sglang() -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(
        seqlen=80,
        heads=16,
        grouped_heads=8,
        dtype=torch.bfloat16,
        g_mode="linear_negative",
        g_min=-5861.0,
        varlen=True,
    )
    _assert_case_close(case, _build_case(case), repeats=3)


def test_kkt_solve_rejects_fp32_input() -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(seqlen=64, dtype=torch.float32, beta_dtype=torch.float32)
    with pytest.raises(RuntimeError, match="k must be fp16 or bf16"):
        _run_hip(case, _build_case(case))


def test_kkt_solve_rejects_non_fp32_g() -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = KktSolveCase(seqlen=64, dtype=torch.float16)
    tensors = _build_case(case)
    tensors["g"] = tensors["g"].to(case.dtype)
    with pytest.raises(RuntimeError, match="g must be fp32"):
        _run_hip(case, tensors)


if __name__ == "__main__":
    raise SystemExit(pytest.main([__file__, "-q"]))
