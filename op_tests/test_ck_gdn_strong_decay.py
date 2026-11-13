# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#
"""Strong-decay regression for ``aiter.ck_gdn_prefill``.

Chunked prefill applies the chunk gate on the masked lower triangle.  A
strongly decaying chunk used to turn the separable ``exp2(g_row) *
exp2(-g_col)`` product into ``0 * inf`` and poison A / the gated score tile
with NaN once the cumulative decay left the FP32 exponent range.  Every case
here asserts only that output and final state stay finite, because that is
exactly what the fix restores; numerical agreement with the HIPC / Triton
reference is covered by ``test_ck_gdn_native.py``.
"""

import pytest
import torch
import torch.nn.functional as F


# (h_qk, h_v, decay) -- h_v / h_qk covers every head ratio the native layer
# accepts: 4, 3 and 1. The boundary decays are -1.35 / -1.4, the point where a
# 64-token chunk crosses |g_cum| = 128 log2 units.
_CASES = [
    (2, 8, -0.5),
    (2, 8, -1.0),
    (2, 8, -1.35),
    (2, 8, -1.4),
    (2, 8, -2.0),
    (2, 8, -10.0),
    (2, 8, -100.0),
    (2, 6, -1.0),
    (2, 6, -2.0),
    (2, 6, -100.0),
    (8, 24, -1.0),
    (8, 24, -1.4),
    (8, 24, -2.0),
    (8, 24, -100.0),
    (4, 4, -2.0),
]


@pytest.mark.parametrize(("num_q_heads", "num_v_heads", "decay"), _CASES)
def test_aiter_ck_gdn_prefill_strong_decay(num_q_heads, num_v_heads, decay):
    """Strong constant decay must stay finite.

    The gate is applied as exp2(g_row - g_col) on the masked lower triangle, so
    the exponent never exceeds zero and a strongly decaying chunk can only
    underflow towards zero. The separable exp2(g_row) * exp2(-g_col) form used
    to overflow the column factor into +inf and turn the underflowed row factor
    into NaN once |g_cum| passed the FP32 range (|g| * min(T, 64) * log2(e) > 128).
    """
    import aiter

    torch.manual_seed(7)

    seq_len = 128
    head_dim = 128

    q = F.normalize(
        torch.randn(
            seq_len,
            num_q_heads,
            head_dim,
            device="cuda",
            dtype=torch.float32,
        ),
        dim=-1,
    ).to(torch.bfloat16)

    k = F.normalize(
        torch.randn_like(q, dtype=torch.float32),
        dim=-1,
    ).to(torch.bfloat16)

    v = torch.randn(
        seq_len,
        num_v_heads,
        head_dim,
        device="cuda",
        dtype=torch.bfloat16,
    )

    # 合法的 FP32 log-decay 输入。
    g = torch.full(
        (seq_len, num_v_heads),
        decay,
        device="cuda",
        dtype=torch.float32,
    )

    beta = torch.sigmoid(
        torch.randn(
            seq_len,
            num_v_heads,
            device="cuda",
            dtype=torch.float32,
        )
    )

    initial_state = torch.randn(
        1,
        num_v_heads,
        head_dim,
        head_dim,
        device="cuda",
        dtype=torch.float32,
    ) * 0.01

    flags = {
        "use_g": True,
        "use_gk": False,
        "use_exp2": False,
        "transpose_state": True,
        "qk_l2norm": False,
        "gate_in_kernel": False,
        "has_dt_bias": False,
        "beta_sigmoid_in_kernel": False,
        "output_final_state": True,
        "cp_context": False,
        "cp_world_size": 2,
    }

    workspace = aiter.ck_gdn_prefill_alloc_workspace(
        q,
        v,
        None,
        **flags,
    )

    output, final_state = aiter.ck_gdn_prefill(
        q,
        k,
        v,
        g,
        beta,
        workspace,
        initial_state=initial_state,
        scale=head_dim**-0.5,
        cp_rank=1,
        **flags,
    )
    torch.cuda.synchronize()

    output_finite = bool(torch.isfinite(output).all())
    state_finite = bool(torch.isfinite(final_state).all())

    print(
        f"h_qk={num_q_heads}, h_v={num_v_heads}, g={decay}: "
        f"output_finite={output_finite}, "
        f"state_finite={state_finite}"
    )

    assert output_finite
    assert state_finite
