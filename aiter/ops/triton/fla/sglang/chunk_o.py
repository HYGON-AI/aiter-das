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
HAS_DUMPED_CHUNK_FWD_O_KERNEL_METADATA = False

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


_DEFAULT_CHUNK_O_CONFIG = {
    "BK": 128,
    "BV": 64,
    "num_warps": 4,
    "num_stages": 2,
}


@functools.lru_cache(maxsize=1)
def _load_chunk_o_configs() -> dict:
    device_name = arch_info.get_arch()
    path = os.path.join(
        AITER_TRITON_CONFIGS_PATH,
        "chunk_fwd_o",
        f"chunk_fwd_o-{device_name}.json",
    )
    if not os.path.exists(path):
        logger.warning(
            f"chunk_fwd_o config not found at {path}, using default {_DEFAULT_CHUNK_O_CONFIG}."
        )
        return {}
    with open(path) as f:
        payload = json.load(f)
    return payload.get("config", {}) if isinstance(payload, dict) else {}


@functools.lru_cache
def _get_chunk_o_config(K: int, V: int, BT: int) -> dict:
    cfgs = _load_chunk_o_configs()
    key = f"K={K},V={V},BT={BT}"
    cfg = cfgs.get(key)
    if cfg is None:
        default_cfg = cfgs.get("default", _DEFAULT_CHUNK_O_CONFIG)
        if TRITON_CONFIG_CHECK:
            logger.warning(
                "chunk_fwd_o config missing for "
                f"{key}, using default config {default_cfg}."
            )
        cfg = default_cfg
    merged = dict(_DEFAULT_CHUNK_O_CONFIG)
    merged.update(cfg)
    return merged


def launch_chunk_fwd_kernel_o(
    *,
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    h: torch.Tensor,
    g: torch.Tensor | None,
    o: torch.Tensor,
    cu_seqlens: torch.LongTensor | None,
    chunk_indices: torch.LongTensor | None,
    scale: float,
    T: int,
    H: int,
    Hg: int,
    K: int,
    V: int,
    BT: int,
    NT: int,
    B: int,
    kernel_cfg: dict | None,
):
    global HAS_DUMPED_CHUNK_FWD_O_KERNEL_METADATA

    def grid(meta):
        return (triton.cdiv(V, meta["BV"]), NT, B * H)

    cfg = kernel_cfg if kernel_cfg is not None else _get_chunk_o_config(K, V, BT)
    launch_grid = (triton.cdiv(V, cfg["BV"]), NT, B * H)
    compiled_kernel = chunk_fwd_kernel_o[grid](
        q=q,
        k=k,
        v=v,
        h=h,
        g=g,
        o=o,
        cu_seqlens=cu_seqlens,
        chunk_indices=chunk_indices,
        scale=scale,
        T=T,
        H=H,
        Hg=Hg,
        K=K,
        V=V,
        BT=BT,
        BK=cfg["BK"],
        BV=cfg["BV"],
        num_warps=cfg["num_warps"],
        num_stages=cfg["num_stages"],
    )
    if (
        TRITON_CONFIG_CHECK
        and not HAS_DUMPED_CHUNK_FWD_O_KERNEL_METADATA
        and compiled_kernel is not None
    ):
        print("chunk_fwd_kernel_o metadata")
        print(f"  grid: {launch_grid}")
        print(
            f"  meta: BT={BT}, BK={cfg['BK']}, BV={cfg['BV']}, K={K}, V={V}, H={H}, Hg={Hg}, "
            f"NT={NT}, B={B}, T={T}, num_warps={cfg['num_warps']}, num_stages={cfg['num_stages']}"
        )
        print(f"  registers: {compiled_kernel.n_regs}")
        print(f"  spills: {compiled_kernel.n_spills}")
        print(f"  shared memory: {compiled_kernel.metadata.shared} bytes")
        HAS_DUMPED_CHUNK_FWD_O_KERNEL_METADATA = True


