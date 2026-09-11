# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""Focused regression checks for skipped routes and asynchronous sorting outputs."""
import numpy as np
import torch
import aiter


def route_ids(m, e, k, mode):
    ids = ((np.arange(m)[:, None] * 7 + np.arange(k)) % e).astype(np.int32)
    if mode == "all":
        ids.fill(-1)
    elif mode == "mixed":
        ids.reshape(-1)[::3] = -1
    elif mode == "rows":
        ids[::2] = -1
    elif mode == "bounds":
        bad = np.array([-1, -2, -(2**31), e, e + 1, 2**31 - 1], np.int32)
        ids.reshape(-1)[::2] = np.resize(bad, ids.reshape(-1)[::2].size)
    return ids


def reference(ids, weights, e, unit, mask):
    m, k = ids.shape
    flat = ids.reshape(-1)
    selected = np.flatnonzero((flat >= 0) & (flat < e))
    if mask is not None:
        selected = selected[mask[flat[selected]] != 0]
    selected = selected[np.argsort(flat[selected], kind="stable")]
    counts = np.bincount(flat[selected], minlength=e).astype(np.int32)
    padded = ((counts + unit - 1) // unit) * unit
    offsets = np.concatenate(([0], np.cumsum(padded)[:-1])).astype(np.int32)
    n = int(padded.sum())
    sentinel = np.array((k << 24) | m, dtype=np.uint32).view(np.int32).item()
    sorted_ids = np.full(n, sentinel, np.int32)
    sorted_w = np.zeros(n, np.float32)
    local = np.arange(e) if mask is None else np.cumsum(mask) - 1
    sorted_e = np.repeat(local, padded // unit).astype(np.int32)
    begin = 0
    for expert, count in enumerate(counts):
        routes = selected[begin : begin + count]
        out = slice(offsets[expert], offsets[expert] + count)
        sorted_ids[out] = ((routes % k) << 24) | (routes // k)
        sorted_w[out] = weights.reshape(-1)[routes]
        begin += count
    return sorted_ids, sorted_w, sorted_e, np.concatenate((counts, offsets)), n


class SortingCase:
    def __init__(self, m, e, k, unit=32, mode="valid", mask_kind="none", with_buf=True):
        self.m, self.e, self.k, self.unit = m, e, k, unit
        self.ids_cpu = route_ids(m, e, k, mode)
        self.weights_cpu = (np.arange(m * k, dtype=np.float32).reshape(m, k) % 23) / 16
        self.mask_cpu = None
        if mask_kind != "none":
            self.mask_cpu = np.ones(e, np.int32)
            if mask_kind == "even":
                self.mask_cpu[1::2] = 0
            elif mask_kind == "zero":
                self.mask_cpu.fill(0)
        self.ids = torch.from_numpy(self.ids_cpu).to("cuda")
        self.weights = torch.from_numpy(self.weights_cpu).to("cuda")
        self.mask = None if self.mask_cpu is None else torch.from_numpy(self.mask_cpu).to("cuda")
        capacity = m * k + e * unit - k if m else 0
        self.owners = []

        def output(n, dtype):
            owner = torch.full((n + 32,), -777, dtype=dtype, device="cuda")
            self.owners.append(owner)
            return owner[16:-16]

        self.sorted_ids = output(capacity, torch.int32)
        self.sorted_w = output(capacity, torch.float32)
        self.sorted_e = output((capacity + unit - 1) // unit, torch.int32)
        self.positions = output(e * 2, torch.int32)
        self.total = output(1, torch.int32)
        self.buf = torch.full((m, 16), 13.0, device="cuda") if with_buf else None

    def args(self):
        return [self.ids, self.weights, self.sorted_ids, self.sorted_w, self.sorted_e,
                self.positions, self.total, self.buf, self.e, self.unit, self.mask]

    def run(self):
        aiter.moe_sorting_fwd(*self.args())

    def check(self):
        ids, weights, experts, positions, n = reference(
            self.ids_cpu, self.weights_cpu, self.e, self.unit, self.mask_cpu)
        assert self.total.item() == n, (self.total.item(), n)
        for actual, expected in ((self.sorted_ids[:n], ids), (self.sorted_w[:n], weights),
                                 (self.sorted_e[:n // self.unit], experts), (self.positions, positions)):
            np.testing.assert_array_equal(actual.cpu().numpy(), expected)
        for owner in self.owners:
            assert torch.all(owner[:16] == -777) and torch.all(owner[-16:] == -777)
        if self.buf is not None:
            assert torch.count_nonzero(self.buf).item() == 0


def check_bad_arguments():
    case = SortingCase(17, 32, 5)
    bad = [
        (0, case.ids.to(torch.int64)), (0, case.ids.cpu()),
        (0, case.ids.t().contiguous().t()), (0, case.ids.flatten()),
        (1, case.weights.to(torch.float16)), (1, case.weights[:, :4]),
        (2, case.sorted_ids[:1]), (2, case.sorted_ids.to(torch.int64)),
        (3, case.sorted_w.cpu()), (4, case.sorted_e[:1]),
        (5, case.positions[:1]), (6, case.total[:0]),
        (7, torch.empty(3, device="cuda")), (8, 0), (9, 0),
        (8, -1), (9, -32), (8, 4),
        (10, torch.ones(31, dtype=torch.int32, device="cuda")),
        (10, torch.ones(32, dtype=torch.bool, device="cuda")),
    ]
    for index, tensor in bad:
        args = case.args()
        args[index] = tensor
        try:
            aiter.moe_sorting_fwd(*args)
        except (RuntimeError, ValueError, TypeError):
            pass
        else:
            raise AssertionError(f"bad argument {index} was accepted")
    args = case.args()
    args[0] = torch.empty((17, 0), dtype=torch.int32, device="cuda")
    args[1] = torch.empty((17, 0), dtype=torch.float32, device="cuda")
    try:
        aiter.moe_sorting_fwd(*args)
    except (RuntimeError, ValueError, TypeError):
        pass
    else:
        raise AssertionError("topk=0 was accepted")
    for owner in case.owners:
        assert torch.all(owner == -777)
    return len(bad) + 1


def check_graph(m, mask_kind):
    case = SortingCase(m, 512, 10, mask_kind=mask_kind)
    stream = torch.cuda.Stream()
    stream.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(stream):
        case.run()
    stream.synchronize()
    graph = torch.cuda.CUDAGraph()
    with torch.cuda.graph(graph, stream=stream):
        case.run()
    for mode in ("valid", "all", "bounds", "rows", "valid"):
        case.ids_cpu = route_ids(m, 512, 10, mode)
        case.ids.copy_(torch.from_numpy(case.ids_cpu))
        for owner in case.owners:
            owner[16:-16].fill_(-777)
        case.buf.fill_(13)
        graph.replay()
        case.check()
        # Exercise allocator reuse between replays without changing graph storage.
        scratch = torch.empty(4_196_480, dtype=torch.uint8, device="cuda")
        scratch.fill_(0xA5)
        del scratch


def run_invalid_suite(smoke=False):
    shapes = [(0, 512, 10), (1, 32, 5), (7, 512, 10), (16, 512, 10),
              (17, 512, 10), (32, 32, 5), (64, 32, 5), (511, 512, 10),
              (512, 512, 10), (513, 512, 3), (8192, 512, 10)]
    if smoke:
        shapes = [(7, 512, 10), (8192, 512, 10)]
    count = 0
    for index, (m, e, k) in enumerate(shapes):
        for mode in ("valid", "all", "mixed", "rows", "bounds"):
            for mask in ("none", "one", "even", "zero"):
                for with_buf in (False, True):
                    # Alternating streams catches accidental default-stream launches.
                    stream = torch.cuda.Stream() if count % 2 else torch.cuda.current_stream()
                    with torch.cuda.stream(stream):
                        case = SortingCase(m, e, k, (16, 32, 64)[index % 3], mode, mask, with_buf)
                        case.run()
                        case.check()
                    count += 1
        print(f"invalid route cases passed: M={m} E={e} K={k}", flush=True)
    bad = check_bad_arguments()
    graphs = 0
    for m in (7, 8192):
        for mask in ("none", "even", "zero"):
            check_graph(m, mask)
            graphs += 5
    print(f"INVALID_SORTING_PASS cases={count} bad_args={bad} graph_replays={graphs}", flush=True)
