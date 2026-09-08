# SPDX-License-Identifier: MIT

import functools
import json
import os

import torch
import triton
import triton.language as tl

import aiter.ops.triton.utils.arch_info as arch_info
from aiter import logger
from aiter.ops.triton.utils.core import AITER_TRITON_CONFIGS_PATH

TRITON_CONFIG_CHECK = os.environ.get("TRITON_CONFIG_CHECK", "0") == "1"
HAS_DUMPED_CHUNK_DELTA_H_KERNEL_METADATA = False

@triton.jit
def safe_exp(x):
    return exp(tl.where(x <= 0, x, float("-inf")))

@triton.jit
def exp(x):
    return tl.exp(x)


@triton.jit
def exp2(x):
    return tl.math.exp2(x)


def prepare_chunk_indices(cu_seqlens: torch.LongTensor, chunk_size: int) -> torch.LongTensor:
    chunk_rows = []
    for i in range(len(cu_seqlens) - 1):
        seqlen = int((cu_seqlens[i + 1] - cu_seqlens[i]).item())
        n_chunks = triton.cdiv(seqlen, chunk_size)
        for chunk_idx in range(n_chunks):
            chunk_rows.append([i, chunk_idx])
    if len(chunk_rows) == 0:
        return torch.empty((0, 2), dtype=torch.long, device=cu_seqlens.device)
    return torch.tensor(chunk_rows, dtype=torch.long, device=cu_seqlens.device)


def prepare_chunk_offsets(cu_seqlens: torch.LongTensor, chunk_size: int) -> torch.LongTensor:
    seq_lens = cu_seqlens[1:] - cu_seqlens[:-1]
    chunk_counts = (seq_lens + chunk_size - 1) // chunk_size
    offsets = torch.zeros_like(chunk_counts)
    if len(offsets) > 1:
        offsets[1:] = torch.cumsum(chunk_counts, dim=0)[:-1]
    return offsets


_DEFAULT_CHUNK_DELTA_H_CONFIG = {
    "BV": 32,
    "num_warps": 8,
    "num_stages": 2,
}


@functools.lru_cache(maxsize=1)
def _load_chunk_delta_h_configs() -> dict:
    device_name = arch_info.get_arch()
    path = os.path.join(
        AITER_TRITON_CONFIGS_PATH,
        "chunk_gated_delta_rule_fwd_h",
        f"chunk_gated_delta_rule_fwd_h-{device_name}.json",
    )
    if not os.path.exists(path):
        logger.warning(
            f"chunk_gated_delta_rule_fwd_h config not found at {path}, using default {_DEFAULT_CHUNK_DELTA_H_CONFIG}."
        )
        return {}
    with open(path) as f:
        payload = json.load(f)
    return payload.get("config", {}) if isinstance(payload, dict) else {}

@functools.lru_cache
def _get_chunk_delta_h_config(K: int, V: int, BT: int, H: int) -> dict:
    cfgs = _load_chunk_delta_h_configs()
    key = f"K={K},V={V},BT={BT},H={H}"
    cfg = cfgs.get(key)

    if cfg is None:
        default_cfg = cfgs.get("default", _DEFAULT_CHUNK_DELTA_H_CONFIG)
        if TRITON_CONFIG_CHECK:
            logger.warning(
                "chunk_gated_delta_rule_fwd_h config missing for "
                f"{key}, using default config {default_cfg}."
            )
        cfg = default_cfg
    merged = dict(_DEFAULT_CHUNK_DELTA_H_CONFIG)
    merged.update(cfg)
    return merged


