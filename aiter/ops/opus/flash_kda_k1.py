# SPDX-License-Identifier: MIT
"""K1（定长 / packed 变长）：直接写出 K2 消费的 C16 workspace。

定长入口支持任意正 T，尾块由 native fixed-tail 实例按 `FixedTailInfo{tokens=T}`
掩蔽，不构造变长 metadata。packed 变长入口通过 GPU metadata 描述序列边界
（`FlashKdaVarlenMeta`：`chunk_info[Qcap,2]` + `sequence_info[N,3]`）。

类型注解必须保持具体对象（不要 `from __future__ import annotations`）：
`torch_compile_guard` 用首参注解的**对象身份**判断是否 Tensor 型调度。
"""

from dataclasses import dataclass

import torch

from ...jit.core import compile_ops
from .flash_kda_workspace import FlashKdaPrepareMeta, FlashKdaWorkspace

C16 = 16
K = 128
V = 128


@compile_ops("module_flash_kda_hcu", fc_name="kda_k1_varlen_forward")
def _kda_k1_varlen_forward(
    q: torch.Tensor,
    k: torch.Tensor,
    g: torch.Tensor,
    beta: torch.Tensor,
    A_log: torch.Tensor,
    dt_bias: torch.Tensor,
    scale: float,
    lower_bound: float,
    ws_kdqd: torch.Tensor,
    ws_krgt: torch.Tensor,
    ws_inv: torch.Tensor,
    ws_mqk: torch.Tensor,
    beta_sigmoid: torch.Tensor,
    chunk_info: torch.Tensor,
) -> None: ...


@compile_ops("module_flash_kda_hcu", fc_name="kda_build_varlen_metadata")
def _kda_build_varlen_metadata(
    cu_seqlens: torch.Tensor,
    chunk_info: torch.Tensor,
    sequence_info: torch.Tensor,
) -> None: ...


@compile_ops("module_flash_kda_hcu", fc_name="kda_k1_forward")
def _kda_k1_forward(
    q: torch.Tensor,
    k: torch.Tensor,
    g: torch.Tensor,
    beta: torch.Tensor,
    A_log: torch.Tensor,
    dt_bias: torch.Tensor,
    scale: float,
    lower_bound: float,
    ws_kdqd: torch.Tensor,
    ws_krgt: torch.Tensor,
    ws_inv: torch.Tensor,
    ws_mqk: torch.Tensor,
    beta_sigmoid: torch.Tensor,
    write_beta_fp32: bool,
) -> None: ...


# ===========================================================================
# packed 变长：GPU metadata + 可复用 workspace
# ===========================================================================
@dataclass(frozen=True)
class FlashKdaVarlenMeta:
    """变长 metadata 的形状与两张 descriptor Tensor（不复用定长 meta）。"""

    T_total: int
    H: int
    N: int
    chunk_capacity_per_head: int
    chunk_info: torch.Tensor      # INT64 [chunk_capacity_per_head,2]：(全局 token 起点, 有效 token 数)
    sequence_info: torch.Tensor   # INT64 [N,3]：(token 起点, L, chunk 起点)


