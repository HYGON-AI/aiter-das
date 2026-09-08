# SPDX-License-Identifier: MIT
"""HIP chunk_fwd_o tests against the Triton vLLM implementation.

Run from the repository root:

    TRITON_CACHE_DIR=./cache PYTHONPATH=. pytest op_tests/test_chunk_fwd_o_hip_vllm.py

These tests use ``aiter.ops.triton.fla.vllm.chunk_o.chunk_fwd_o`` as the
reference, matching the validation style of ``test_chunk_gated_hip_vllm.py``.
"""

from __future__ import annotations

from dataclasses import dataclass

import pytest
import torch

import aiter
from aiter.ops.triton.fla.vllm.chunk_o import (
    chunk_fwd_o as triton_chunk_fwd_o,
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
    (True, False),
    (True, True),
    (False, True),
]


@dataclass(frozen=True)
class ChunkFwdOCase:
    batch: int = 1
    seqlen: int = 130
    heads: int = 16
    grouped_heads: int = 8
    k_dim: int = 128
    v_dim: int = 128
    chunk_size: int = 64
    dtype: torch.dtype = torch.float16
    input_scale: float = 0.01
    g_scale: float = 0.01
    state_scale: float = 0.01
    varlen: bool = False
    use_g: bool = True
    use_g_gamma: bool = False
    use_exp2: bool = False
    transpose_state_layout: bool = True


def _cdiv(a: int, b: int) -> int:
    return (a + b - 1) // b


