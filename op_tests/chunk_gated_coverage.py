# SPDX-License-Identifier: MIT
"""Shared shape coverage and tensor builders for the HIP chunk_gated_delta_rule
forward tests (``test_chunk_gated_hip_vllm.py`` / ``test_chunk_gated_hip_sglang.py``).

The HIP kernel currently only supports ``k_dim == v_dim == 128`` and
``chunk_size == 64``.  Every :class:`CoverageShape` below therefore implicitly
uses ``k_dim = v_dim = 128`` and ``chunk_size = 64`` (the defaults baked into the
``ChunkGatedCase`` / ``SglangChunkGatedCase`` dataclasses in the test files);
``CoverageShape`` only varies the sequence length, head counts, varlen flag and
the optional padded buffer length.
"""

from __future__ import annotations

from dataclasses import dataclass
from typing import Optional

import torch


# --------------------------------------------------------------------------- #
# Constraint constants (kept here so the supported size is documented in one
# place).  The HIP kernel rejects anything else.
# --------------------------------------------------------------------------- #
SUPPORTED_K_DIM = 128
SUPPORTED_V_DIM = 128
SUPPORTED_CHUNK_SIZE = 64


@dataclass(frozen=True)
class CoverageShape:
    """A shape variant for coverage testing.

    ``seqlen`` is the *valid* token count (what ``cu_seqlens`` covers).  When
    ``buf_seqlen`` is set the input tensors are allocated with that many tokens
    and the trailing ``buf_seqlen - seqlen`` tokens are padding that the kernel
    must not touch -- this mirrors real SGLang/vLLM padded varlen inputs.
    """

    seqlen: int
    heads: int
    grouped_heads: int
    varlen: bool = False
    buf_seqlen: Optional[int] = None


# --------------------------------------------------------------------------- #
# Parametrization axes shared by the coverage tests.
# --------------------------------------------------------------------------- #
DTYPES = [torch.float16, torch.bfloat16]

# (use_g, use_gk) combinations.  At least one gate is exercised in every mode;
# the "both off" case is already covered by the per-test optional-argument
# suites, so it is deliberately omitted from the coverage matrix.
GATE_MODES = [
    (True, False),
    (True, True),
    (False, True),
]

# Short / medium lengths -- every token is within cu_seqlens (no padding), so
# the full output tensor is compared.  Varlen variants use multi-segment
# cu_seqlens that fully cover [0, seqlen].
SHORT_MEDIUM_SHAPES = [
    CoverageShape(seqlen=64, heads=4, grouped_heads=2, varlen=False),
    CoverageShape(seqlen=65, heads=4, grouped_heads=2, varlen=False),
    CoverageShape(seqlen=128, heads=8, grouped_heads=4, varlen=False),
    CoverageShape(seqlen=130, heads=8, grouped_heads=4, varlen=True),
    CoverageShape(seqlen=192, heads=4, grouped_heads=2, varlen=True),
    CoverageShape(seqlen=256, heads=8, grouped_heads=8, varlen=False),
    CoverageShape(seqlen=512, heads=16, grouped_heads=8, varlen=True),
    CoverageShape(seqlen=513, heads=8, grouped_heads=4, varlen=False),
]

# Long / stress shapes -- padded buffers (buf_seqlen > seqlen) with a single
# varlen segment [0, seqlen]; only the first ``seqlen`` tokens are validated.
# The 2149/2152 entry mirrors the real captured SGLang request shape.
LONG_STRESS_SHAPES = [
    CoverageShape(seqlen=2149, buf_seqlen=2152, heads=8, grouped_heads=8, varlen=True),
    CoverageShape(seqlen=4096, buf_seqlen=4128, heads=8, grouped_heads=4, varlen=True),
    CoverageShape(seqlen=8192, buf_seqlen=8200, heads=8, grouped_heads=2, varlen=True),
]

# (seqlen, state_index) for the model-shape coverage.  state_index must be <
# MODEL_STATE_ROWS (49) which matches the inline model-shape tests.  seqlen is a
# single varlen segment [0, seqlen].
MODEL_SHAPES = [
    (9008, 7),
    (9009, 31),
    (2152, 3),
]

MODEL_STATE_ROWS = 49


# --------------------------------------------------------------------------- #
# Helpers
# --------------------------------------------------------------------------- #
def _cdiv(a: int, b: int) -> int:
    return (a + b - 1) // b


def prepare_chunk_indices(cu_seqlens: torch.Tensor, chunk_size: int) -> torch.Tensor:
    """Local copy of the vllm/sglang helper to avoid importing either frontend
    module from this shared module."""

    chunk_rows = []
    for i in range(cu_seqlens.numel() - 1):
        seqlen = int((cu_seqlens[i + 1] - cu_seqlens[i]).item())
        for chunk_idx in range(_cdiv(seqlen, chunk_size)):
            chunk_rows.append([i, chunk_idx])
    if not chunk_rows:
        return torch.empty((0, 2), dtype=torch.long, device=cu_seqlens.device)
    return torch.tensor(chunk_rows, dtype=torch.long, device=cu_seqlens.device)