class FlashKdaVarlenWorkspace:
    """按 shape 分配的变长 workspace；只负责分配与启动，不缓存输入结果。

    * `run_metadata(cu)` 每次调用重新生成 GPU metadata（容量只由 shape 决定，
      partition 可变；**不回读 GPU**）。
    * `run_k1(...)` 走 K1 变长实例。
    * 不共享可写 workspace 给无序并发 stream；跨 stream 由调用方 event 化。
    """

    def __init__(self, T_total: int, H: int, N: int, device: torch.device) -> None:
        if T_total < 0:
            raise ValueError("T_total must be >= 0")
        if N < 1:
            raise ValueError("N must be >= 1")
        if H < 1:
            raise ValueError("H must be >= 1")
        if N * H > 65535:
            raise ValueError("N*H must be <= 65535 (grid.y limit)")
        self.T_total, self.H, self.N = int(T_total), int(H), int(N)
        self.chunk_capacity_per_head = (self.T_total + C16 - 1) // C16 + self.N
        if self.chunk_capacity_per_head <= 0:
            raise ValueError("chunk_capacity_per_head must be >= 1")
        self.workspace_chunk_count = self.H * self.chunk_capacity_per_head
        # 允许传 torch.device("cuda")：与 "cuda:N" 归一化，否则后面的相等比较会误判。
        device = torch.device(device)
        if device.type == "cuda" and device.index is None:
            device = torch.device("cuda", torch.cuda.current_device())
        self.device = device
        bf16 = dict(device=device, dtype=torch.bfloat16)
        f32 = dict(device=device, dtype=torch.float32)
        # 未使用槽不初始化（K1/K2 都不得访问；测试用毒值验证 producer 完备性）
        self.kdqd = torch.empty((self.workspace_chunk_count, 2, 8, 16, 16), **bf16)
        self.krgt = torch.empty((self.workspace_chunk_count, 9, 16, 16), **bf16)
        self.beta_sigmoid = torch.empty((self.workspace_chunk_count, C16), **f32)
        self.inv = torch.empty((self.workspace_chunk_count, 1, 1, 16, 16), **bf16)
        self.mqk = torch.empty_like(self.inv)
        # metadata 由 builder 在 GPU 上清零并写满（含空序列），故不预清零。
        self.chunk_info = torch.empty((self.chunk_capacity_per_head, 2), device=device, dtype=torch.int64)
        self.sequence_info = torch.empty((self.N, 3), device=device, dtype=torch.int64)
        self.cu_ref: torch.Tensor | None = None

    @property
    def workspace(self) -> FlashKdaWorkspace:
        return FlashKdaWorkspace(
            self.kdqd, self.krgt, self.inv, self.mqk, self.beta_sigmoid,
        )

    @property
    def meta(self) -> FlashKdaVarlenMeta:
        return FlashKdaVarlenMeta(
            T_total=self.T_total, H=self.H, N=self.N,
            chunk_capacity_per_head=self.chunk_capacity_per_head,
            chunk_info=self.chunk_info, sequence_info=self.sequence_info,
        )

    def check_cu(self, cu_seqlens: torch.Tensor) -> None:
        """结构校验（不回读内容）；有效内容（cu[0]=0、cu[N]=T_total、单调）由调用方保证。"""
        if not cu_seqlens.is_cuda or not cu_seqlens.is_contiguous():
            raise ValueError("cu_seqlens must be contiguous CUDA")
        if cu_seqlens.dim() != 1:
            raise ValueError("cu_seqlens must be 1-D")
        if cu_seqlens.dtype not in (torch.int32, torch.int64):
            raise ValueError("cu_seqlens must be INT32 or INT64")
        if cu_seqlens.numel() != self.N + 1:
            raise ValueError(
                f"cu_seqlens must have N+1={self.N + 1} entries, got {cu_seqlens.numel()}")
        if cu_seqlens.device != self.device:
            raise ValueError("cu_seqlens must share the workspace device")

    def run_metadata(self, cu_seqlens: torch.Tensor) -> FlashKdaVarlenMeta:
        self.check_cu(cu_seqlens)
        _kda_build_varlen_metadata(cu_seqlens, self.chunk_info, self.sequence_info)
        self.cu_ref = cu_seqlens  # 调用期保活（graph/异步安全）
        return self.meta

    def run_k1(self, q: torch.Tensor, k: torch.Tensor, g: torch.Tensor,
               beta: torch.Tensor, A_log: torch.Tensor,
               dt_bias: torch.Tensor | None, scale: float,
               lower_bound: float) -> None:
        """K1 变长实例：packed q/k/g/beta + 已生成的 chunk_info → workspace。

        必须先 `run_metadata(cu)`（或由调用方保证 chunk_info 与当前 partition 一致）。
        """
        if q.ndim != 4 or q.size(0) != 1:
            raise ValueError("varlen K1 requires q=[1,T_total,H,128]")
        if q.size(2) != self.H or q.size(1) != self.T_total:
            raise ValueError("q shape does not match this workspace (T_total/H)")
        if dt_bias is None:
            dt_bias = torch.zeros((0,), device=q.device, dtype=torch.float32)
        _kda_k1_varlen_forward(
            q, k, g, beta, A_log, dt_bias, float(scale), float(lower_bound),
            self.kdqd, self.krgt, self.inv, self.mqk, self.beta_sigmoid,
            self.chunk_info,
        )


