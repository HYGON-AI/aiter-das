# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""Regression coverage for ASM masks including shared experts and a sentinel."""
import numpy as np
import torch
from unittest.mock import patch

from aiter.fused_moe_asm_wna16 import _resolve_sorting_num_experts, moe_sorting_ck
from aiter.ops.triton.fused_moe import triton_moe_sum
from .moe_sorting_invalid_cases import SortingCase, reference


def make_case(m, rank, shared, sentinel, unit=32, all_invalid=False):
    e = 512 + shared + int(sentinel)
    case = SortingCase(m, e, 10, unit=unit)
    case.mask_cpu = np.zeros(e, np.int32)
    case.mask_cpu[rank * 128 : (rank + 1) * 128] = 1
    case.mask_cpu[512 : 512 + shared] = 1
    case.mask = torch.from_numpy(case.mask_cpu).to("cuda")
    routes = [rank * 128, rank * 128 + 127, ((rank + 1) % 4) * 128,
              rank * 128 + 64, 512, 513, 514, -1, -(2**31), 2**31 - 1]
    case.ids_cpu = np.tile(np.array(routes, np.int32), (m, 1))
    if all_invalid:
        case.ids_cpu.fill(-1)
    case.ids.copy_(torch.from_numpy(case.ids_cpu))
    return case