def _multi_split_cu_seqlens(seqlen: int, device: torch.device) -> torch.Tensor:
    """Three-segment cu_seqlens that fully cover [0, seqlen]."""
    return torch.tensor(
        [0, max(1, seqlen // 3), max(2, (2 * seqlen) // 3), seqlen],
        device=device,
        dtype=torch.long,
    )


# --------------------------------------------------------------------------- #
# Gate configuration
# --------------------------------------------------------------------------- #
def apply_gate_flags(
    tensors: dict,
    *,
    batch: int,
    seqlen: int,
    heads: int,
    k_dim: int,
    use_g: bool,
    use_gk: bool,
    g_scale: float,
    device: torch.device,
) -> None:
    """Force ``tensors["g"]`` / ``tensors["gk"]`` to match the (use_g, use_gk)
    flags.  When ``use_g`` is True and a ``g`` tensor already exists (created by
    ``_build_case``) it is reused so its shape stays consistent with the padded
    buffer length; otherwise a fresh fp32 gate is drawn."""

    if use_g:
        if tensors.get("g") is None:
            tensors["g"] = torch.randn(
                (batch, seqlen, heads), device=device, dtype=torch.float32
            ) * g_scale
    else:
        tensors["g"] = None

    if use_gk:
        tensors["gk"] = torch.randn(
            (batch, seqlen, heads, k_dim), device=device, dtype=torch.float32
        ) * g_scale
    else:
        tensors["gk"] = None


# --------------------------------------------------------------------------- #
# Varlen overrides
# --------------------------------------------------------------------------- #
def _override_varlen_tensors(
    tensors: dict,
    *,
    shape: CoverageShape,
    chunk_size: int,
    device: torch.device,
    set_n_seq: bool,
) -> None:
    if not shape.varlen:
        return
    if shape.buf_seqlen is not None:
        cu_seqlens = torch.tensor([0, shape.seqlen], device=device, dtype=torch.long)
        n_seq = 1
    else:
        cu_seqlens = _multi_split_cu_seqlens(shape.seqlen, device)
        n_seq = int(cu_seqlens.numel()) - 1
    tensors["cu_seqlens"] = cu_seqlens
    tensors["chunk_indices"] = prepare_chunk_indices(cu_seqlens, chunk_size)
    if set_n_seq:
        tensors["n_seq"] = n_seq


def override_vllm_varlen_tensors(
    tensors: dict,
    *,
    shape: CoverageShape,
    chunk_size: int,
    device: torch.device,
) -> None:
    _override_varlen_tensors(
        tensors, shape=shape, chunk_size=chunk_size, device=device, set_n_seq=True
    )


def override_sglang_varlen_tensors(
    tensors: dict,
    *,
    shape: CoverageShape,
    chunk_size: int,
    device: torch.device,
) -> None:
    _override_varlen_tensors(
        tensors, shape=shape, chunk_size=chunk_size, device=device, set_n_seq=False
    )


# --------------------------------------------------------------------------- #
# Model-shape tensor builders
# --------------------------------------------------------------------------- #
def _build_model_shape_tensors(
    case,
    tensors: dict,
    *,
    seqlen: int,
    state_index: int,
    set_n_seq: bool,
) -> None:
    device = torch.device("cuda")
    state_rows = max(MODEL_STATE_ROWS, state_index + 1)
    tensors["initial_state"] = torch.zeros(
        (state_rows, case.heads, case.v_dim, case.k_dim),
        device=device,
        dtype=torch.float32,
    )
    tensors["initial_state_indices"] = torch.tensor(
        [state_index], device=device, dtype=torch.int32
    )
    cu_seqlens = torch.tensor([0, seqlen], device=device, dtype=torch.long)
    tensors["cu_seqlens"] = cu_seqlens
    tensors["chunk_indices"] = prepare_chunk_indices(cu_seqlens, case.chunk_size)
    if set_n_seq:
        tensors["n_seq"] = 1


def build_model_shape_tensors_vllm(
    case, tensors: dict, *, seqlen: int, state_index: int
) -> None:
    _build_model_shape_tensors(
        case, tensors, seqlen=seqlen, state_index=state_index, set_n_seq=True
    )


def build_model_shape_tensors_sglang(
    case, tensors: dict, *, seqlen: int, state_index: int
) -> None:
    _build_model_shape_tensors(
        case, tensors, seqlen=seqlen, state_index=state_index, set_n_seq=False
    )