class FlashKdaFixedWorkspace:
    """定长 K1 直接写出 workspace，无 raw 中间张量。"""

    def __init__(self, B: int, T: int, H: int, device: torch.device,
                 *, write_beta_fp32: bool) -> None:
        # 接受任意正 T：块数向上取整，最后一个块由 native fixed-tail 实例
        # 按 `FixedTailInfo{tokens=T}` 掩蔽（与 packed 变长共用中性规则）。
        if T <= 0:
            raise ValueError("K1 requires T > 0")
        self.B, self.T, self.H = B, T, H
        self.chunks = (T + C16 - 1) // C16
        self.workspace_chunk_count = B * H * self.chunks
        self.write_beta_fp32 = bool(write_beta_fp32)
        # 数值区按区域独立分配（每块 16 B 对齐）：kd|qd 与 kr|gt 各是一整块。
        bf16 = dict(device=device, dtype=torch.bfloat16)
        f32 = dict(device=device, dtype=torch.float32)
        self.kdqd = torch.empty((self.workspace_chunk_count, 2, 8, 16, 16), **bf16)
        self.krgt = torch.empty((self.workspace_chunk_count, 9, 16, 16), **bf16)
        self.beta_sigmoid = torch.empty((self.workspace_chunk_count, C16), **f32)
        self.inv = torch.empty((self.workspace_chunk_count, 1, 1, 16, 16), **bf16)
        self.mqk = torch.empty_like(self.inv)

    @property
    def workspace(self) -> FlashKdaWorkspace:
        return FlashKdaWorkspace(
            self.kdqd, self.krgt, self.inv, self.mqk, self.beta_sigmoid,
        )

    def run_direct(self, q: torch.Tensor, k: torch.Tensor, g: torch.Tensor,
                   beta: torch.Tensor, A_log: torch.Tensor, dt_bias: torch.Tensor,
                   scale: float, lower_bound: float) -> None:
        _kda_k1_forward(
            q, k, g, beta, A_log, dt_bias, float(scale), float(lower_bound),
            self.kdqd, self.krgt, self.inv, self.mqk, self.beta_sigmoid,
            self.write_beta_fp32,
        )


def _check_k1_inputs(q, k, g, beta, A_log, dt_bias, lower_bound, *, varlen: bool):
    """K1 公共输入校验；返回 (B, T, H, K, dt_bias)。"""
    tag = "varlen K1" if varlen else "K1"
    if q.ndim != 4 or tuple(q.shape[-1:]) != (K,):
        raise ValueError(f"{tag} requires q=[B,T,H,128]")
    if tuple(q.shape) != tuple(k.shape) or tuple(g.shape) != tuple(q.shape):
        raise ValueError("q/k/g must share shape")
    if varlen and tuple(q.shape[:1]) != (1,):
        raise ValueError("varlen K1 requires B=1")
    if any(x.dtype is not torch.bfloat16 for x in (q, k, g)):
        raise ValueError(f"{tag} q/k/g must be BF16")
    if any(not x.is_cuda or not x.is_contiguous() for x in (q, k, g, beta, A_log)):
        raise ValueError(f"{tag} inputs must be contiguous CUDA tensors")
    B, T, H, Kdim = q.shape
    if beta.dtype not in (torch.float32, torch.bfloat16) or tuple(beta.shape) != (B, T, H):
        raise ValueError(f"{tag} beta must be FP32/BF16 [B,T,H]")
    if A_log.dtype is not torch.float32 or tuple(A_log.shape) != (H,):
        raise ValueError(f"{tag} A_log must be FP32 [H]")
    if dt_bias is None:
        dt_bias = torch.zeros((H * Kdim,), device=q.device, dtype=torch.float32)
    elif (dt_bias.dtype is not torch.float32 or not dt_bias.is_cuda
          or not dt_bias.is_contiguous() or dt_bias.numel() != H * Kdim):
        raise ValueError(f"{tag} dt_bias must be contiguous CUDA FP32 [H*128]")
    if any(x.device != q.device for x in (k, g, beta, A_log, dt_bias)):
        raise ValueError(f"{tag} tensors must share a device")
    if not -5 <= lower_bound < 0:
        raise ValueError(f"{tag} requires lower_bound in [-5,0)")
    return B, T, H, Kdim, dt_bias