def launch_chunk_gated_delta_rule_fwd_kernel_h_blockdim64(
    *,
    k: torch.Tensor,
    u: torch.Tensor,
    w: torch.Tensor,
    v_new: torch.Tensor | None,
    g: torch.Tensor | None,
    gk: torch.Tensor | None,
    h: torch.Tensor,
    initial_state: torch.Tensor | None,
    initial_state_indices: torch.Tensor | None,
    # final_state: torch.Tensor | None,
    cu_seqlens: torch.LongTensor | None,
    chunk_offsets: torch.LongTensor | None,
    N: int,
    T: int,
    H: int,
    Hg: int,
    K: int,
    V: int,
    BT: int,
    kernel_cfg: dict | None,
):
    global HAS_DUMPED_CHUNK_DELTA_H_KERNEL_METADATA

    def grid(meta):
        return (triton.cdiv(V, meta["BV"]), N * H)

    cfg = kernel_cfg if kernel_cfg is not None else _get_chunk_delta_h_config(K, V, BT, H)
    launch_grid = (triton.cdiv(V, cfg["BV"]), N * H)
    compiled_kernel = chunk_gated_delta_rule_fwd_kernel_h_blockdim64[grid](
        k=k,
        v=u,
        w=w,
        v_new=v_new,
        g=g,
        gk=gk,
        h=h,
        initial_state=initial_state,
        initial_state_indices=initial_state_indices,
        cu_seqlens=cu_seqlens,
        chunk_offsets=chunk_offsets,
        T=T,
        H=H,
        Hg=Hg,
        K=K,
        V=V,
        BT=BT,
        BV=cfg["BV"],
        INPLACE_UPDATE=True,
        num_warps=cfg["num_warps"],
        num_stages=cfg["num_stages"],
    )
    if (
        TRITON_CONFIG_CHECK
        and not HAS_DUMPED_CHUNK_DELTA_H_KERNEL_METADATA
        and compiled_kernel is not None
    ):
        print("chunk_gated_delta_rule_fwd_kernel_h_blockdim64 metadata")
        print(f"  grid: {launch_grid}")
        print(
            f"  meta: BT={BT}, BV={cfg['BV']}, K={K}, V={V}, H={H}, Hg={Hg}, N={N}, T={T}, "
            f"num_warps={cfg['num_warps']}, num_stages={cfg['num_stages']}"
        )
        print(f"  registers: {compiled_kernel.n_regs}")
        print(f"  spills: {compiled_kernel.n_spills}")
        print(f"  shared memory: {compiled_kernel.metadata.shared} bytes")
        HAS_DUMPED_CHUNK_DELTA_H_KERNEL_METADATA = True


