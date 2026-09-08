# Test for get_aiter_moe_config and aiter_moe with W16A16 (non-quantized)

import torch
import pandas as pd
from typing import Optional, List

from aiter.fused_moe import fused_topk, torch_moe
from aiter import ActivationType, dtypes
from aiter.test_common import checkAllclose, perftest
from aiter.moe import (
    get_aiter_moe_config,
    aiter_moe,
    aiter_moe_shfl_weight,
    MoeSolutionType,
    MoeQuantType,
)
import aiter

torch.set_default_device("cuda")


# ---------------------------------------------------------------------------
# Weight preparation helpers (W16A16 – no quantization)
# ---------------------------------------------------------------------------

def prepare_w16a16_inputs(m, k, n, e, topk, dtype):
    """Build all tensors needed to run a w16a16 MOE test.

    Returns a dict of tensors keyed by name.
    """
    torch.manual_seed(0)
    input_tensor = torch.randn((m, k), device="cuda", dtype=dtype) / 10
    w1 = torch.randn((e, 2 * n, k), device="cuda", dtype=dtype) / 2
    w2 = torch.randn((e, k, n), device="cuda", dtype=dtype) / 2
    score = torch.randn((m, e), device="cuda", dtype=dtype)

    topk_weights, topk_ids = fused_topk(input_tensor, score, topk, True)

    return {
        "input": input_tensor,
        "w1": w1,
        "w2": w2,
        "topk_weights": topk_weights,
        "topk_ids": topk_ids,
        "score": score,
    }

# ---------------------------------------------------------------------------
# Test: get_aiter_moe_config (w16a16)
# ---------------------------------------------------------------------------

def test_get_config(m, k, n, e, topk, dtype, use_shuffle=0):
    """Test that get_aiter_moe_config returns a valid w16a16 config or
    gracefully reports no-solution."""
    N1 = 2 * n  # gate + up
    N2 = k      # down / hidden_size
    K = k       # model dimension

    status, moe_cfg = get_aiter_moe_config(
        M=m, E=e, N1=N1, N2=N2, K=K,
        top_k=topk, block_size=0, dtype=dtype,
        quant_type=MoeQuantType.W16A16,
        use_shuffle=use_shuffle,
    )

    if status:
        assert moe_cfg.solution_type is not None, \
            "status=True but solution_type is None"
        assert moe_cfg.config is not None, \
            "status=True but config is None"
        assert moe_cfg.solution_type in (
            MoeSolutionType.ASM,
            MoeSolutionType.TRITON,
            MoeSolutionType.CK,
        ), f"Unexpected solution_type: {moe_cfg.solution_type}"
        assert moe_cfg.quant_type == MoeQuantType.W16A16
        aiter.logger.info(
            f"[get_config_w16a16] {m=}, {k=}, {n=}, {e=}, {topk=}, "
            f"use_shuffle={use_shuffle}, solution={moe_cfg.solution_type}, "
            f"need_shuffle={moe_cfg.need_shuffle}, "
            f"config keys={list(moe_cfg.config.keys())}"
        )
    else:
        assert moe_cfg.solution_type is None, \
            "status=False but solution_type is not None"
        assert moe_cfg.config is None, \
            "status=False but config is not None"
        aiter.logger.info(
            f"[get_config_w16a16] {m=}, {k=}, {n=}, {e=}, {topk=}, "
            f"use_shuffle={use_shuffle}, no solution found (expected on unsupported configs)"
        )

    return status, moe_cfg


# ---------------------------------------------------------------------------
# Test: aiter_moe end-to-end for w16a16
# ---------------------------------------------------------------------------

@perftest(num_warmup=1, num_iters=2)
def _run_torch_ref(hidden_states, w1, w2, topk_weights, topk_ids):
    return torch_moe(hidden_states, w1, w2, topk_weights, topk_ids)


