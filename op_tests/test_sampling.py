# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""Correctness tests for top-k / top-p / top-k+top-p sampling.

Strategy: sample a large number of tokens per batch row, then verify every
sampled token id lies in the reference "allowed" set produced by a pure-torch
top-k/top-p mask.

Additional cases:
  greedy  : top_k=1 (and vanishing top_p) must be exact argmax sampling
  edge    : tiny shapes, disabled filters, zero-probability support,
            two-token distribution frequency
  mixed   : per-row heterogeneous k/p arrays (non-constant tensor values)
  indices : the `indices` gather path (output[i] samples probs[indices[i]])
  robust  : fp16/bf16 inputs, non-contiguous inputs, check_nan guard
  rng     : seed/offset determinism and generator state advance
  dist    : distribution match vs torch.multinomial (statistical, TV distance)

Run inside the wangwq_cv_test container:
    cd /wkp/aiter && python op_tests/test_sampling.py [--quick] [--ops ...]
"""

import argparse
import sys
import time
from typing import Optional

import torch

from aiter.ops.sampling import (
    top_k_sampling_from_probs,
    top_p_sampling_from_probs,
    top_k_top_p_sampling_from_probs,
)


def apply_top_k_only(logits: torch.Tensor, k: torch.Tensor) -> torch.Tensor:
    no_top_k_mask = k == logits.shape[1]
    k = k.masked_fill(no_top_k_mask, 1)
    max_top_k = int(k.max().item())
    k_index = k.sub(1).unsqueeze(1).long()
    top_k_mask = logits.topk(max_top_k, dim=1).values.gather(1, k_index)
    top_k_mask.masked_fill_(no_top_k_mask.unsqueeze(1), -float("inf"))
    return logits.masked_fill(logits < top_k_mask, -float("inf"))


def apply_top_k_top_p(
    logits: torch.Tensor,
    k: Optional[torch.Tensor],
    p: Optional[torch.Tensor],
) -> torch.Tensor:
    if p is None:
        return logits if k is None else apply_top_k_only(logits, k)

    logits_sort, logits_idx = logits.sort(dim=-1, descending=False)
    if k is not None:
        top_k_mask = logits_sort.size(1) - k.to(torch.long)
        top_k_mask = logits_sort.gather(1, top_k_mask.unsqueeze(dim=1))
        top_k_mask = logits_sort < top_k_mask
        logits_sort.masked_fill_(top_k_mask, -float("inf"))

    probs_sort = logits_sort.softmax(dim=-1)
    probs_sum = torch.cumsum(probs_sort, dim=-1, out=probs_sort)
    top_p_mask = probs_sum <= 1 - p.unsqueeze(dim=1)
    top_p_mask[:, -1] = False
    logits_sort.masked_fill_(top_p_mask, -float("inf"))

    return logits_sort.scatter(dim=-1, index=logits_idx, src=logits_sort)


def validate_sampling(sampled_ids: torch.Tensor, allowed_logits: torch.Tensor) -> torch.Tensor:
    values = allowed_logits.gather(1, sampled_ids.long().unsqueeze(1)).squeeze(1)
    return torch.isfinite(values)


def print_sizes(label: str, **tensors) -> None:
    def shape_of(t):
        return tuple(t.shape) if isinstance(t, torch.Tensor) else tuple(t)

    dims = ", ".join(f"{name}={shape_of(t)}" for name, t in tensors.items())
    print(f"  [sizes] {label}: {dims}", flush=True)


def build_inputs(
    batch: int,
    vocab: int,
    device: torch.device,
    seed: int,
    disable_prob: float = 0.5,
):
    gen = torch.Generator(device=device).manual_seed(seed)
    logits = torch.rand((batch, vocab), device=device, generator=gen)
    k_values = torch.randint(1, min(1000, vocab), (batch,), device=device, generator=gen)
    p_values = (
        torch.rand((batch,), device=device, generator=gen) * 0.5 + 0.5
    )
    disable_k = torch.rand((batch,), device=device, generator=gen) < disable_prob
    disable_p = torch.rand((batch,), device=device, generator=gen) < disable_prob
    k_values.masked_fill_(disable_k, vocab)
    p_values.masked_fill_(disable_p, 1.0)
    return logits, k_values, p_values


def _reference_allowed(
    logits: torch.Tensor, k: Optional[torch.Tensor], p: Optional[torch.Tensor]
) -> torch.Tensor:
    ref = apply_top_k_top_p(logits.clone(), k, p)
    return torch.softmax(ref, dim=-1)


def run_topk(batch: int, vocab: int, device: torch.device, seed: int, iters: int) -> bool:
    logits, k_values, _ = build_inputs(batch, vocab, device, seed)
    probs = logits.softmax(dim=-1, dtype=torch.float32)
    allowed = _reference_allowed(logits, k_values, None)
    print_sizes("top_k", probs=probs, k=k_values)

    ok = True
    for it in range(iters):
        sampled = top_k_sampling_from_probs(probs, k_values, deterministic=True)
        valid = validate_sampling(sampled, allowed)
        if not bool(valid.all().item()):
            ok = False
            bad = torch.nonzero(~valid, as_tuple=False).flatten()[:3].tolist()
            print(f"  [top_k iter={it}] invalid rows: {bad}", flush=True)
            break
    return ok


def run_topp(batch: int, vocab: int, device: torch.device, seed: int, iters: int) -> bool:
    logits, _, p_values = build_inputs(batch, vocab, device, seed)
    probs = logits.softmax(dim=-1, dtype=torch.float32)
    allowed = _reference_allowed(logits, None, p_values)
    print_sizes("top_p", probs=probs, p=p_values)

    ok = True
    for it in range(iters):
        sampled = top_p_sampling_from_probs(probs, p_values, deterministic=True)
        valid = validate_sampling(sampled, allowed)
        if not bool(valid.all().item()):
            ok = False
            bad = torch.nonzero(~valid, as_tuple=False).flatten()[:3].tolist()
            print(f"  [top_p iter={it}] invalid rows: {bad}", flush=True)
            break
    return ok


def run_topk_topp(batch: int, vocab: int, device: torch.device, seed: int, iters: int) -> bool:
    logits, k_values, p_values = build_inputs(batch, vocab, device, seed)
    probs = logits.softmax(dim=-1, dtype=torch.float32)
    allowed = _reference_allowed(logits, k_values, p_values)
    print_sizes("top_k_top_p", probs=probs, k=k_values, p=p_values)

    ok = True
    for it in range(iters):
        sampled = top_k_top_p_sampling_from_probs(
            probs, k_values, p_values, deterministic=True
        )
        valid = validate_sampling(sampled, allowed)
        if not bool(valid.all().item()):
            ok = False
            bad = torch.nonzero(~valid, as_tuple=False).flatten()[:3].tolist()
            print(f"  [top_k_top_p iter={it}] invalid rows: {bad}", flush=True)
            break
    return ok


def run_scalar_smoke(device: torch.device, seed: int) -> bool:
    torch.manual_seed(seed)
    batch, vocab = 8, 4096
    logits = torch.rand((batch, vocab), device=device)
    probs = logits.softmax(dim=-1, dtype=torch.float32)
    print_sizes("scalar", probs=probs)

    scalar_k = 32
    k_tensor = torch.full((batch,), scalar_k, dtype=torch.int32, device=device)
    allowed_k = _reference_allowed(logits, k_tensor, None)
    sampled = top_k_sampling_from_probs(probs, scalar_k, deterministic=True)
    if not bool(validate_sampling(sampled, allowed_k).all().item()):
        print("  [scalar top_k] invalid", flush=True)
        return False

    scalar_p = 0.9
    p_tensor = torch.full((batch,), scalar_p, dtype=torch.float32, device=device)
    allowed_p = _reference_allowed(logits, None, p_tensor)
    sampled = top_p_sampling_from_probs(probs, scalar_p, deterministic=True)
    if not bool(validate_sampling(sampled, allowed_p).all().item()):
        print("  [scalar top_p] invalid", flush=True)
        return False

    allowed_kp = _reference_allowed(logits, k_tensor, p_tensor)
    sampled = top_k_top_p_sampling_from_probs(probs, scalar_k, scalar_p, deterministic=True)
    if not bool(validate_sampling(sampled, allowed_kp).all().item()):
        print("  [scalar top_k_top_p] invalid", flush=True)
        return False

    return True


def run_greedy(device: torch.device, seed: int) -> bool:
    """top_k=1 (and a vanishing top_p) must be exact argmax sampling."""
    ok = True
    for peaked in (False, True):
        gen = torch.Generator(device=device).manual_seed(seed + (1 if peaked else 0))
        logits = torch.randn((256, 32768), device=device, generator=gen) * (
            4.0 if peaked else 1.0
        )
        probs = logits.softmax(dim=-1, dtype=torch.float32).contiguous()
        rowmax = probs.max(dim=1).values
        print_sizes(f"greedy peaked={peaked}", probs=probs)

        def is_argmax(sampled):
            got = probs.gather(1, sampled.long().unsqueeze(1)).squeeze(1)
            return bool((got == rowmax).all().item())

        if not is_argmax(top_k_sampling_from_probs(probs, 1, deterministic=True)):
            print(f"  [greedy top_k=1 peaked={peaked}] sampled id is not argmax", flush=True)
            ok = False
        if not is_argmax(top_p_sampling_from_probs(probs, 1e-6, deterministic=True)):
            print(f"  [greedy top_p->0 peaked={peaked}] sampled id is not argmax", flush=True)
            ok = False
    return ok


def run_edge(device: torch.device, seed: int) -> bool:
    """Edge shapes/values: tiny batch/vocab, disabled filters, zero-prob support."""
    ok = True
    gen = torch.Generator(device=device).manual_seed(seed)

    # batch=1, tiny vocab, filters disabled
    probs = torch.rand((1, 17), device=device, generator=gen)
    probs = probs.softmax(dim=-1, dtype=torch.float32).contiguous()
    print_sizes("edge b=1 tiny-vocab", probs=probs)
    for name, out in [
        ("top_k", top_k_sampling_from_probs(probs, 17, deterministic=True)),
        ("top_p", top_p_sampling_from_probs(probs, 1.0, deterministic=True)),
        ("joint", top_k_top_p_sampling_from_probs(probs, 17, 1.0, deterministic=True)),
    ]:
        if not bool(((out >= 0) & (out < 17)).all().item()):
            print(f"  [edge b=1 v=17 {name}] out-of-range sample", flush=True)
            ok = False

    # two-token distribution [0.7, 0.3]: zero-mass ids must never appear and the
    # 0.7-token frequency must match, with all filters disabled (k=vocab, p=1.0)
    probs = torch.zeros((8192, 64), device=device)
    probs[:, 0] = 0.7
    probs[:, 1] = 0.3
    print_sizes("edge two-token", probs=probs)
    n_rep, total = 8, 8192 * 8
    samplers = {
        "top_k": lambda off: top_k_sampling_from_probs(
            probs, 64, deterministic=True, seed=seed, offset=off),
        "top_p": lambda off: top_p_sampling_from_probs(
            probs, 1.0, deterministic=True, seed=seed, offset=off),
        "joint": lambda off: top_k_top_p_sampling_from_probs(
            probs, 64, 1.0, deterministic=True, seed=seed, offset=off),
    }
    for name, fn in samplers.items():
        cnt, in_support = 0, True
        for i in range(n_rep):
            out = fn(i * 8192 * 32)
            in_support &= bool(((out == 0) | (out == 1)).all().item())
            cnt += int((out == 0).sum().item())
        freq = cnt / total
        if not in_support:
            print(f"  [two-token {name}] sampled a zero-probability id", flush=True)
            ok = False
        if abs(freq - 0.7) > 0.02:
            print(f"  [two-token {name}] freq(token0)={freq:.4f}, expected 0.7", flush=True)
            ok = False

    # support restricted to 100 of 4096 tokens: filters disabled, so any sample
    # outside the support means zero-probability ids can be emitted
    logits = torch.rand((32, 4096), device=device, generator=gen)
    logits[:, 100:] = -float("inf")
    probs = logits.softmax(dim=-1, dtype=torch.float32).contiguous()
    print_sizes("edge support-100", probs=probs)
    for name, out in [
        ("top_k", top_k_sampling_from_probs(probs, 4096, deterministic=True)),
        ("top_p", top_p_sampling_from_probs(probs, 1.0, deterministic=True)),
        ("joint", top_k_top_p_sampling_from_probs(probs, 4096, 1.0, deterministic=True)),
    ]:
        if not bool((out < 100).all().item()):
            print(f"  [support {name}] sampled a zero-probability id", flush=True)
            ok = False
    return ok


def run_mixed(device: torch.device, seed: int) -> bool:
    """Per-row heterogeneous k/p arrays (non-constant tensor values) for all ops."""
    gen = torch.Generator(device=device).manual_seed(seed)
    batch, vocab = 256, 32768
    logits = torch.rand((batch, vocab), device=device, generator=gen)
    k_values = torch.randint(1, 65, (batch,), device=device, generator=gen)
    p_values = torch.rand((batch,), device=device, generator=gen) * 0.4 + 0.5
    probs = logits.softmax(dim=-1, dtype=torch.float32).contiguous()
    print_sizes("mixed", probs=probs, k=k_values, p=p_values)

    ok = True
    cases = [
        ("top_k", lambda: top_k_sampling_from_probs(probs, k_values, deterministic=True),
         k_values, None),
        ("top_p", lambda: top_p_sampling_from_probs(probs, p_values, deterministic=True),
         None, p_values),
        ("joint", lambda: top_k_top_p_sampling_from_probs(
            probs, k_values, p_values, deterministic=True), k_values, p_values),
    ]
    for name, fn, kk, pp in cases:
        allowed = _reference_allowed(logits, kk, pp)
        valid = validate_sampling(fn(), allowed)
        if not bool(valid.all().item()):
            bad = torch.nonzero(~valid, as_tuple=False).flatten()[:5].tolist()
            print(f"  [mixed {name}] invalid rows: {bad}", flush=True)
            ok = False
    return ok


def run_indices(device: torch.device, seed: int) -> bool:
    """`indices` gathers rows: output[i] must sample from probs[indices[i]].

    Per flashinfer's convention, per-row k/p arrays are indexed by the gathered
    probs row (row_idx = indices[bx]), so arrays are sized to probs rows.
    """
    gen = torch.Generator(device=device).manual_seed(seed)
    n_rows, vocab, batch = 64, 4096, 32
    logits = torch.rand((n_rows, vocab), device=device, generator=gen)
    probs = logits.softmax(dim=-1, dtype=torch.float32).contiguous()
    idx = torch.randint(0, n_rows, (batch,), device=device, generator=gen).to(torch.int32)
    sub_logits = logits[idx.long()]
    p_values = torch.rand((n_rows,), device=device, generator=gen) * 0.4 + 0.5
    ref_k = torch.full((batch,), 20, dtype=torch.int32, device=device)
    ref_p = torch.full((batch,), 0.9, dtype=torch.float32, device=device)
    print_sizes("indices", probs=probs, idx=idx, p_per_probs_row=p_values, out=(batch,))

    ok = True
    cases = [
        ("top_k",
         lambda: top_k_sampling_from_probs(probs, 20, indices=idx, deterministic=True),
         ref_k, None),
        ("top_p",
         lambda: top_p_sampling_from_probs(probs, p_values, indices=idx, deterministic=True),
         None, p_values[idx.long()]),
        ("joint",
         lambda: top_k_top_p_sampling_from_probs(probs, 20, 0.9, indices=idx, deterministic=True),
         ref_k, ref_p),
    ]
    for name, fn, kk, pp in cases:
        sampled = fn()
        if sampled.dtype != torch.int32 or sampled.shape[0] != batch:
            print(f"  [indices {name}] bad output dtype/shape: "
                  f"{sampled.dtype} {tuple(sampled.shape)}", flush=True)
            ok = False
            continue
        allowed = _reference_allowed(sub_logits, kk, pp)
        if not bool(validate_sampling(sampled, allowed).all().item()):
            print(f"  [indices {name}] sampled outside the allowed set of probs[indices[i]]",
                  flush=True)
            ok = False
    return ok


def run_robust(device: torch.device, seed: int) -> bool:
    """fp16/bf16 inputs, non-contiguous inputs, and the check_nan guard."""
    ok = True
    gen = torch.Generator(device=device).manual_seed(seed)
    batch, vocab = 64, 4096
    logits = torch.rand((batch, vocab), device=device, generator=gen)
    probs32 = logits.softmax(dim=-1, dtype=torch.float32).contiguous()
    scalar_k = 50
    ref_k = torch.full((batch,), scalar_k, dtype=torch.int32, device=device)
    print_sizes("robust", probs=probs32, ref_k=ref_k)

    for dt in (torch.float16, torch.bfloat16):
        probs_low = probs32.to(dt)
        # the kernel sees the float() re-widening of the low-precision values,
        # so the reference must be built from those, not from probs32
        allowed = _reference_allowed(probs_low.float().log(), ref_k, None)
        sampled = top_k_sampling_from_probs(probs_low, scalar_k, deterministic=True)
        if not bool(validate_sampling(sampled, allowed).all().item()):
            print(f"  [dtype {dt}] invalid sample", flush=True)
            ok = False

    probs_nc = probs32[:, : vocab // 2]  # non-contiguous column slice
    allowed = _reference_allowed(probs_nc.log(), ref_k, None)
    sampled = top_k_sampling_from_probs(probs_nc, scalar_k, deterministic=True)
    if not bool(validate_sampling(sampled, allowed).all().item()):
        print("  [non-contiguous] invalid sample", flush=True)
        ok = False

    probs_nan = probs32.clone()
    probs_nan[0, 0] = float("nan")
    raised = False
    try:
        top_k_sampling_from_probs(probs_nan, scalar_k, check_nan=True)
    except ValueError:
        raised = True
    if not raised:
        print("  [check_nan] ValueError not raised for NaN input", flush=True)
        ok = False
    return ok


def run_rng(device: torch.device, seed: int) -> bool:
    """Seed/offset determinism, generator state advance, default-generator progress."""
    batch, vocab = 1024, 4096
    gen = torch.Generator(device=device).manual_seed(seed)
    probs = torch.rand((batch, vocab), device=device, generator=gen)
    probs = probs.softmax(dim=-1, dtype=torch.float32).contiguous()
    inc = (batch * 32 + 3) // 4 * 4
    print_sizes("rng", probs=probs)
    ok = True

    a = top_k_sampling_from_probs(probs, 64, deterministic=True, seed=seed, offset=0)
    if not torch.equal(a, top_k_sampling_from_probs(
            probs, 64, deterministic=True, seed=seed, offset=0)):
        print("  [rng] same (seed, offset) produced different outputs", flush=True)
        ok = False
    if torch.equal(a, top_k_sampling_from_probs(
            probs, 64, deterministic=True, seed=seed, offset=inc)):
        print("  [rng] different offset produced identical outputs", flush=True)
        ok = False
    if torch.equal(a, top_k_sampling_from_probs(
            probs, 64, deterministic=True, seed=seed + 1, offset=0)):
        print("  [rng] different seed produced identical outputs", flush=True)
        ok = False

    g = torch.Generator(device=device)
    g.manual_seed(seed)
    state0 = g.get_state().view(torch.int64).clone()
    top_k_sampling_from_probs(probs, 64, generator=g)
    state1 = g.get_state().view(torch.int64)
    if (int(state1[0].item()) != int(state0[0].item())
            or int(state1[1].item()) != int(state0[1].item()) + inc):
        print(f"  [rng] generator state advance wrong: {state0.tolist()} -> "
              f"{state1.tolist()} (expect offset +{inc})", flush=True)
        ok = False

    # without explicit seed/offset the default generator must keep advancing
    e = top_k_sampling_from_probs(probs, 64)
    if torch.equal(e, top_k_sampling_from_probs(probs, 64)):
        print("  [rng] successive default-generator calls identical", flush=True)
        ok = False

    # nondeterministic mode is a smoke test: outputs must stay in range
    o = top_k_sampling_from_probs(probs, 64, deterministic=False, seed=seed, offset=0)
    if not bool(((o >= 0) & (o < vocab)).all().item()):
        print("  [rng] deterministic=False produced out-of-range ids", flush=True)
        ok = False
    return ok


def run_dist(device: torch.device, seed: int, n_calls: int = 256) -> bool:
    """Unfiltered top_k (=vocab) must reproduce torch.multinomial statistics."""
    gen = torch.Generator(device=device).manual_seed(seed)
    batch, vocab = 128, 8192
    probs = torch.rand((batch, vocab), device=device, generator=gen)
    probs = (probs / probs.sum(dim=-1, keepdim=True)).contiguous()
    print_sizes("dist", probs=probs, samples=(batch * n_calls,))

    def pooled(sample_fn):
        vals = []
        for i in range(n_calls):
            out = sample_fn(i * batch * 32)
            vals.append(probs.gather(1, out.long().unsqueeze(1)).squeeze(1))
        return torch.cat(vals)

    sa = pooled(lambda off: top_k_sampling_from_probs(
        probs, vocab, deterministic=True, seed=seed, offset=off))
    ref_gen = torch.Generator(device=device).manual_seed(seed + 777)
    sr = pooled(lambda _off: torch.multinomial(probs, 1, generator=ref_gen).squeeze(-1))

    hi = max(sa.max(), sr.max()).item() * 1.001
    ha = torch.histc(sa.float(), bins=16, min=0.0, max=hi)
    hr = torch.histc(sr.float(), bins=16, min=0.0, max=hi)
    tv = 0.5 * (ha / ha.sum() - hr / hr.sum()).abs().sum().item()
    if tv >= 0.06:
        print(f"  [dist] TV(aiter vs multinomial)={tv:.4f} >= 0.06", flush=True)
        return False
    return True


ALL_OPS = [
    "top_k", "top_p", "top_k_top_p", "scalar",
    "greedy", "edge", "mixed", "indices", "robust", "rng", "dist",
]
QUICK_OPS = ["scalar", "greedy", "edge", "rng"]


def parse_args() -> argparse.Namespace:
    parser = argparse.ArgumentParser()
    parser.add_argument("--batch", type=int, default=256)
    parser.add_argument("--vocab", type=int, default=32768)
    parser.add_argument("--iters", type=int, default=32,
                        help="Repeat each sampler N times to catch flaky rejection outcomes")
    parser.add_argument("--seed", type=int, default=42)
    parser.add_argument("--device", default="cuda")
    parser.add_argument("--quick", action="store_true",
                        help="run only the fast subset (skips the statistical dist test)")
    parser.add_argument(
        "--ops",
        nargs="+",
        choices=ALL_OPS,
        default=None,
        help="subset of test cases to run (default: all, or QUICK_OPS with --quick)",
    )
    args = parser.parse_args()
    if args.ops is None:
        args.ops = QUICK_OPS if args.quick else ALL_OPS
    return args


def main() -> int:
    args = parse_args()
    if not torch.cuda.is_available():
        print("cuda/hip not available", flush=True)
        return 1
    device = torch.device(args.device)

    runners = {
        "top_k": lambda: run_topk(args.batch, args.vocab, device, args.seed, args.iters),
        "top_p": lambda: run_topp(args.batch, args.vocab, device, args.seed, args.iters),
        "top_k_top_p": lambda: run_topk_topp(
            args.batch, args.vocab, device, args.seed, args.iters
        ),
        "scalar": lambda: run_scalar_smoke(device, args.seed),
        "greedy": lambda: run_greedy(device, args.seed),
        "edge": lambda: run_edge(device, args.seed),
        "mixed": lambda: run_mixed(device, args.seed),
        "indices": lambda: run_indices(device, args.seed),
        "robust": lambda: run_robust(device, args.seed),
        "rng": lambda: run_rng(device, args.seed),
        "dist": lambda: run_dist(device, args.seed),
    }

    print(
        f"batch={args.batch} vocab={args.vocab} iters={args.iters} "
        f"device={torch.cuda.get_device_name(0)}",
        flush=True,
    )
    failed = 0
    for op in args.ops:
        t0 = time.perf_counter()
        ok = runners[op]()
        torch.cuda.synchronize()
        dt = (time.perf_counter() - t0) * 1000
        status = "PASS" if ok else "FAIL"
        print(f"  {status} {op:12s} {dt:8.2f} ms", flush=True)
        failed += 0 if ok else 1

    if failed:
        print(f"FAILED {failed}/{len(args.ops)}", flush=True)
        return 1
    print(f"PASSED {len(args.ops)}/{len(args.ops)}", flush=True)
    return 0


if __name__ == "__main__":
    sys.exit(main())
