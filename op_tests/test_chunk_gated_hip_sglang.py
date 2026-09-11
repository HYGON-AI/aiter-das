# SPDX-License-Identifier: MIT
"""HIP SGLang chunk_gated_delta_rule_fwd tests against the Triton SGLang reference.

Run from the repository root:

    TRITON_CACHE_DIR=./cache PYTHONPATH=. pytest op_tests/test_chunk_gated_hip_sglang.py
"""

from __future__ import annotations

from dataclasses import dataclass, replace

import pytest
import torch

import aiter
from aiter.ops.triton.fla.sglang.chunk_delta_h import (
    chunk_gated_delta_rule_fwd_h as triton_chunk_gated_delta_rule_fwd_h_sglang,
    prepare_chunk_indices,
)
from op_tests.chunk_gated_coverage import (
    CoverageShape,
    DTYPES,
    GATE_MODES,
    LONG_STRESS_SHAPES,
    MODEL_SHAPES,
    SHORT_MEDIUM_SHAPES,
    apply_gate_flags,
    build_model_shape_tensors_sglang,
    override_sglang_varlen_tensors,
)


@dataclass(frozen=True)
class SglangChunkGatedCase:
    batch: int = 1
    seqlen: int = 130
    heads: int = 4
    grouped_heads: int = 2
    k_dim: int = 128
    v_dim: int = 128
    chunk_size: int = 64
    dtype: torch.dtype = torch.float16
    state_dtype: torch.dtype = torch.float32
    input_scale: float = 0.01
    g_scale: float = 0.01
    state_scale: float = 0.0
    varlen: bool = False
    state_index_mode: str = "identity"
    use_g: bool = True
    use_gk: bool = False
    output_final_state: bool = True
    save_new_value: bool = True
    use_exp2: bool = False