@perftest(num_warmup=10, num_iters=100, num_rotate_args=1)
def _run_aiter_moe_perf(hidden_states,
        w1,
        w2,
        topk_weights,
        topk_ids,
        moe_config,
        inplace,
        activation,
        w1_scale,
        w2_scale,
        w1_zp,
        w2_zp,
        a1_scale,
        a2_scale,
        block_shape,
        global_num_experts,
        expert_map,
        routed_scaling_factor,
        use_shuffle,
        ):
    if inplace:
        mortal_input = hidden_states.clone()  # 保证inplace操作的正确性
    else:
        mortal_input = hidden_states
    return aiter_moe(mortal_input, w1, w2, topk_weights, topk_ids, moe_config, inplace, activation, w1_scale, w2_scale, w1_zp, w2_zp,
                     a1_scale, a2_scale, block_shape, global_num_experts, expert_map, routed_scaling_factor,
                     use_weight_shuffle=use_shuffle)


def test_aiter_moe_w16a16(m, k, n, e, topk, dtype, inplace, routed_scaling_factor, use_shuffle=0):
    """End-to-end: get config -> run aiter_moe -> compare with torch
    reference."""
    N1 = 2 * n
    N2 = k
    K = k

    status, moe_cfg = get_aiter_moe_config(
        M=m, E=e, N1=N1, N2=N2, K=K,
        top_k=topk, block_size=0, dtype=dtype,
        quant_type=MoeQuantType.W16A16,
        use_shuffle=use_shuffle,
    )

    if not status:
        aiter.logger.info(
            f"[aiter_moe_w16a16] SKIP {m=}, {N1=}, {N2=}, {K=}, {e=}, {topk=}: "
            f"no backend available"
        )
        return None

    backend = moe_cfg.solution_type
    aiter.logger.info(
        f"[aiter_moe_w16a16] {m=}, {N1=}, {N2=}, {K=}, {e=}, {topk=}, "
        f"backend={backend}"
    )

    data = prepare_w16a16_inputs(m, k, n, e, topk, dtype)

    # Torch reference
    ref_out, _ = _run_torch_ref(
        data["input"], data["w1"], data["w2"],
        data["topk_weights"], data["topk_ids"],
    )

    # Shuffle weights if the selected backend/config requires a preshuffled layout.
    w1_input, w2_input = data["w1"], data["w2"]
    if moe_cfg.need_shuffle:
        w1_input, w2_input = aiter_moe_shfl_weight(
            data["w1"], data["w2"], moe_cfg
        )

    # generic aiter_moe dispatch with w16a16 config
    aiter_out, aiter_us = _run_aiter_moe_perf(
        hidden_states=data["input"],
        w1=w1_input,
        w2=w2_input,
        topk_weights=data["topk_weights"],
        topk_ids=data["topk_ids"],
        moe_config=moe_cfg,
        inplace=inplace,
        activation="silu",
        w1_scale=None,
        w2_scale=None,
        w1_zp=None,
        w2_zp=None,
        a1_scale=None,
        a2_scale=None,
        block_shape=None,
        global_num_experts=e,
        expert_map=None,
        routed_scaling_factor=routed_scaling_factor,
        use_shuffle=use_shuffle,
    )

    msg = (f"[aiter_moe_w16a16] {m=}, {N1=}, {N2=}, {K=}, {e=}, {topk=}, "
           f"backend={backend}, use_shuffle={use_shuffle}, need_shuffle={moe_cfg.need_shuffle}")
    # Non-quantized bf16 matmul accumulation order differs between torch and
    # the fused triton/asm kernels, so we need a relaxed atol (matching
    # test_moe_w16a16.py which uses atol=1 for torch vs triton).
    assert torch.isfinite(aiter_out).all(), (
        "Non-finite output in test_aiter_moe_w16a16: "
        f"{m=}, {k=}, {n=}, {e=}, {topk=}, {dtype=}, "
        f"backend={backend}"
    )
    check_ret = checkAllclose(ref_out, aiter_out, rtol=0.01, atol=0.5, msg=msg)
    assert check_ret <= 0.03, (
        "Accuracy check failed in test_aiter_moe_w16a16: "
        f"{m=}, {k=}, {n=}, {N1=}, {N2=}, {K=}, {e=}, {topk=}, "
        f"{dtype=}, {inplace=}, {routed_scaling_factor=}, {use_shuffle=}, "
        f"backend={backend}, need_shuffle={moe_cfg.need_shuffle}, "
        f"error_ratio={check_ret:.6f}, tolerance=0.03"
    )
    ret_output = "passed" if check_ret == 0 else (1 - check_ret)
    return {"m": m, "k": k, "n": n, "e":e, "topk":topk,"backend": backend, "us": aiter_us, "accuracy": ret_output}