@triton.heuristics({
    "USE_G": lambda args: args["g"] is not None,
    "IS_VARLEN": lambda args: args["cu_seqlens"] is not None,
})
@triton.jit(do_not_specialize=["T"])
def chunk_fwd_kernel_o(
    q,
    k,
    v,
    h,
    g,
    o,
    cu_seqlens,
    chunk_indices,
    scale,
    T,
    H: tl.constexpr,
    Hg: tl.constexpr,
    K: tl.constexpr,
    V: tl.constexpr,
    BT: tl.constexpr,
    BK: tl.constexpr,
    BV: tl.constexpr,
    USE_G: tl.constexpr,
    IS_VARLEN: tl.constexpr,
):
    i_v, i_t, i_bh = tl.program_id(0), tl.program_id(1), tl.program_id(2)
    i_b, i_h = i_bh // H, i_bh % H

    if IS_VARLEN:
        i_tg = i_t
        i_n, i_t = (
            tl.load(chunk_indices + i_t * 2).to(tl.int32),
            tl.load(chunk_indices + i_t * 2 + 1).to(tl.int32),
        )
        bos, eos = (
            tl.load(cu_seqlens + i_n).to(tl.int32),
            tl.load(cu_seqlens + i_n + 1).to(tl.int32),
        )
        T = eos - bos
    else:
        NT = tl.cdiv(T, BT)
        i_tg = i_b * NT + i_t
        bos, eos = i_b * T, i_b * T + T

    q += (bos * Hg + i_h // (H // Hg)) * K
    k += (bos * Hg + i_h // (H // Hg)) * K
    v += (bos * H + i_h) * V
    o += (bos * H + i_h) * V
    h += (i_tg * H + i_h).to(tl.int64) * V * K

    b_o = tl.zeros([BT, BV], dtype=tl.float32)
    b_A = tl.zeros([BT, BT], dtype=tl.float32)

    for i_k in range(tl.cdiv(K, BK)):
        p_q = tl.make_block_ptr(
            q, (T, K), (Hg * K, 1), (i_t * BT, i_k * BK), (BT, BK), (1, 0)
        )
        p_k = tl.make_block_ptr(
            k, (K, T), (1, Hg * K), (i_k * BK, i_t * BT), (BK, BT), (0, 1)
        )
        p_h = tl.make_block_ptr(
            h, (V, K), (K, 1), (i_v * BV, i_k * BK), (BV, BK), (1, 0)
        )
        b_q = tl.load(p_q, boundary_check=(0, 1))
        b_k = tl.load(p_k, boundary_check=(0, 1))
        b_h = tl.load(p_h, boundary_check=(0, 1))
        b_o += tl.dot(b_q, tl.trans(b_h))
        b_A += tl.dot(b_q, b_k)

    if USE_G:
        g += bos * H + i_h
        p_g = tl.make_block_ptr(g, (T,), (H,), (i_t * BT,), (BT,), (0,))
        b_g = tl.load(p_g, boundary_check=(0,))
        b_o = b_o * exp(b_g)[:, None]
        b_A = b_A * safe_exp(b_g[:, None] - b_g[None, :])

    o_i = tl.arange(0, BT)
    m_A = o_i[:, None] >= o_i[None, :]
    b_A = tl.where(m_A, b_A, 0)

    p_v = tl.make_block_ptr(
        v, (T, V), (H * V, 1), (i_t * BT, i_v * BV), (BT, BV), (1, 0)
    )
    p_o = tl.make_block_ptr(
        o, (T, V), (H * V, 1), (i_t * BT, i_v * BV), (BT, BV), (1, 0)
    )
    b_v = tl.load(p_v, boundary_check=(0, 1))
    b_o = b_o * scale + tl.dot(b_A.to(b_v.dtype), b_v) * scale
    tl.store(p_o, b_o.to(p_o.dtype.element_ty), boundary_check=(0, 1))


def chunk_fwd_o(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    h: torch.Tensor,
    g: torch.Tensor | None = None,
    g_gamma: torch.Tensor | None = None,
    scale: float | None = None,
    cu_seqlens: torch.LongTensor | None = None,
    chunk_size: int = 64,
    chunk_indices: torch.LongTensor | None = None,
    use_exp2: bool = False,
    transpose_state_layout: bool = False,
    kernel_cfg: dict | None = None,
) -> torch.Tensor:
    B, T, Hg, K, V = *q.shape, v.shape[-1]
    H = v.shape[-2]
    BT = chunk_size
    if chunk_indices is None and cu_seqlens is not None:
        chunk_indices = prepare_chunk_indices(cu_seqlens, BT)
    NT = triton.cdiv(T, BT) if cu_seqlens is None else len(chunk_indices)
    if scale is None:
        scale = k.shape[-1] ** -0.5

    o = torch.empty_like(v)

    launch_chunk_fwd_kernel_o(
        q=q,
        k=k,
        v=v,
        h=h,
        g=g,
        o=o,
        cu_seqlens=cu_seqlens,
        chunk_indices=chunk_indices,
        scale=scale,
        T=T,
        H=H,
        Hg=Hg,
        K=K,
        V=V,
        BT=BT,
        NT=NT,
        B=B,
        kernel_cfg=kernel_cfg,
    )
    return o