def _build_case(case: SglangChunkGatedCase) -> dict[str, object]:
    torch.manual_seed(43)
    device = torch.device("cuda")

    k = torch.randn(
        (case.batch, case.seqlen, case.grouped_heads, case.k_dim),
        device=device,
        dtype=case.dtype,
    ) * case.input_scale
    w = torch.randn(
        (case.batch, case.seqlen, case.heads, case.k_dim),
        device=device,
        dtype=case.dtype,
    ) * case.input_scale
    u = torch.randn(
        (case.batch, case.seqlen, case.heads, case.v_dim),
        device=device,
        dtype=case.dtype,
    ) * case.input_scale

    g = torch.randn(
        (case.batch, case.seqlen, case.heads),
        device=device,
        dtype=torch.float32,
    ) * case.g_scale
    if not case.use_g:
        g = None

    gk = None
    if case.use_gk:
        gk = torch.randn(
            (case.batch, case.seqlen, case.heads, case.k_dim),
            device=device,
            dtype=torch.float32,
        ) * case.g_scale

    cu_seqlens = None
    chunk_indices = None
    n_seq = case.batch
    if case.varlen:
        if case.batch != 1:
            raise ValueError("SGLang varlen tests use batch=1 padded inputs")
        cu_seqlens = torch.tensor(
            [0, max(1, case.seqlen // 3), max(2, (2 * case.seqlen) // 3), case.seqlen],
            device=device,
            dtype=torch.long,
        )
        chunk_indices = prepare_chunk_indices(cu_seqlens, case.chunk_size)
        n_seq = int(cu_seqlens.numel() - 1)

    if case.state_index_mode == "identity":
        state_rows = n_seq
        initial_state_indices = torch.arange(n_seq, device=device, dtype=torch.int32)
    elif case.state_index_mode == "reverse":
        state_rows = n_seq
        initial_state_indices = torch.arange(n_seq - 1, -1, -1, device=device, dtype=torch.int32)
    elif case.state_index_mode == "random":
        state_rows = n_seq + 3
        initial_state_indices = torch.randperm(
            state_rows, device=device, dtype=torch.int64
        )[:n_seq].to(torch.int32)
    else:
        raise ValueError(f"unsupported state index mode: {case.state_index_mode}")

    initial_state = torch.randn(
        (state_rows, case.heads, case.v_dim, case.k_dim),
        device=device,
        dtype=case.state_dtype,
    ) * case.state_scale

    return {
        "k": k,
        "w": w,
        "u": u,
        "g": g,
        "gk": gk,
        "initial_state": initial_state,
        "initial_state_indices": initial_state_indices,
        "cu_seqlens": cu_seqlens,
        "chunk_indices": chunk_indices,
    }


def _apply_varlen_index_dtypes(
    tensors: dict[str, object],
    *,
    cu_dtype: torch.dtype,
    indices_dtype: torch.dtype,
    chunk_size: int,
) -> None:
    """Force cu_seqlens / chunk_indices element dtypes (may differ)."""
    cu = tensors["cu_seqlens"]
    assert isinstance(cu, torch.Tensor)
    cu = cu.to(dtype=cu_dtype)
    indices = prepare_chunk_indices(cu, chunk_size).to(dtype=indices_dtype)
    tensors["cu_seqlens"] = cu
    tensors["chunk_indices"] = indices


def _run_hip(case: SglangChunkGatedCase, tensors: dict[str, object]):
    state = tensors["initial_state"].clone()
    h, v_new = aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
        tensors["k"],
        tensors["w"],
        tensors["u"],
        g=tensors["g"],
        gk=tensors["gk"],
        initial_state=state,
        initial_state_indices=tensors["initial_state_indices"],
        output_final_state=case.output_final_state,
        chunk_size=case.chunk_size,
        save_new_value=case.save_new_value,
        cu_seqlens=tensors["cu_seqlens"],
        chunk_indices=tensors["chunk_indices"],
        use_exp2=case.use_exp2,
        transpose_state_layout=True,
    )
    return h, v_new, state


def _run_triton(case: SglangChunkGatedCase, tensors: dict[str, object]):
    state = tensors["initial_state"].clone()
    h, v_new = triton_chunk_gated_delta_rule_fwd_h_sglang(
        k=tensors["k"],
        w=tensors["w"],
        u=tensors["u"],
        g=tensors["g"],
        gk=tensors["gk"],
        initial_state=state,
        initial_state_indices=tensors["initial_state_indices"],
        output_final_state=case.output_final_state,
        chunk_size=case.chunk_size,
        save_new_value=case.save_new_value,
        cu_seqlens=tensors["cu_seqlens"],
        chunk_indices=tensors["chunk_indices"],
        use_exp2=case.use_exp2,
        transpose_state_layout=True,
    )
    return h, v_new, state


def _tolerances(dtype: torch.dtype) -> tuple[float, float, float, float]:
    if dtype == torch.float16:
        return 6e-2, 6e-2, 6e-2, 6e-2
    if dtype == torch.bfloat16:
        return 8e-2, 8e-2, 8e-2, 8e-2
    raise AssertionError(f"unexpected dtype: {dtype}")


def _assert_case_close(
    case: SglangChunkGatedCase,
    tensors: dict[str, object],
    *,
    repeats: int = 1,
    valid_seqlen: int | None = None,
) -> None:
    elem_rtol, elem_atol, state_rtol, state_atol = _tolerances(case.dtype)
    for _ in range(repeats):
        h_hip, v_new_hip, state_hip = _run_hip(case, tensors)
        h_tri, v_new_tri, state_tri = _run_triton(case, tensors)
        torch.cuda.synchronize()

        if valid_seqlen is not None:
            h_hip = h_hip[:, :valid_seqlen]
            h_tri = h_tri[:, :valid_seqlen]
            if v_new_hip is not None:
                v_new_hip = v_new_hip[:, :valid_seqlen]
            if v_new_tri is not None:
                v_new_tri = v_new_tri[:, :valid_seqlen]

        torch.testing.assert_close(
            h_hip, h_tri, rtol=elem_rtol, atol=elem_atol, equal_nan=True
        )
        if case.save_new_value:
            assert v_new_hip is not None
            assert v_new_tri is not None
            torch.testing.assert_close(
                v_new_hip, v_new_tri, rtol=elem_rtol, atol=elem_atol, equal_nan=True
            )
        else:
            assert v_new_hip is None
            assert v_new_tri is None

        torch.testing.assert_close(
            state_hip, state_tri, rtol=state_rtol, atol=state_atol, equal_nan=True
        )


def _build_coverage_case(
    shape: CoverageShape,
    *,
    dtype: torch.dtype,
    use_g: bool,
    use_gk: bool,
) -> tuple[SglangChunkGatedCase, dict[str, object]]:
    buf_seqlen = shape.buf_seqlen or shape.seqlen
    case = SglangChunkGatedCase(
        seqlen=buf_seqlen,
        heads=shape.heads,
        grouped_heads=shape.grouped_heads,
        dtype=dtype,
        input_scale=0.01,
        g_scale=0.01,
        state_scale=0.01 if shape.seqlen >= 129 else 0.0,
        varlen=shape.varlen,
        use_g=use_g,
        use_gk=use_gk,
        state_index_mode="random" if shape.varlen and shape.seqlen <= 130 else "identity",
    )
    if shape.varlen and shape.seqlen > 130:
        case = replace(case, state_index_mode="identity")
    tensors = _build_case(case)
    apply_gate_flags(
        tensors,
        batch=case.batch,
        seqlen=buf_seqlen,
        heads=case.heads,
        k_dim=case.k_dim,
        use_g=use_g,
        use_gk=use_gk,
        g_scale=case.g_scale,
        device=torch.device("cuda"),
    )
    override_sglang_varlen_tensors(
        tensors, shape=shape, chunk_size=case.chunk_size, device=torch.device("cuda")
    )
    if shape.varlen and shape.buf_seqlen is not None:
        device = torch.device("cuda")
        state_rows = 440
        tensors["initial_state"] = torch.randn(
            (state_rows, case.heads, case.v_dim, case.k_dim),
            device=device,
            dtype=torch.float32,
        ) * case.state_scale
        tensors["initial_state_indices"] = torch.tensor(
            [3], device=device, dtype=torch.int32
        )
        tensors["cu_seqlens"] = torch.tensor(
            [0, shape.seqlen], device=device, dtype=torch.int32
        )
        tensors["chunk_indices"] = prepare_chunk_indices(
            tensors["cu_seqlens"], case.chunk_size
        )
    return case, tensors


@pytest.mark.parametrize(
    "case",
    [
        pytest.param(
            SglangChunkGatedCase(seqlen=64, dtype=torch.float16),
            id="aligned_one_chunk_fp16",
        ),
        pytest.param(
            SglangChunkGatedCase(seqlen=65, dtype=torch.float16),
            id="tail_one_token_fp16",
        ),
        pytest.param(
            SglangChunkGatedCase(seqlen=128, dtype=torch.bfloat16),
            id="aligned_two_chunks_bf16",
        ),
        pytest.param(
            SglangChunkGatedCase(seqlen=130, dtype=torch.bfloat16, varlen=True),
            id="varlen_tail_bf16",
        ),
        pytest.param(
            SglangChunkGatedCase(
                batch=4,
                seqlen=129,
                heads=32,
                grouped_heads=16,
                dtype=torch.float16,
                state_dtype=torch.bfloat16,
                state_scale=0.05,
                use_gk=True,
            ),
            id="padded_p128_fp16_bf16_state_tail",
        ),
        pytest.param(
            SglangChunkGatedCase(
                seqlen=390,
                heads=128,
                grouped_heads=64,
                dtype=torch.bfloat16,
                state_dtype=torch.bfloat16,
                state_scale=0.05,
                varlen=True,
                state_index_mode="random",
            ),
            id="varlen_p384_bf16_state_tail",
        ),
    ],
)
def test_chunk_gated_delta_rule_fwd_boundary_cases_match_triton_sglang(
    monkeypatch: pytest.MonkeyPatch, case: SglangChunkGatedCase,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    monkeypatch.delenv("AITER_FLA_FORCE_BV", raising=False)
    _assert_case_close(case, _build_case(case))


@pytest.mark.parametrize(
    "case",
    [
        pytest.param(
            SglangChunkGatedCase(seqlen=65, use_g=False),
            id="without_g_or_gk",
        ),
        pytest.param(
            SglangChunkGatedCase(seqlen=65, use_g=True, use_gk=True, use_exp2=True),
            id="with_g_gk_exp2_argument",
        ),
        pytest.param(
            SglangChunkGatedCase(seqlen=65, save_new_value=False),
            id="without_v_new",
        ),
        pytest.param(
            SglangChunkGatedCase(seqlen=65, output_final_state=False),
            id="output_final_state_argument_ignored",
        ),
        pytest.param(
            SglangChunkGatedCase(seqlen=130, varlen=True, state_index_mode="reverse"),
            id="varlen_reverse_state_indices",
        ),
    ],
)
def test_chunk_gated_delta_rule_fwd_optional_arguments_match_triton_sglang(
    case: SglangChunkGatedCase,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    _assert_case_close(case, _build_case(case))


def test_chunk_gated_delta_rule_fwd_sglang_rebuilds_empty_chunk_indices() -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = SglangChunkGatedCase(seqlen=130, varlen=True)
    tensors = _build_case(case)
    # Empty / invalid meta should be rebuilt by the Python HIP wrapper.
    tensors["chunk_indices"] = torch.empty(
        (0, 2), device=torch.device("cuda"), dtype=torch.long
    )
    tensors["chunk_offsets"] = None
    _assert_case_close(case, tensors)


@pytest.mark.parametrize("cu_dtype", [torch.int32, torch.int64])
@pytest.mark.parametrize("indices_dtype", [torch.int32, torch.int64])
def test_chunk_gated_delta_rule_fwd_varlen_index_dtypes_sglang(
    cu_dtype: torch.dtype, indices_dtype: torch.dtype
) -> None:
    """HIP accepts int32/int64 for cu_seqlens and chunk_indices independently."""
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = SglangChunkGatedCase(
        dtype=torch.float16,
        varlen=True,
        state_index_mode="identity",
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


@pytest.mark.parametrize("seqlen", [63, 64, 65, 128, 390])
def test_chunk_gated_delta_rule_fwd_bv64_target_matches_triton_sglang(
    monkeypatch: pytest.MonkeyPatch, seqlen: int,
) -> None:
    """Exercise BV64 one/multi-chunk full and tail control-flow paths."""
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    monkeypatch.setenv("AITER_FLA_FORCE_BV", "64")
    case = SglangChunkGatedCase(
        seqlen=seqlen,
        heads=8,
        grouped_heads=4,
        dtype=torch.bfloat16,
        state_dtype=torch.bfloat16,
        input_scale=0.01,
        g_scale=0.01,
        state_scale=0.01,
        varlen=True,
        state_index_mode="random",
    )
    tensors = _build_case(case)
    _apply_varlen_index_dtypes(
        tensors,
        cu_dtype=torch.int32,
        indices_dtype=torch.int32,
        chunk_size=case.chunk_size,
    )
    _assert_case_close(case, tensors, repeats=2)


@pytest.mark.parametrize(
    "seqlen,state_index",
    [
        (9008, 7),
        (9009, 31),
    ],
)
def test_chunk_gated_delta_rule_fwd_model_shape_matches_triton_sglang(
    seqlen: int, state_index: int
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = SglangChunkGatedCase(
        seqlen=seqlen,
        heads=8,
        grouped_heads=2,
        dtype=torch.bfloat16,
        input_scale=0.001,
        g_scale=0.01,
        state_scale=0.0,
        varlen=True,
    )
    tensors = _build_case(case)
    tensors["initial_state"] = torch.zeros(
        (49, case.heads, case.v_dim, case.k_dim),
        device=torch.device("cuda"),
        dtype=torch.float32,
    )
    tensors["initial_state_indices"] = torch.tensor(
        [state_index], device=torch.device("cuda"), dtype=torch.int32
    )
    tensors["cu_seqlens"] = torch.tensor(
        [0, seqlen], device=torch.device("cuda"), dtype=torch.int32
    )
    tensors["chunk_indices"] = prepare_chunk_indices(
        tensors["cu_seqlens"], case.chunk_size
    )

    _assert_case_close(case, tensors)


@pytest.mark.parametrize("use_g,use_gk", GATE_MODES)
@pytest.mark.parametrize("shape", SHORT_MEDIUM_SHAPES)
@pytest.mark.parametrize("dtype", DTYPES)
def test_chunk_gated_delta_rule_fwd_coverage_short_medium_sglang(
    monkeypatch: pytest.MonkeyPatch,
    use_g: bool,
    use_gk: bool,
    shape: CoverageShape,
    dtype: torch.dtype,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    monkeypatch.delenv("AITER_FLA_FORCE_BV", raising=False)
    case, tensors = _build_coverage_case(
        shape, dtype=dtype, use_g=use_g, use_gk=use_gk
    )
    _assert_case_close(case, tensors)


@pytest.mark.parametrize("use_g,use_gk", GATE_MODES)
@pytest.mark.parametrize("shape", LONG_STRESS_SHAPES)
def test_chunk_gated_delta_rule_fwd_coverage_long_stress_sglang(
    use_g: bool,
    use_gk: bool,
    shape: CoverageShape,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case, tensors = _build_coverage_case(
        shape, dtype=torch.float16, use_g=use_g, use_gk=use_gk
    )
    _assert_case_close(
        case, tensors, repeats=3, valid_seqlen=shape.seqlen
    )


@pytest.mark.parametrize("use_g,use_gk", GATE_MODES)
@pytest.mark.parametrize("seqlen,state_index", MODEL_SHAPES)
def test_chunk_gated_delta_rule_fwd_coverage_model_shape_sglang(
    use_g: bool,
    use_gk: bool,
    seqlen: int,
    state_index: int,
) -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = SglangChunkGatedCase(
        seqlen=seqlen,
        heads=8,
        grouped_heads=2,
        dtype=torch.bfloat16,
        input_scale=0.001,
        g_scale=0.01,
        state_scale=0.0,
        varlen=True,
        use_g=use_g,
        use_gk=use_gk,
    )
    tensors = _build_case(case)
    apply_gate_flags(
        tensors,
        batch=case.batch,
        seqlen=case.seqlen,
        heads=case.heads,
        k_dim=case.k_dim,
        use_g=use_g,
        use_gk=use_gk,
        g_scale=case.g_scale,
        device=torch.device("cuda"),
    )
    build_model_shape_tensors_sglang(
        case, tensors, seqlen=seqlen, state_index=state_index
    )
    _assert_case_close(case, tensors, repeats=2)


def test_chunk_gated_delta_rule_fwd_sglang_requires_initial_state_and_indices() -> None:
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = SglangChunkGatedCase(seqlen=64)
    tensors = _build_case(case)

    with pytest.raises(RuntimeError, match="requires initial_state"):
        aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
            tensors["k"],
            tensors["w"],
            tensors["u"],
            g=tensors["g"],
            initial_state=None,
            initial_state_indices=tensors["initial_state_indices"],
        )

    with pytest.raises(RuntimeError, match="requires int32 initial_state_indices"):
        aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
            tensors["k"],
            tensors["w"],
            tensors["u"],
            g=tensors["g"],
            initial_state=tensors["initial_state"],
            initial_state_indices=None,
        )

    with pytest.raises(RuntimeError, match="must be float32 or bfloat16"):
        aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
            tensors["k"],
            tensors["w"],
            tensors["u"],
            g=tensors["g"],
            initial_state=tensors["initial_state"].to(torch.float16),
            initial_state_indices=tensors["initial_state_indices"],
        )


@pytest.mark.parametrize(
    ("input_dtype", "state_dtype", "varlen", "heads", "all_invalid"),
    [
        pytest.param(torch.float16, torch.float32, False, 2, False, id="fp16-fp32-bv16"),
        pytest.param(torch.bfloat16, torch.bfloat16, False, 4, False, id="bf16-bf16-bv32"),
        pytest.param(torch.bfloat16, torch.bfloat16, True, 4, False, id="bf16-bf16-varlen"),
        pytest.param(torch.float16, torch.float32, False, 2, True, id="all-minus-one"),
    ],
)
def test_chunk_gated_delta_rule_fwd_sglang_state_pool_view_and_minus_one(
    input_dtype: torch.dtype,
    state_dtype: torch.dtype,
    varlen: bool,
    heads: int,
    all_invalid: bool,
) -> None:
    """Envelope slot stride and -1 semantics against a scratch-slot reference."""
    if not torch.cuda.is_available():
        pytest.skip("ROCm/HIP CUDA-compatible device required")

    case = SglangChunkGatedCase(
        batch=1 if varlen else 3,
        seqlen=130 if varlen else 64,
        heads=heads,
        grouped_heads=min(2, heads),
        dtype=input_dtype,
        state_dtype=state_dtype,
        state_scale=0.0,
        varlen=varlen,
    )
    tensors = _build_case(case)
    indices = tensors["initial_state_indices"]
    assert isinstance(indices, torch.Tensor)
    n_seq = int(indices.numel())
    assert n_seq == 3

    state_rows = n_seq + 2
    backing = torch.full(
        (state_rows, heads + 1, case.v_dim, case.k_dim),
        17.0,
        device="cuda",
        dtype=state_dtype,
    )
    state_view = backing[:, :heads]
    state_view.copy_(torch.randn_like(state_view) * 0.01)
    assert state_view.stride(0) != heads * case.v_dim * case.k_dim
    padding_before = backing[:, heads:].clone()
    state_before = state_view.clone()

    pool_indices = torch.full(
        (n_seq,), -1, device="cuda", dtype=torch.int32
    )
    if not all_invalid:
        pool_indices.copy_(torch.tensor([2, -1, 0], device="cuda", dtype=torch.int32))

    tensors["initial_state"] = state_view
    tensors["initial_state_indices"] = pool_indices

    elem_rtol, elem_atol, state_rtol, state_atol = _tolerances(input_dtype)
    expected_pool = state_before.clone()
    steps = 2 if state_dtype == torch.bfloat16 else 1
    for _ in range(steps):
        # The local Triton kernel cannot consume -1 or an envelope slot pitch.
        # Give every no-state sequence its own zero scratch slot and run it on
        # a contiguous pool; scratch writes are discarded from the expected
        # pool. Rebuilding it per step also checks BF16 writeback/reload.
        scratch_count = int((pool_indices == -1).sum().item())
        reference_pool = torch.zeros(
            (state_rows + scratch_count, heads, case.v_dim, case.k_dim),
            device="cuda",
            dtype=state_dtype,
        )
        reference_pool[:state_rows].copy_(expected_pool)
        reference_indices = pool_indices.clone()
        next_scratch = state_rows
        for sequence_id in range(n_seq):
            if int(reference_indices[sequence_id].item()) == -1:
                reference_indices[sequence_id] = next_scratch
                next_scratch += 1

        reference_tensors = dict(tensors)
        reference_tensors["initial_state"] = reference_pool
        reference_tensors["initial_state_indices"] = reference_indices
        h_ref, v_new_ref, state_ref = _run_triton(case, reference_tensors)

        h_hip, v_new_hip = aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
            tensors["k"],
            tensors["w"],
            tensors["u"],
            g=tensors["g"],
            gk=tensors["gk"],
            initial_state=state_view,
            initial_state_indices=pool_indices,
            output_final_state=True,
            chunk_size=case.chunk_size,
            save_new_value=case.save_new_value,
            cu_seqlens=tensors["cu_seqlens"],
            chunk_indices=tensors["chunk_indices"],
            use_exp2=case.use_exp2,
            transpose_state_layout=True,
        )
        torch.cuda.synchronize()

        torch.testing.assert_close(h_hip, h_ref, rtol=elem_rtol, atol=elem_atol)
        assert v_new_hip is not None and v_new_ref is not None
        torch.testing.assert_close(
            v_new_hip, v_new_ref, rtol=elem_rtol, atol=elem_atol
        )

        next_expected_pool = expected_pool.clone()
        for slot in pool_indices[pool_indices >= 0].tolist():
            next_expected_pool[slot].copy_(state_ref[slot])
        torch.testing.assert_close(
            state_view, next_expected_pool, rtol=state_rtol, atol=state_atol
        )
        torch.testing.assert_close(
            backing[:, heads:], padding_before, rtol=0, atol=0
        )
        expected_pool = next_expected_pool


if __name__ == "__main__":
    raise SystemExit(pytest.main([__file__, "-q"]))