def flash_kda_k1_forward(
    q: torch.Tensor,
    k: torch.Tensor,
    g: torch.Tensor,
    beta: torch.Tensor,
    A_log: torch.Tensor,
    dt_bias: torch.Tensor | None = None,
    *,
    scale: float | None = None,
    lower_bound: float = -5.0,
) -> tuple[FlashKdaWorkspace, FlashKdaPrepareMeta]:
    """定长 K1：直接生成 K2 消费的 workspace，beta 保留 FP32 sigmoid 值。

    范围：**任意正 T**。`T % 16 == 0` 走满块实例；否则块数用 `ceil(T/16)`，
    最后一个块带 `FixedTailInfo{tokens=T}`，按与 packed 变长相同的中性规则掩蔽
    无效 token（q/k=0、beta activated=0、gate 前缀增量=0）。
    **不构造 cu、不发射 metadata kernel。**
    """
    B, T, H, Kdim, dt_bias = _check_k1_inputs(
        q, k, g, beta, A_log, dt_bias, lower_bound, varlen=False)
    if T <= 0:
        raise ValueError("K1 requires T > 0")
    if scale is None:
        scale = Kdim ** -0.5
    if scale <= 0:
        raise ValueError("K1 requires scale > 0")

    chunks = (T + C16 - 1) // C16
    direct = FlashKdaFixedWorkspace(B, T, H, q.device, write_beta_fp32=True)
    direct.run_direct(q, k, g, beta, A_log, dt_bias.view(H, Kdim),
                      float(scale), float(lower_bound))
    return direct.workspace, FlashKdaPrepareMeta(
        B=B, T=T, H=H, K=Kdim, C=C16,
        workspace_head_stride_chunks=B * chunks)


def flash_kda_k1_varlen_forward(
    q: torch.Tensor,
    k: torch.Tensor,
    g: torch.Tensor,
    beta: torch.Tensor,
    A_log: torch.Tensor,
    dt_bias: torch.Tensor | None = None,
    *,
    cu_seqlens: torch.Tensor,
    scale: float | None = None,
    lower_bound: float = -5.0,
) -> tuple[FlashKdaWorkspace, FlashKdaVarlenMeta]:
    """packed 变长 K1：GPU metadata → 变长 K1 实例 → workspace。

    `cu_seqlens` 必须是**同 GPU** 的 INT32/INT64 连续张量；CPU cu 明确拒绝
    （不在调用里隐式搬运）。有效内容（cu[0]=0、cu[N]=T_total、单调不减）是
    调用方前置条件。
    """
    B, T_total, H, Kdim, dt_bias = _check_k1_inputs(
        q, k, g, beta, A_log, dt_bias, lower_bound, varlen=True)
    if beta.dtype not in (torch.float32, torch.bfloat16) or tuple(beta.shape) != (1, T_total, H):
        raise ValueError("varlen K1 beta must be FP32/BF16 [1,T_total,H]")
    if cu_seqlens.device != q.device:
        raise ValueError("varlen K1 tensors must share a device")
    if scale is None:
        scale = Kdim ** -0.5
    if scale <= 0:
        raise ValueError("varlen K1 requires scale > 0")

    n_seqs = int(cu_seqlens.numel()) - 1
    runner = FlashKdaVarlenWorkspace(int(T_total), int(H), n_seqs, q.device)
    runner.run_metadata(cu_seqlens)
    runner.run_k1(q, k, g, beta, A_log, dt_bias, float(scale), float(lower_bound))
    return runner.workspace, runner.meta