# ---------------------------------------------------------------------------
# Test: aiter_moe w16a16 ASM shuffle vs non-shuffle
# ---------------------------------------------------------------------------

def test_aiter_moe_w16a16_shuffle(m, k, n, e, topk, dtype, inplace, routed_scaling_factor):
    """Compare w16a16 ASM non-shuffle and shuffle paths via the public MOE APIs."""
    N1 = 2 * n
    N2 = k
    K = k

    status, moe_cfg = get_aiter_moe_config(
        M=m, E=e, N1=N1, N2=N2, K=K,
        top_k=topk, block_size=0, dtype=dtype,
        quant_type=MoeQuantType.W16A16,
        spec_sol_type=MoeSolutionType.ASM,
        use_shuffle=0,
    )
    if not status:
        aiter.logger.info(
            f"[w16a16_shuffle] SKIP {m=}: ASM non-shuffle config not available"
        )
        return None

    shuffle_status, shuffle_moe_cfg = get_aiter_moe_config(
        M=m, E=e, N1=N1, N2=N2, K=K,
        top_k=topk, block_size=0, dtype=dtype,
        quant_type=MoeQuantType.W16A16,
        spec_sol_type=MoeSolutionType.ASM,
        use_shuffle=1,
    )
    if not shuffle_status:
        aiter.logger.info(
            f"[w16a16_shuffle] SKIP {m=}: ASM shuffle config not available"
        )
        return None

    data = prepare_w16a16_inputs(m, k, n, e, topk, dtype)

    asm_out, asm_us = _run_aiter_moe_perf(
        hidden_states=data["input"],
        w1=data["w1"],
        w2=data["w2"],
        topk_weights=data["topk_weights"],
        topk_ids=data["topk_ids"],
        moe_config=moe_cfg,
        inplace=inplace,
        activation="silu",
        w1_scale=None,
        w2_scale=None,
        w1_zp=None,
        w2_zp=None,
        a1_scale=None,
        a2_scale=None,
        block_shape=None,
        global_num_experts=e,
        expert_map=None,
        routed_scaling_factor=routed_scaling_factor,
        use_shuffle=0,
    )

    w1_shuffle, w2_shuffle = data["w1"], data["w2"]
    if shuffle_moe_cfg.need_shuffle:
        w1_shuffle, w2_shuffle = aiter_moe_shfl_weight(
            data["w1"], data["w2"], shuffle_moe_cfg
        )

    shuffle_out, shuffle_us = _run_aiter_moe_perf(
        hidden_states=data["input"],
        w1=w1_shuffle,
        w2=w2_shuffle,
        topk_weights=data["topk_weights"],
        topk_ids=data["topk_ids"],
        moe_config=shuffle_moe_cfg,
        inplace=inplace,
        activation="silu",
        w1_scale=None,
        w2_scale=None,
        w1_zp=None,
        w2_zp=None,
        a1_scale=None,
        a2_scale=None,
        block_shape=None,
        global_num_experts=e,
        expert_map=None,
        routed_scaling_factor=routed_scaling_factor,
        use_shuffle=1,
    )

    msg = (f"[w16a16_shuffle] {m=}, {k=}, {n=}, {e=}, {topk=}, "
           f"asm_cfg={moe_cfg.config}, shuffle_cfg={shuffle_moe_cfg.config}, "
           f"asm_us={asm_us:.2f}, shuffle_us={shuffle_us:.2f}")
    assert torch.isfinite(shuffle_out).all(), (
        "Non-finite output in test_aiter_moe_w16a16_shuffle: "
        f"{m=}, {k=}, {n=}, {e=}, {topk=}, {dtype=}, "
        f"backend={shuffle_moe_cfg.solution_type}"
    )
    check_ret = checkAllclose(asm_out, shuffle_out, rtol=0.01, atol=0.01, msg=msg)
    assert check_ret <= 0.03, (
        "Accuracy check failed in test_aiter_moe_w16a16_shuffle: "
        f"{m=}, {k=}, {n=}, {N1=}, {N2=}, {K=}, {e=}, {topk=}, "
        f"{dtype=}, {inplace=}, {routed_scaling_factor=}, "
        f"asm_backend={moe_cfg.solution_type}, shuffle_backend={shuffle_moe_cfg.solution_type}, "
        f"error_ratio={check_ret:.6f}, tolerance=0.03"
    )
    ret_output = "passed" if check_ret == 0 else (1 - check_ret)
    uplift = asm_us / shuffle_us - 1 if shuffle_us > 0 else 0
    return {
        "m": m,
        "k": k,
        "n": n,
        "e": e,
        "topk": topk,
        "asm_us": asm_us,
        "shuffle_us": shuffle_us,
        "shuffle_uplift": f"{uplift:.1%}",
        "accuracy": ret_output
    }