@triton.heuristics({
    "USE_G": lambda args: args["g"] is not None,
    "USE_GK": lambda args: args["gk"] is not None,
    "USE_INITIAL_STATE": lambda args: args["initial_state"] is not None,
    # "USE_INITIAL_STATE_INDICES": lambda args: args["initial_state_indices"] is not None,
    # "STORE_FINAL_STATE": lambda args: args["ht"] is not None,
    "SAVE_NEW_VALUE": lambda args: args["v_new"] is not None,
    "IS_VARLEN": lambda args: args["cu_seqlens"] is not None,
})
@triton.jit(do_not_specialize=["T"])
def chunk_gated_delta_rule_fwd_kernel_h_blockdim64(
    k,
    v,
    w,
    v_new,
    g,
    gk,
    h,
    initial_state,
    initial_state_indices,
    cu_seqlens,
    chunk_offsets,
    T,
    H: tl.constexpr,
    Hg: tl.constexpr,
    K: tl.constexpr,
    V: tl.constexpr,
    BT: tl.constexpr,
    BV: tl.constexpr,
    USE_G: tl.constexpr,
    USE_GK: tl.constexpr,
    USE_INITIAL_STATE: tl.constexpr,
    INPLACE_UPDATE: tl.constexpr,
    SAVE_NEW_VALUE: tl.constexpr,
    IS_VARLEN: tl.constexpr,
):
    i_v, i_nh = tl.program_id(0), tl.program_id(1)
    i_n, i_h = i_nh // H, i_nh % H
    if IS_VARLEN:
        bos, eos = tl.load(cu_seqlens + i_n).to(tl.int32), tl.load(
            cu_seqlens + i_n + 1
        ).to(tl.int32)
        T = eos - bos
        NT = tl.cdiv(T, BT)
        boh = tl.load(chunk_offsets + i_n).to(tl.int32)
    else:
        bos, eos = i_n * T, i_n * T + T
        NT = tl.cdiv(T, BT)
        boh = i_n * NT

    # [BV, BK]
    b_h1 = tl.zeros([BV, 64], dtype=tl.float32)
    if K > 64:
        b_h2 = tl.zeros([BV, 64], dtype=tl.float32)
    if K > 128:
        b_h3 = tl.zeros([BV, 64], dtype=tl.float32)
    if K > 192:
        b_h4 = tl.zeros([BV, 64], dtype=tl.float32)

    # calculate offset
    h += ((boh * H + i_h) * V * K).to(tl.int64)
    v += ((bos * H + i_h) * V).to(tl.int64)
    k += ((bos * Hg + i_h // (H // Hg)) * K).to(tl.int64)
    w += ((bos * H + i_h) * K).to(tl.int64)
    if SAVE_NEW_VALUE:
        v_new += ((bos * H + i_h) * V).to(tl.int64)
    stride_v = H * V
    stride_h = H * V * K
    stride_k = Hg * K
    stride_w = H * K

    index = tl.load(initial_state_indices + i_n).to(tl.int32)
    h0 = initial_state + index * stride_h
    ht = initial_state + index * stride_h
    if USE_INITIAL_STATE:
        h0 = h0 + i_h * V * K
    if INPLACE_UPDATE:
        ht = ht + i_h * V * K

    # load initial state
    if USE_INITIAL_STATE:
        p_h0_1 = tl.make_block_ptr(h0, (V, K), (K, 1), (i_v * BV, 0), (BV, 64), (1, 0))
        b_h1 += tl.load(p_h0_1, boundary_check=(0, 1)).to(tl.float32)
        if K > 64:
            p_h0_2 = tl.make_block_ptr(
                h0, (V, K), (K, 1), (i_v * BV, 64), (BV, 64), (1, 0)
            )
            b_h2 += tl.load(p_h0_2, boundary_check=(0, 1)).to(tl.float32)
        if K > 128:
            p_h0_3 = tl.make_block_ptr(
                h0, (V, K), (K, 1), (i_v * BV, 128), (BV, 64), (1, 0)
            )
            b_h3 += tl.load(p_h0_3, boundary_check=(0, 1)).to(tl.float32)
        if K > 192:
            p_h0_4 = tl.make_block_ptr(
                h0, (V, K), (K, 1), (i_v * BV, 192), (BV, 64), (1, 0)
            )
            b_h4 += tl.load(p_h0_4, boundary_check=(0, 1)).to(tl.float32)

    # main recurrence
    for i_t in range(NT):
        p_h1 = tl.make_block_ptr(
            h + i_t * stride_h, (V, K), (K, 1), (i_v * BV, 0), (BV, 64), (1, 0)
        )
        tl.store(p_h1, b_h1.to(p_h1.dtype.element_ty), boundary_check=(0, 1))
        if K > 64:
            p_h2 = tl.make_block_ptr(
                h + i_t * stride_h, (V, K), (K, 1), (i_v * BV, 64), (BV, 64), (1, 0)
            )
            tl.store(p_h2, b_h2.to(p_h2.dtype.element_ty), boundary_check=(0, 1))
        if K > 128:
            p_h3 = tl.make_block_ptr(
                h + i_t * stride_h, (V, K), (K, 1), (i_v * BV, 128), (BV, 64), (1, 0)
            )
            tl.store(p_h3, b_h3.to(p_h3.dtype.element_ty), boundary_check=(0, 1))
        if K > 192:
            p_h4 = tl.make_block_ptr(
                h + i_t * stride_h, (V, K), (K, 1), (i_v * BV, 192), (BV, 64), (1, 0)
            )
            tl.store(p_h4, b_h4.to(p_h4.dtype.element_ty), boundary_check=(0, 1))

        p_w1 = tl.make_block_ptr(
            w, (T, K), (stride_w, 1), (i_t * BT, 0), (BT, 64), (1, 0)
        )
        b_w1 = tl.load(p_w1, boundary_check=(0, 1))
        if K > 64:
            p_w2 = tl.make_block_ptr(
                w, (T, K), (stride_w, 1), (i_t * BT, 64), (BT, 64), (1, 0)
            )
            b_w2 = tl.load(p_w2, boundary_check=(0, 1))
        if K > 128:
            p_w3 = tl.make_block_ptr(
                w, (T, K), (stride_w, 1), (i_t * BT, 128), (BT, 64), (1, 0)
            )
            b_w3 = tl.load(p_w3, boundary_check=(0, 1))
        if K > 192:
            p_w4 = tl.make_block_ptr(
                w, (T, K), (stride_w, 1), (i_t * BT, 192), (BT, 64), (1, 0)
            )
            b_w4 = tl.load(p_w4, boundary_check=(0, 1))

        b_v = tl.dot(b_w1, tl.trans(b_h1).to(b_w1.dtype))
        if K > 64:
            b_v += tl.dot(b_w2, tl.trans(b_h2).to(b_w2.dtype))
        if K > 128:
            b_v += tl.dot(b_w3, tl.trans(b_h3).to(b_w3.dtype))
        if K > 192:
            b_v += tl.dot(b_w4, tl.trans(b_h4).to(b_w4.dtype))
        p_v = tl.make_block_ptr(
            v, (T, V), (stride_v, 1), (i_t * BT, i_v * BV), (BT, BV), (1, 0)
        )
        b_v = tl.load(p_v, boundary_check=(0, 1)) - b_v

        if SAVE_NEW_VALUE:
            p_v = tl.make_block_ptr(
                v_new, (T, V), (stride_v, 1), (i_t * BT, i_v * BV), (BT, BV), (1, 0)
            )
            tl.store(p_v, b_v.to(p_v.dtype.element_ty), boundary_check=(0, 1))

        last_idx = min((i_t + 1) * BT, T) - 1
        if USE_G:
            b_g_last = tl.load(g + bos * H + last_idx * H + i_h)
            p_g = tl.make_block_ptr(
                g + bos * H + i_h, (T,), (H,), (i_t * BT,), (BT,), (0,)
            )
            b_g = tl.load(p_g, boundary_check=(0,))
            b_v = b_v * safe_exp(b_g_last - b_g)[:, None]
            b_g_last = exp(b_g_last)
            b_h1 = b_h1 * b_g_last
            if K > 64:
                b_h2 = b_h2 * b_g_last
            if K > 128:
                b_h3 = b_h3 * b_g_last
            if K > 192:
                b_h4 = b_h4 * b_g_last

        if USE_GK:
            o_k1 = tl.arange(0, 64)
            b_gk_last1 = tl.load(
                gk + (bos + last_idx) * H * K + i_h * K + o_k1,
                mask=(o_k1 < K),
                other=0.0,
            )
            b_h1 *= exp(b_gk_last1)[None, :]
            if K > 64:
                o_k2 = 64 + o_k1
                b_gk_last2 = tl.load(
                    gk + (bos + last_idx) * H * K + i_h * K + o_k2,
                    mask=(o_k2 < K),
                    other=0.0,
                )
                b_h2 *= exp(b_gk_last2)[None, :]
            if K > 128:
                o_k3 = 128 + o_k1
                b_gk_last3 = tl.load(
                    gk + (bos + last_idx) * H * K + i_h * K + o_k3,
                    mask=(o_k3 < K),
                    other=0.0,
                )
                b_h3 *= exp(b_gk_last3)[None, :]
            if K > 192:
                o_k4 = 192 + o_k1
                b_gk_last4 = tl.load(
                    gk + (bos + last_idx) * H * K + i_h * K + o_k4,
                    mask=(o_k4 < K),
                    other=0.0,
                )
                b_h4 *= exp(b_gk_last4)[None, :]
        b_v = b_v.to(k.dtype.element_ty)

        p_k1 = tl.make_block_ptr(
            k, (K, T), (1, stride_k), (0, i_t * BT), (64, BT), (0, 1)
        )
        b_k1 = tl.load(p_k1, boundary_check=(0, 1))
        if K > 64:
            p_k2 = tl.make_block_ptr(
                k, (K, T), (1, stride_k), (64, i_t * BT), (64, BT), (0, 1)
            )
            b_k2 = tl.load(p_k2, boundary_check=(0, 1))
        if K > 128:
            p_k3 = tl.make_block_ptr(
                k, (K, T), (1, stride_k), (128, i_t * BT), (64, BT), (0, 1)
            )
            b_k3 = tl.load(p_k3, boundary_check=(0, 1))
        if K > 192:
            p_k4 = tl.make_block_ptr(
                k, (K, T), (1, stride_k), (192, i_t * BT), (64, BT), (0, 1)
            )
            b_k4 = tl.load(p_k4, boundary_check=(0, 1))

        b_h1 += tl.trans(tl.dot(b_k1, b_v))
        if K > 64:
            b_h2 += tl.trans(tl.dot(b_k2, b_v))
        if K > 128:
            b_h3 += tl.trans(tl.dot(b_k3, b_v))
        if K > 192:
            b_h4 += tl.trans(tl.dot(b_k4, b_v))

    # epilogue
    if INPLACE_UPDATE:
        p_ht = tl.make_block_ptr(ht, (V, K), (K, 1), (i_v * BV, 0), (BV, 64), (1, 0))
        tl.store(p_ht, b_h1.to(p_ht.dtype.element_ty), boundary_check=(0, 1))
        if K > 64:
            p_ht = tl.make_block_ptr(
                ht, (V, K), (K, 1), (i_v * BV, 64), (BV, 64), (1, 0)
            )
            tl.store(p_ht, b_h2.to(p_ht.dtype.element_ty), boundary_check=(0, 1))
        if K > 128:
            p_ht = tl.make_block_ptr(
                ht, (V, K), (K, 1), (i_v * BV, 128), (BV, 64), (1, 0)
            )
            tl.store(p_ht, b_h3.to(p_ht.dtype.element_ty), boundary_check=(0, 1))
        if K > 192:
            p_ht = tl.make_block_ptr(
                ht, (V, K), (K, 1), (i_v * BV, 192), (BV, 64), (1, 0)
            )
            tl.store(p_ht, b_h4.to(p_ht.dtype.element_ty), boundary_check=(0, 1))


def chunk_gated_delta_rule_fwd_h(
    k: torch.Tensor,
    w: torch.Tensor,
    u: torch.Tensor,
    g: torch.Tensor | None = None,
    gk: torch.Tensor | None = None,
    initial_state: torch.Tensor | None = None,
    initial_state_indices: torch.Tensor | None = None,
    output_final_state: bool = True,
    chunk_size: int = 64,
    save_new_value: bool = True,
    cu_seqlens: torch.LongTensor | None = None,
    chunk_indices: torch.LongTensor | None = None,
    use_exp2: bool = False,
    transpose_state_layout: bool = True,
    kernel_cfg: dict | None = None,
):
    B, T, Hg, K, V = *k.shape, u.shape[-1]
    H = u.shape[-2]
    BT = chunk_size

    chunk_indices = (
        prepare_chunk_indices(cu_seqlens, chunk_size)
        if cu_seqlens is not None
        else None
    )
    # N: the actual number of sequences in the batch with either equal or variable lengths
    if cu_seqlens is None:
        N, NT, chunk_offsets = B, triton.cdiv(T, BT), None
    else:
        N, NT, chunk_offsets = (
            len(cu_seqlens) - 1,
            len(chunk_indices),
            prepare_chunk_offsets(cu_seqlens, BT),
        )
    assert K <= 256, "current kernel does not support head dimension larger than 256."

    h = k.new_empty(B, NT, H, V, K)

    v_new = torch.empty_like(u) if save_new_value else None

    launch_chunk_gated_delta_rule_fwd_kernel_h_blockdim64(
        k=k,
        u=u,
        w=w,
        v_new=v_new,
        g=g,
        gk=gk,
        h=h,
        initial_state=initial_state,
        initial_state_indices=initial_state_indices,
        cu_seqlens=cu_seqlens,
        chunk_offsets=chunk_offsets,
        N=N,
        T=T,
        H=H,
        Hg=Hg,
        K=K,
        V=V,
        BT=BT,
        # use_exp2=use_exp2,
        # transpose_state_layout=transpose_state_layout,
        kernel_cfg=kernel_cfg,
    )
    return h, v_new