def check_wrapper(case):
    e = _resolve_sorting_num_experts(512, case.mask)
    result = moe_sorting_ck(case.ids, case.weights, e, 16, case.buf,
                            case.unit, case.mask)
    ids, weights, experts, total, positions, _ = result
    expected = reference(case.ids_cpu, case.weights_cpu, e, case.unit, case.mask_cpu)
    n = expected[-1]
    assert total.item() == n
    for actual, ref in zip((ids[:n], weights[:n], experts[:n // case.unit], positions),
                           expected[:-1]):
        np.testing.assert_array_equal(actual.cpu().numpy(), ref)
    if n:
        assert experts[:n // case.unit].max().item() < int(case.mask_cpu.sum())
    assert torch.count_nonzero(case.buf).item() == 0


def sum_inputs(case, dtype, n):
    ids = case.ids_cpu
    valid = (ids >= 0) & (ids < case.e)
    valid[valid] &= case.mask_cpu[ids[valid]] != 0
    values = (np.arange(case.m * case.k * n).reshape(case.m, case.k, n) % 17 - 8) / 16
    values[~valid] = np.nan
    x = torch.tensor(values, dtype=dtype, device="cuda")
    out = torch.empty((case.m, n), dtype=dtype, device="cuda")
    expected = torch.tensor(np.where(valid[..., None], values, 0).sum(1) * 0.75,
                            dtype=dtype, device="cuda")
    return x, out, expected


def check_sum(case, dtype, n):
    x, out, expected = sum_inputs(case, dtype, n)
    triton_moe_sum(x, out, 0.75, topk_ids=case.ids,
                   num_experts=_resolve_sorting_num_experts(512, case.mask),
                   expert_mask=case.mask)
    torch.testing.assert_close(out, expected, rtol=0, atol=0)


def check_graph(m):
    case = make_case(m, 0, 1, True)
    x, out, expected = sum_inputs(case, torch.float32, 17)
    stream = torch.cuda.Stream()
    stream.wait_stream(torch.cuda.current_stream())

    def run():
        e = _resolve_sorting_num_experts(512, case.mask)
        sorted_result = moe_sorting_ck(case.ids, case.weights, e, 16, case.buf,
                                      case.unit, case.mask)
        triton_moe_sum(x, out, 0.75, topk_ids=case.ids, num_experts=e, expert_mask=case.mask)
        return sorted_result

    with torch.cuda.stream(stream):
        run()
    stream.synchronize()
    graph = torch.cuda.CUDAGraph()
    with torch.cuda.graph(graph, stream=stream):
        result = run()
    for rank, empty in ((0, False), (3, False), (1, True), (2, False)):
        changed = make_case(m, rank, 1, True, all_invalid=empty)
        case.ids.copy_(changed.ids)
        case.mask.copy_(changed.mask)
        changed_x, _, expected = sum_inputs(changed, torch.float32, 17)
        x.copy_(changed_x)
        graph.replay()
        ids, weights, experts, total, positions, _ = result
        ref = reference(changed.ids_cpu, changed.weights_cpu, changed.e, changed.unit,
                        changed.mask_cpu)
        n = ref[-1]
        assert total.item() == n
        for actual, wanted in zip((ids[:n], weights[:n], experts[:n // case.unit], positions), ref[:-1]):
            np.testing.assert_array_equal(actual.cpu().numpy(), wanted)
        torch.testing.assert_close(out, expected, rtol=0, atol=0)
    return 4


def check_metadata():
    assert _resolve_sorting_num_experts(512, None) == 512
    for e in (512, 513, 514, 515):
        assert _resolve_sorting_num_experts(512, torch.empty(e, dtype=torch.int32)) == e
    for mask in (torch.empty(513, 1, dtype=torch.int32), torch.empty(513),
                 torch.empty(511, dtype=torch.int32), torch.empty(1026, dtype=torch.int32)[::2]):
        try:
            _resolve_sorting_num_experts(512, mask)
        except ValueError:
            pass
        else:
            raise AssertionError("invalid mask metadata accepted")
    # A high-level adapter must not weaken the direct C++ ABI.
    case = make_case(7, 0, 0, True)
    args = case.args()
    args[8] = 512
    try:
        import aiter
        aiter.moe_sorting_fwd(*args)
    except RuntimeError as exc:
        assert "length-num_experts" in str(exc)
    else:
        raise AssertionError("C++ accepted a mismatched mask")
    return 10


def check_asm_dispatch_domains():
    """Exercise each public ASM branch up to sorting, without requiring its GEMM."""
    import aiter.fused_moe_asm_wna16 as asm

    class SortingReached(Exception):
        pass

    mask = torch.zeros(514, dtype=torch.int32, device="cpu")
    mask[:128] = 1
    mask[512] = 1

    def check_sorting(ids, weights, e, model_dim, buf, unit, expert_mask):
        assert e == 514, f"ASM branch passed routed E={e} instead of the mask domain"
        assert expert_mask is mask
        raise SortingReached

    config = dict(BLOCK_SIZE_M=16, SOL_ID1=10000, SOL_ID2=20000,
                  PERSIST_GROUP1=0, PERSIST_GROUP2=0)
    branches = [dict(use_int4_w4a16=True),
                dict(use_int8_w8a8=True, per_channel_quant=True),
                dict(use_int8_w4a8=True, block_shape=[0, 64]),
                dict(use_int8_w8a8=True),
                dict(use_fp8_w8a8=True, per_channel_quant=True),
                dict(use_fp8_w8a8=True), dict()]
    with patch.object(asm, "moe_sorting_ck", side_effect=check_sorting), \
         patch.object(asm, "get_gfx", return_value="gfx938"), \
         patch.object(asm, "get_cu_num", return_value=64), \
         patch.object(asm, "decode_sol_w4a16", return_value=config), \
         patch.object(asm, "decode_sol_0", return_value=config), \
         patch.object(asm, "decode_sol_w8a8_c", return_value=config):
        for flags in branches:
            packed = flags.get("use_int4_w4a16") or flags.get("use_int8_w4a8")
            x = torch.empty((1, 256), dtype=torch.float16, device="cpu")
            # Only tensor metadata is consumed before the intercepted sorting call.
            w1 = torch.empty((129, 256, 128 if packed else 256), device="cpu")
            w2 = torch.empty((129, 256, 64 if packed else 128), device="cpu")
            ids = torch.zeros((1, 8), dtype=torch.int32, device="cpu")
            weights = torch.ones((1, 8), dtype=torch.float32, device="cpu")
            try:
                asm.fused_experts_asm_impl(x, w1, w2, weights, ids, torch.float16,
                    global_num_experts=512, expert_map=mask, solution_id="10000+20000", **flags)
            except SortingReached:
                continue
            raise AssertionError(f"ASM branch did not reach sorting: {flags}")
    return len(branches)


def run_mask_abi_suite(smoke=False):
    dispatch = check_asm_dispatch_domains()
    metadata = check_metadata()
    count = sums = 0
    for m in ((7, 513) if smoke else (0, 1, 7, 31, 511, 512, 513, 4096)):
        for rank in range(4):
            for shared, sentinel in ((0, False), (0, True), (1, True), (2, True)):
                for invalid in (False, True):
                    case = make_case(m, rank, shared, sentinel,
                                     unit=(16, 32, 64)[count % 3], all_invalid=invalid)
                    case.run()
                    case.check()
                    check_wrapper(case)
                    count += 1
                    for dtype in (torch.float16, torch.bfloat16, torch.float32):
                        check_sum(case, dtype, 17 if count % 2 else 256)
                        sums += 1
        print(f"MASK_ABI cases passed M={m}", flush=True)
    graphs = sum(check_graph(m) for m in (7, 513))
    print(f"MASK_ABI_PASS sorting={count} sums={sums} metadata={metadata} graph_replays={graphs} dispatch={dispatch}", flush=True)