# ---------------------------------------------------------------------------
# Main: run tests
# ---------------------------------------------------------------------------

if __name__ == "__main__":
    failed_cases = []

    def run_accuracy_case(test_func, *args, **kwargs):
        try:
            return test_func(*args, **kwargs)
        except AssertionError as exc:
            failed_cases.append(str(exc))
            print(f"[ACCURACY FAILED] {exc}", flush=True)
            return None

    dtype = dtypes.bf16
    PART2_CSV_OUTPUT = "w16a16_part2_aiter_moe.csv"
    PART3_CSV_OUTPUT = "w16a16_part3_shuffle.csv"
    
    # Pick a shape covered by tuned_fmoe_asm*.csv; otherwise the interface may
    # fall back to Triton and skip the ASM shuffle path.
    e = 256
    topk = 8
    k = 3072
    n = 128
    inplace = False
    routed_scaling_factor = 1.0
    use_shuffle = 0


    # --- Part 1: test get_aiter_moe_config (w16a16) ---
    aiter.logger.info("=" * 60)
    aiter.logger.info("Part 1: Testing get_aiter_moe_config for w16a16")
    aiter.logger.info("=" * 60)

    test_tokens = [1, 2, 4, 8, 16, 32, 64, 128, 256, 512, 1024, 2048, 4096]
    for m in test_tokens:
        test_get_config(m, k, n, e, topk, dtype, use_shuffle)

    # --- Part 2: test aiter_moe end-to-end (w16a16) ---
    aiter.logger.info("=" * 60)
    aiter.logger.info("Part 2: Testing aiter_moe end-to-end for w16a16")
    aiter.logger.info("=" * 60)

    df = []
    for m in test_tokens:
        ret = run_accuracy_case(
            test_aiter_moe_w16a16,
            m, k, n, e, topk, dtype, inplace, routed_scaling_factor, use_shuffle,
        )
        if ret is not None:
            df.append(ret)
    if df:
        df = pd.DataFrame(df)
        aiter.logger.info(f"aiter_moe summary:\n{df}")
        df.to_csv(PART2_CSV_OUTPUT, index=False)
        aiter.logger.info(f"aiter_moe summary csv saved to {PART2_CSV_OUTPUT}")

    # --- Part 3: test ASM shuffle vs non-shuffle (w16a16) ---
    aiter.logger.info("=" * 60)
    aiter.logger.info("Part 3: Testing ASM shuffle vs non-shuffle for w16a16")
    aiter.logger.info("=" * 60)

    df_shuffle = []
    for m in test_tokens:
        ret = run_accuracy_case(
            test_aiter_moe_w16a16_shuffle,
            m, k, n, e, topk, dtype, inplace, routed_scaling_factor,
        )
        if ret is not None:
            df_shuffle.append(ret)
    if df_shuffle:
        df_shuffle = pd.DataFrame(df_shuffle)
        aiter.logger.info(f"shuffle summary:\n{df_shuffle}")
        df_shuffle.to_csv(PART3_CSV_OUTPUT, index=False)
        aiter.logger.info(f"shuffle summary csv saved to {PART3_CSV_OUTPUT}")

    if failed_cases:
        details = "\n".join(
            f"[{index}] {message}"
            for index, message in enumerate(failed_cases, start=1)
        )
        raise AssertionError(
            f"{len(failed_cases)} accuracy case(s) failed:\n{details}"
        )

    # --- Part 4: test MOE_C vs ASM vs ASM shuffle (w16a16) ---
    # Keep this disabled by default because it is intended for local perf triage.
    #
    # PART4_CSV_OUTPUT = "w16a16_part4_moec_vs_asm_vs_shuffle.csv"
    # df_part4 = []
    # for m in test_tokens:
    #     data = prepare_w16a16_inputs(m, k, n, e, topk, dtype)
    #     asm_status, asm_cfg = get_aiter_moe_config(
    #         M=m, E=e, N1=2 * n, N2=k, K=k, top_k=topk, block_size=0,
    #         dtype=dtype, quant_type=MoeQuantType.W16A16,
    #         spec_sol_type=MoeSolutionType.ASM, use_shuffle=0)
    #     shuffle_status, shuffle_cfg = get_aiter_moe_config(
    #         M=m, E=e, N1=2 * n, N2=k, K=k, top_k=topk, block_size=0,
    #         dtype=dtype, quant_type=MoeQuantType.W16A16,
    #         spec_sol_type=MoeSolutionType.ASM, use_shuffle=1)
    #     moe_c_status, moe_c_cfg = get_aiter_moe_config(
    #         M=m, E=e, N1=2 * n, N2=k, K=k, top_k=topk, block_size=0,
    #         dtype=dtype, quant_type=MoeQuantType.W16A16,
    #         spec_sol_type=MoeSolutionType.MOE_C, use_shuffle=1)
    #     if not (asm_status and shuffle_status and moe_c_status):
    #         continue
    #
    #     shuffle_w1, shuffle_w2 = aiter_moe_shfl_weight(
    #         data["w1"], data["w2"], shuffle_cfg)
    #     moe_c_w1, moe_c_w2 = aiter_moe_shfl_weight(
    #         data["w1"], data["w2"], moe_c_cfg)
    #
    #     asm_out, asm_us = _run_aiter_moe_perf(
    #         data["input"], data["w1"], data["w2"], data["topk_weights"],
    #         data["topk_ids"], asm_cfg, inplace, "silu", None, None, None,
    #         None, None, None, None, e, None, routed_scaling_factor, 0)
    #     shuffle_out, shuffle_us = _run_aiter_moe_perf(
    #         data["input"], shuffle_w1, shuffle_w2, data["topk_weights"],
    #         data["topk_ids"], shuffle_cfg, inplace, "silu", None, None,
    #         None, None, None, None, e, None, routed_scaling_factor, 1)
    #     moe_c_out, moe_c_us = _run_aiter_moe_perf(
    #         data["input"], moe_c_w1, moe_c_w2, data["topk_weights"],
    #         data["topk_ids"], moe_c_cfg, inplace, "silu", None, None, None,
    #         None, None, None, None, e, None, routed_scaling_factor, 1)
    #
    #     checkAllclose(asm_out, shuffle_out, rtol=0.01, atol=0.5,
    #                   msg=f"[part4] asm vs asm shuffle {m=}")
    #     checkAllclose(asm_out, moe_c_out, rtol=0.01, atol=0.5,
    #                   msg=f"[part4] asm vs moe_c {m=}")
    #     df_part4.append({
    #         "m": m,
    #         "asm_us": asm_us,
    #         "asm_shuffle_us": shuffle_us,
    #         "moe_c_us": moe_c_us,
    #     })
    # if df_part4:
    #     df_part4 = pd.DataFrame(df_part4)
    #     aiter.logger.info(f"part4 summary:\n{df_part4}")
    #     df_part4.to_csv(PART4_CSV_OUTPUT, index=False)
