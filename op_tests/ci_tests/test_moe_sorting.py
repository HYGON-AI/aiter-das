# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
import torch
from typing import Tuple
import aiter
from aiter.test_common import checkAllclose, perftest, benchmark
from aiter.fused_moe import moe_sorting, fused_topk
from aiter import dtypes

BLOCK_SIZE_M = 32

failed_cases = []


def record_failures(test_name, result, **case_info):
    failed_outputs = [name for name, status in result.items() if status == "failed"]
    if not failed_outputs:
        return

    details = ", ".join(f"{name}={value}" for name, value in case_info.items())
    failed_cases.append(
        f"{test_name}: {details}, failed_outputs={failed_outputs}"
    )


@perftest(num_iters=3, num_warmup=0)
def test_moe_sorting_naive(
    topk_ids: torch.Tensor,
    topk_weights: torch.Tensor,
    num_experts: int,
    expert_mask=None,
) -> Tuple[torch.Tensor, torch.Tensor, torch.Tensor]:

    block_size = BLOCK_SIZE_M

    device = topk_ids.device
    M, topk = topk_ids.shape
    topk = topk_ids.shape[1]
    max_num_tokens_padded = topk_ids.numel() + num_experts * block_size - topk
    max_num_m_blocks = int((max_num_tokens_padded + block_size - 1) // block_size)
    init_val = topk << 24 | M
    sorted_ids = torch.full(
        (max_num_tokens_padded,), init_val, dtype=dtypes.i32, device=device
    )
    sorted_weights = torch.zeros(
        (max_num_tokens_padded,), dtype=dtypes.fp32, device=device
    )
    sorted_expert_ids = torch.full(
        (max_num_m_blocks,), -1, dtype=dtypes.i32, device=device
    )
    num_tokens_post_pad = torch.empty((1), dtype=dtypes.i32, device=device)

    sorted_ids_begin = 0
    sorted_expert_ids_begin = 0
    skip_expert_num = 0
    for expertId in range(num_experts):
        if expert_mask != None and expert_mask[expertId] == 0:
            skip_expert_num += 1
            continue
        token_id, topk_id = torch.where(topk_ids == expertId)
        tokensNum = token_id.numel()
        sorted_expert_ids_num = (tokensNum + block_size - 1) // block_size
        tokensNumPad = sorted_expert_ids_num * block_size
        sorted_ids[sorted_ids_begin : sorted_ids_begin + tokensNum] = (
            topk_id << 24 | token_id
        )
        sorted_weights[sorted_ids_begin : sorted_ids_begin + tokensNum] = topk_weights[
            token_id, topk_id
        ]
        sorted_ids_begin = sorted_ids_begin + tokensNumPad
        sorted_expert_ids[
            sorted_expert_ids_begin : sorted_expert_ids_begin + sorted_expert_ids_num
        ] = (expertId - skip_expert_num)
        sorted_expert_ids_begin = sorted_expert_ids_begin + sorted_expert_ids_num

    num_tokens_post_pad[0] = sorted_ids_begin

    return sorted_ids, sorted_weights, sorted_expert_ids, num_tokens_post_pad


@perftest()
def test_moe_sorting_ck(
    topk_ids, topk_weights, num_experts, model_dim, moebuf_dtype, expert_mask=None
):
    return moe_sorting(
        topk_ids,
        topk_weights,
        num_experts,
        model_dim,
        moebuf_dtype,
        expert_mask=expert_mask,
    )

@perftest()
def test_moe_sorting_ck_no_moebuf(
    topk_ids, topk_weights, num_experts, block_size=BLOCK_SIZE_M, expert_mask=None
):
    device = topk_ids.device
    M, topk = topk_ids.shape
    max_num_tokens_padded = topk_ids.numel() + num_experts * block_size - topk
    max_num_m_blocks = int((max_num_tokens_padded + block_size - 1) // block_size)
    sorted_ids = torch.empty((max_num_tokens_padded,), dtype=dtypes.i32, device=device)
    sorted_weights = torch.empty(
        (max_num_tokens_padded,), dtype=dtypes.fp32, device=device
    )
    sorted_expert_ids = torch.empty(
        (max_num_m_blocks,), dtype=dtypes.i32, device=device
    )
    tokens_positions_per_expert = torch.empty(
        (num_experts * 2,), dtype=dtypes.i32, device=device
    )
    num_valid_ids = torch.empty((1,), dtype=dtypes.i32, device=device)

    if topk_ids.dtype != dtypes.i32:
        topk_ids = topk_ids.to(dtypes.i32)

    aiter.moe_sorting_fwd(
        topk_ids,
        topk_weights,
        sorted_ids,
        sorted_weights,
        sorted_expert_ids,
        tokens_positions_per_expert,
        num_valid_ids,
        None,  # moe_buf=None
        num_experts,
        block_size,
        expert_mask,
    )
    return sorted_ids, sorted_weights, sorted_expert_ids, num_valid_ids

@benchmark()
def test_moe_sorting(
    dtype, token, model_dim, inter_dim, E, topk, has_expert_mask=False
):
    dim = (token, model_dim, inter_dim)
    input = torch.randn((token, model_dim), dtype=dtype, device="cuda")
    score = torch.rand((token, E), device="cuda", dtype=dtype)

    topk_weights, topk_ids = fused_topk(input, score, topk, True)

    expert_mask = (
        torch.randint(0, 2, (E,), dtype=topk_ids.dtype, device="cuda")
        if has_expert_mask
        else None
    )

    (
        sorted_ids_a,
        sorted_weights_a,
        sorted_expert_ids_a,
        num_tokens_post_padded_a,
    ), avg_a = test_moe_sorting_naive(topk_ids, topk_weights, E, expert_mask)

    (
        sorted_ids_b,
        sorted_weights_b,
        sorted_expert_ids_b,
        num_tokens_post_padded_b,
        tokens_per_expert_b,
        moe_buf,
    ), avg_b = test_moe_sorting_ck(
        topk_ids, topk_weights, E, model_dim, dtype, expert_mask
    )

    print(
        f"[perf] {token=}, {model_dim=}, {inter_dim=}, {E=}, {topk=}, dtype: {dtype}, torch avg: {avg_a:<8.2f} us, ck avg: {avg_b:<8.2f} us, uplift: {avg_a/avg_b-1:<5.1%}"
    )  
    num_tokens_post_padded_ret = checkAllclose(
        num_tokens_post_padded_a,
        num_tokens_post_padded_b,
        atol=0,
        msg="num_tokens_post_padded",
        )
    num_tokens_post_padded_acc = "passed" if num_tokens_post_padded_ret == 0 else "failed"
    
    mask = sorted_ids_a != (topk << 24 | token)
    num_tokens_post_pad = num_tokens_post_padded_a.item()
    sorted_ids_ret = checkAllclose(
        sorted_ids_a[:num_tokens_post_pad],
        sorted_ids_b[:num_tokens_post_pad],
        msg="sorted_ids",
        )
    sorted_ids_acc = "passed" if sorted_ids_ret == 0 else "failed"
    
    sorted_weights_ret = checkAllclose(
        sorted_weights_a[mask], 
        sorted_weights_b[mask], 
        msg="sorted_weights"
        )
    sorted_weights_acc = "passed" if sorted_weights_ret <= 0.03 else "failed"
    
    expert_mask = sorted_expert_ids_a != -1
    sorted_expert_ids_ret = checkAllclose(
        sorted_expert_ids_a[expert_mask],
        sorted_expert_ids_b[expert_mask],
        msg="sorted_expert_ids",
        )
    sorted_expert_ids_acc = "passed" if sorted_expert_ids_ret == 0 else "failed"
    
    return {"us": avg_b, 
            "num_tokens_post_padded_out": num_tokens_post_padded_acc, 
            "sorted_ids_out": sorted_ids_acc,
            "sorted_weights_out": sorted_weights_acc,
            "sorted_expert_ids_out": sorted_expert_ids_acc
            }

@benchmark()
def test_moe_sorting_none_moebuf(
    dtype, token, model_dim, inter_dim, E, topk, has_expert_mask=False
):
    input = torch.randn((token, model_dim), dtype=dtype, device="cuda")
    score = torch.rand((token, E), device="cuda", dtype=dtype)

    topk_weights, topk_ids = fused_topk(input, score, topk, True)

    expert_mask = (
        torch.randint(0, 2, (E,), dtype=topk_ids.dtype, device="cuda")
        if has_expert_mask
        else None
    )

    (
        sorted_ids_a,
        sorted_weights_a,
        sorted_expert_ids_a,
        num_tokens_post_padded_a,
    ), avg_a = test_moe_sorting_naive(topk_ids, topk_weights, E, expert_mask)

    (
        sorted_ids_b,
        sorted_weights_b,
        sorted_expert_ids_b,
        num_tokens_post_padded_b,
    ), avg_b = test_moe_sorting_ck_no_moebuf(
        topk_ids, topk_weights, E, expert_mask=expert_mask
    )

    print(
        f"[perf-none-moebuf] {token=}, {model_dim=}, {inter_dim=}, {E=}, {topk=}, dtype: {dtype}, torch avg: {avg_a:<8.2f} us, ck avg: {avg_b:<8.2f} us, uplift: {avg_a/avg_b-1:<5.1%}"
    )
    num_tokens_post_padded_ret = checkAllclose(
        num_tokens_post_padded_a,
        num_tokens_post_padded_b,
        atol=0,
        msg="num_tokens_post_padded",
    )
    num_tokens_post_padded_acc = "passed" if num_tokens_post_padded_ret == 0 else "failed"
    
    mask = sorted_ids_a != (topk << 24 | token)
    num_tokens_post_pad = num_tokens_post_padded_a.item()
    sorted_ids_ret = checkAllclose(
        sorted_ids_a[:num_tokens_post_pad],
        sorted_ids_b[:num_tokens_post_pad],
        msg="sorted_ids",
        )
    sorted_ids_acc = "passed" if sorted_ids_ret == 0 else "failed"
    
    sorted_weights_ret = checkAllclose(
        sorted_weights_a[mask], 
        sorted_weights_b[mask], 
        msg="sorted_weights"
        )
    sorted_weights_acc = "passed" if sorted_weights_ret <= 0.03 else "failed"
    
    expert_mask = sorted_expert_ids_a != -1
    sorted_expert_ids_ret = checkAllclose(
        sorted_expert_ids_a[expert_mask],
        sorted_expert_ids_b[expert_mask],
        msg="sorted_expert_ids",
        )
    sorted_expert_ids_acc = "passed" if sorted_expert_ids_ret == 0 else "failed"
    
    return {"us": avg_b, 
            "num_tokens_post_padded_out": num_tokens_post_padded_acc, 
            "sorted_ids_out": sorted_ids_acc,
            "sorted_weights_out": sorted_weights_acc,
            "sorted_expert_ids_out": sorted_expert_ids_acc
            }
    
def run_legacy_suite():
    import pandas as pd

    df = []
    print("test test_moe_sorting, no expert mask")
    for dtype in [dtypes.bf16]:
        for m in [1, 7, 31, 64, 128, 256, 163840][:]:
            for E in [3, 5, 32, 40, 256][:]:
                for top in [5, 8][:]:
                    if top > E:
                        continue
                    ret = test_moe_sorting(dtype, m, 7168, 4096, E, top)
                    record_failures(
                        "test_moe_sorting",
                        ret,
                        token=m,
                        model_dim=7168,
                        inter_dim=4096,
                        E=E,
                        topk=top,
                        dtype=dtype,
                        has_expert_mask=False,
                    )
                    df.append(ret)
    df = pd.DataFrame(df)
    df.to_csv("moe_sorting_no_expert_mask.csv", index=False)
    aiter.logger.info(f"summary:\n{df}")


    df = []
    print("test test_moe_sorting, with expert mask")
    for dtype in [dtypes.bf16]:
        for m in [1, 7, 31, 64, 128, 256, 163840]:
            for E in [3, 5, 32, 40, 256]:
                for top in [5, 8]:
                    if top > E:
                        continue
                    ret = test_moe_sorting(
                        dtype, m, 4096, 4096, E, top, has_expert_mask=True
                    )
                    record_failures(
                        "test_moe_sorting",
                        ret,
                        token=m,
                        model_dim=4096,
                        inter_dim=4096,
                        E=E,
                        topk=top,
                        dtype=dtype,
                        has_expert_mask=True,
                    )
                    df.append(ret)
    df = pd.DataFrame(df)
    df.to_csv("moe_sorting_with_expert_mask.csv", index=False)
    aiter.logger.info(f"summary:\n{df}")

    df = []
    print("test test_moe_sorting_none_moebuf, no expert mask")
    for dtype in [dtypes.bf16]:
        for m in [1, 7, 31, 64, 128, 256, 163840][:]:
            for E in [3, 5, 32, 40, 96, 192, 256][:]:
                for top in [5, 8][:]:
                    if top > E:
                         continue
                    ret = test_moe_sorting_none_moebuf(dtype, m, 7168, 4096, E, top)
                    record_failures(
                        "test_moe_sorting_none_moebuf",
                        ret,
                        token=m,
                        model_dim=7168,
                        inter_dim=4096,
                        E=E,
                        topk=top,
                        dtype=dtype,
                        has_expert_mask=False,
                    )
                    df.append(ret)
    df = pd.DataFrame(df)
    df.to_csv("moe_sorting_none_moebuf_no_expert_mask.csv", index=False)
    aiter.logger.info(f"summary-none-moebuf:\n{df}")


    df = []
    print("test test_moe_sorting_none_moebuf, with expert mask")
    for dtype in [dtypes.bf16]:
        for m in [1, 7, 31, 64, 128, 256, 163840]:
            for E in [3, 5, 32, 40, 96, 192, 256]:
                for top in [5, 8]:
                    if top > E:
                         continue
                    ret = test_moe_sorting_none_moebuf(
                        dtype, m, 4096, 4096, E, top, has_expert_mask=True
                    )
                    record_failures(
                        "test_moe_sorting_none_moebuf",
                        ret,
                        token=m,
                        model_dim=4096,
                        inter_dim=4096,
                        E=E,
                        topk=top,
                        dtype=dtype,
                        has_expert_mask=True,
                    )
                    df.append(ret)
    df = pd.DataFrame(df)
    df.to_csv("moe_sorting_none_moebuf_with_expert_mask.csv", index=False)
    aiter.logger.info(f"summary-none-moebuf-mask:\n{df}")

    if failed_cases:
        raise AssertionError(
            f"moe sorting correctness failures ({len(failed_cases)} cases):\n"
            + "\n".join(failed_cases)
        )


if __name__ == "__main__":
    import argparse
    parser = argparse.ArgumentParser()
    parser.add_argument("--invalid-routes", action="store_true")
    parser.add_argument("--mask-abi", action="store_true")
    parser.add_argument("--smoke", action="store_true")
    options = parser.parse_args()
    if options.mask_abi:
        if __package__:
            from .moe_sorting_res.moe_mask_abi_cases import run_mask_abi_suite
        else:
            from moe_sorting_res.moe_mask_abi_cases import run_mask_abi_suite
        run_mask_abi_suite(smoke=options.smoke)
    elif options.invalid_routes:
        if __package__:
            from .moe_sorting_res.moe_sorting_invalid_cases import run_invalid_suite
        else:
            from moe_sorting_res.moe_sorting_invalid_cases import run_invalid_suite
        run_invalid_suite(smoke=options.smoke)
    else:
        run_legacy_suite()