def _multi_split_cu_seqlens(seqlen: int, device: torch.device) -> torch.Tensor:
    return torch.tensor(
        [0, max(1, seqlen // 3), max(2, (2 * seqlen) // 3), seqlen],
        device=device,
        dtype=torch.long,
    )


def _build_case(case: ChunkFwdOCase) -> dict[str, object]:
    torch.manual_seed(42)
    device = torch.device("cuda")

    q = torch.randn(
        (case.batch, case.seqlen, case.grouped_heads, case.k_dim),
        device=device,
        dtype=case.dtype,
    ) * case.input_scale
    k = torch.randn(
        (case.batch, case.seqlen, case.grouped_heads, case.k_dim),
        device=device,
        dtype=case.dtype,
    ) * case.input_scale
    v = torch.randn(
        (case.batch, case.seqlen, case.heads, case.v_dim),
        device=device,
        dtype=case.dtype,
    ) * case.input_scale

    cu_seqlens = None
    chunk_indices = None
    if case.varlen:
        if case.batch != 1:
            raise ValueError("varlen test cases use batch=1 flattened tokens")
        cu_seqlens = _multi_split_cu_seqlens(case.seqlen, device)
        chunk_indices = prepare_chunk_indices(cu_seqlens, case.chunk_size)

    n_chunks = (
        int(chunk_indices.shape[0])
        if chunk_indices is not None
        else _cdiv(case.seqlen, case.chunk_size)
    )
    if case.transpose_state_layout:
        h_shape = (case.batch, n_chunks, case.heads, case.v_dim, case.k_dim)
    else:
        h_shape = (case.batch, n_chunks, case.heads, case.k_dim, case.v_dim)
    h = torch.randn(h_shape, device=device, dtype=case.dtype) * case.state_scale

    g = torch.randn(
        (case.batch, case.seqlen, case.heads),
        device=device,
        dtype=torch.float32,
    ) * case.g_scale
    if not case.use_g:
        g = None

    g_gamma = torch.randn(
        (case.heads,),
        device=device,
        dtype=torch.float32,
    ) * case.g_scale
    if not case.use_g_gamma:
        g_gamma = None

    return {
        "q": q,
        "k": k,
        "v": v,
        "h": h,
        "g": g,
        "g_gamma": g_gamma,
        "cu_seqlens": cu_seqlens,
        "chunk_indices": chunk_indices,
    }


def _run_hip(case: ChunkFwdOCase, tensors: dict[str, object]) -> torch.Tensor:
    return aiter.chunk_fwd_o_vllm_hip_blockdim64(
        q=tensors["q"],
        k=tensors["k"],
        v=tensors["v"],
        h=tensors["h"],
        g=tensors["g"],
        g_gamma=tensors["g_gamma"],
        scale=case.k_dim ** -0.5,
        cu_seqlens=tensors["cu_seqlens"],
        chunk_size=case.chunk_size,
        chunk_indices=tensors["chunk_indices"],
        use_exp2=case.use_exp2,
        transpose_state_layout=case.transpose_state_layout,
    )


def _run_triton(case: ChunkFwdOCase, tensors: dict[str, object]) -> torch.Tensor:
    return triton_chunk_fwd_o(
        q=tensors["q"],
        k=tensors["k"],
        v=tensors["v"],
        h=tensors["h"],
        g=tensors["g"],
        g_gamma=tensors["g_gamma"],
        scale=case.k_dim ** -0.5,
        cu_seqlens=tensors["cu_seqlens"],
        chunk_size=case.chunk_size,
        chunk_indices=tensors["chunk_indices"],
        use_exp2=case.use_exp2,
        transpose_state_layout=case.transpose_state_layout,
    )


def _tolerances(dtype: torch.dtype) -> tuple[float, float]:
    if dtype == torch.float16:
        return 6e-2, 6e-2
    if dtype == torch.bfloat16:
        return 8e-2, 8e-2
    raise AssertionError(f"unexpected dtype: {dtype}")


def _assert_case_close(
    case: ChunkFwdOCase,
    tensors: dict[str, object],
    *,
    repeats: int = 1,
    valid_seqlen: int | None = None,
) -> None:
    rtol, atol = _tolerances(case.dtype)
    for _ in range(repeats):
        o_hip = _run_hip(case, tensors)
        o_tri = _run_triton(case, tensors)
        torch.cuda.synchronize()

        if valid_seqlen is not None:
            o_hip = o_hip[:, :valid_seqlen]
            o_tri = o_tri[:, :valid_seqlen]

        torch.testing.assert_close(
            o_hip, o_tri, rtol=rtol, atol=atol, equal_nan=True
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
    indices = prepare_chunk_indices(cu, chunk_size).to(dtype=indices_dtype)
    tensors["cu_seqlens"] = cu
    tensors["chunk_indices"] = indices


def _override_vllm_varlen_tensors(
    tensors: dict[str, object],
    *,
    shape: CoverageShape,
    chunk_size: int,
    device: torch.device,
) -> None:
    if not shape.varlen:
        return
    if shape.buf_seqlen is not None:
        cu_seqlens = torch.tensor([0, shape.seqlen], device=device, dtype=torch.long)
    else:
        cu_seqlens = _multi_split_cu_seqlens(shape.seqlen, device)
    tensors["cu_seqlens"] = cu_seqlens
    tensors["chunk_indices"] = prepare_chunk_indices(cu_seqlens, chunk_size)


def _build_coverage_case(
    shape: CoverageShape,
    *,
    dtype: torch.dtype,
    use_g: bool,
    use_g_gamma: bool,
) -> tuple[ChunkFwdOCase, dict[str, object]]:
    buf_seqlen = shape.buf_seqlen or shape.seqlen
    case = ChunkFwdOCase(
        seqlen=buf_seqlen,
        heads=shape.heads,
        grouped_heads=shape.grouped_heads,
        dtype=dtype,
        input_scale=0.01,
        g_scale=0.01,
        state_scale=0.01,
        varlen=shape.varlen,
        use_g=use_g,
        use_g_gamma=use_g_gamma,
    )
    tensors = _build_case(case)
    _override_vllm_varlen_tensors(
        tensors, shape=shape, chunk_size=case.chunk_size, device=torch.device("cuda")
    )
    return case, tensors


@pytest.mark.parametrize(
    "case",
    [
        pytest.param(
            ChunkFwdOCase(
                seqlen=64,
                heads=4,
                grouped_heads=2,
                dtype=torch.float16,
                state_scale=0.0,
            ),
            id="aligned_one_chunk_fp16",
        ),
        pytest.param(
            ChunkFwdOCase(
                seqlen=65,
                heads=4,
                grouped_heads=2,
                dtype=torch.float16,
                state_scale=0.0,
            ),
            id="tail_one_token_fp16",
        ),
        pytest.param(
            ChunkFwdOCase(
                seqlen=128,
                heads=4,
                grouped_heads=2,
                dtype=torch.bfloat16,
                state_scale=0.0,
            ),
            id="aligned_two_chunks_bf16",
        ),
        pytest.param(
            ChunkFwdOCase(
                seqlen=130,
                heads=4,
                grouped_heads=2,
                dtype=torch.bfloat16,
                state_scale=0.0,
                varlen=True,
            ),
            id="varlen_tail_bf16",
        ),
    ],
)
def test_chunk_fwd_o_boundary_cases_match_triton_vllm(
    case: ChunkFwdOCase,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize(
    "case",
    [
        pytest.param(
            ChunkFwdOCase(
                seqlen=65,
                heads=4,
                grouped_heads=2,
                state_scale=0.0,
                use_g=False,
                use_g_gamma=False,
            ),
            id="without_g_or_g_gamma",
        ),
        pytest.param(
            ChunkFwdOCase(
                seqlen=65,
                heads=4,
                grouped_heads=2,
                state_scale=0.0,
                use_g=True,
                use_g_gamma=True,
                use_exp2=True,
            ),
            id="with_g_g_gamma_exp2",
        ),
        pytest.param(
            ChunkFwdOCase(
                seqlen=65,
                heads=4,
                grouped_heads=2,
                state_scale=0.0,
                use_g=False,
                use_g_gamma=True,
            ),
            id="with_g_gamma_only",
        ),
    ],
)
def test_chunk_fwd_o_optional_arguments_match_triton_vllm(
    case: ChunkFwdOCase,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("use_varlen", [False, True])
@pytest.mark.parametrize(
    "use_g,use_g_gamma",
    [(True, False), (True, True), (False, True), (False, False)],
)
@pytest.mark.parametrize("dtype", [torch.float16, torch.bfloat16])
def test_chunk_fwd_o_matches_triton_vllm(
    use_varlen: bool, use_g: bool, use_g_gamma: bool, dtype: torch.dtype
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = ChunkFwdOCase(
        dtype=dtype,
        varlen=use_varlen,
        use_g=use_g,
        use_g_gamma=use_g_gamma,
    )
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize("cu_dtype", [torch.int32, torch.int64])
@pytest.mark.parametrize("indices_dtype", [torch.int32, torch.int64])
def test_chunk_fwd_o_varlen_index_dtypes_vllm(
    cu_dtype: torch.dtype, indices_dtype: torch.dtype
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = ChunkFwdOCase(
        dtype=torch.float16,
        varlen=True,
    )
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


@pytest.mark.parametrize("use_g,use_g_gamma", GATE_MODES)
@pytest.mark.parametrize("shape", SHORT_MEDIUM_SHAPES)
@pytest.mark.parametrize("dtype", DTYPES)
def test_chunk_fwd_o_coverage_short_medium_vllm(
    use_g: bool,
    use_g_gamma: bool,
    shape: CoverageShape,
    dtype: torch.dtype,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case, tensors = _build_coverage_case(
        shape, dtype=dtype, use_g=use_g, use_g_gamma=use_g_gamma
    )
    _assert_case_close(case, tensors)


@pytest.mark.parametrize("use_g,use_g_gamma", GATE_MODES)
@pytest.mark.parametrize("shape", LONG_STRESS_SHAPES)
def test_chunk_fwd_o_coverage_long_stress_vllm(
    use_g: bool,
    use_g_gamma: bool,
    shape: CoverageShape,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case, tensors = _build_coverage_case(
        shape, dtype=torch.float16, use_g=use_g, use_g_gamma=use_g_gamma
    )
    _assert_case_close(case, tensors, repeats=3, valid_seqlen=shape.seqlen)


@pytest.mark.parametrize("use_g,use_g_gamma", GATE_MODES)
@pytest.mark.parametrize("seqlen,_state_index", MODEL_SHAPES)
def test_chunk_fwd_o_coverage_model_shape_vllm(
    use_g: bool,
    use_g_gamma: bool,
    seqlen: int,
    _state_index: int,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = ChunkFwdOCase(
        seqlen=seqlen,
        heads=8,
        grouped_heads=2,
        dtype=torch.bfloat16,
        input_scale=0.001,
        g_scale=0.01,
        state_scale=0.0,
        varlen=True,
        use_g=use_g,
        use_g_gamma=use_g_gamma,
    )
    tensors = _build_case(case)
    cu_seqlens = torch.tensor([0, seqlen], device=torch.device("cuda"), dtype=torch.long)
    tensors["cu_seqlens"] = cu_seqlens
    tensors["chunk_indices"] = prepare_chunk_indices(cu_seqlens, case.chunk_size)
    _assert_case_close(case, tensors, repeats=2)


def test_chunk_fwd_o_rejects_unsupported_chunk_size() -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = ChunkFwdOCase(chunk_size=32)
    tensors = _build_case(case)
    with pytest.raises(RuntimeError, match="chunk_size == 64"):
        _run_hip(case, tensors)


@pytest.mark.parametrize("gate_name", ["g", "g_gamma"])
def test_chunk_fwd_o_rejects_non_fp32_gates(gate_name: str) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = ChunkFwdOCase(use_g=True, use_g_gamma=True)
    tensors = _build_case(case)
    tensors[gate_name] = tensors[gate_name].to(case.dtype)

    with pytest.raises(RuntimeError, match=f"{gate_name} must be float32"):
        _run_hip(case, tensors)


def test_chunk_fwd_o_rejects_transpose_state_layout_false() -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = ChunkFwdOCase(transpose_state_layout=False)
    tensors = _build_case(case)
    with pytest.raises(RuntimeError, match="transpose_state_layout=true"):
        _run_hip(case, tensors)


if __name__ == "__main__":
    raise SystemExit(pytest.main([__file__, "-q"]))
