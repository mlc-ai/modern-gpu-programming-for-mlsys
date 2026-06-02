# Appendix: Flash Attention 4 TIRX Source
:label:`chap_fa4_source`

This appendix contains the FA4 TIRX source used by the Flash Attention chapter. It follows the current `tirx-kernels` implementation style for the kernel builder and verification helper; broader benchmark baselines are intentionally left out.

```python
# Licensed to the Apache Software Foundation (ASF) under one
# or more contributor license agreements.  See the NOTICE file
# distributed with this work for additional information
# regarding copyright ownership.  The ASF licenses this file
# to you under the Apache License, Version 2.0 (the
# "License"); you may not use this file except in compliance
# with the License.  You may obtain a copy of the License at
#
#   http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing,
# software distributed under the License is distributed on an
# "AS IS" BASIS, WITHOUT WARRANTIES OR CONDITIONS OF ANY
# KIND, either express or implied.  See the License for the
# specific language governing permissions and limitations
# under the License.

import math
from enum import Enum

import numpy as np
import torch

import tvm
import tvm.testing
from tvm.script import tirx as Tx
from tvm.tirx.bench import (  # fmt: skip
    CudaProfiler,
    ProtonContext,
    bench,
)
from tvm.tirx.lang.pipeline import MBarrier, Pipe, PipelineState
from tvm.tirx.lang.tile_scheduler import (  # fmt: skip
    FlashAttentionLinearScheduler,
    FlashAttentionLPTScheduler,
)
from tvm.tirx.lang.warp_role import WarpgroupRole, WarpRole
from tvm.tirx.layout import wg_local_layout

M_CLUSTER = 1
N_CLUSTER = 1
SM_NUMBER = 148

NUM_GROUPS = 6
PROFILER_BUFFER_SIZE = int(2e6)
PROFILER_WRITE_STRIDE = SM_NUMBER * NUM_GROUPS
PROFILER_ON = False


class ProfileEventType(Enum):
    IssueTMA_Q = 0
    IssueTMA_K = 1
    IssueTMA_V = 2
    IssueMMA_QK = 3
    IssueMMA_PV = 4
    Softmax_MAX = 5
    Softmax_FMA = 6
    Softmax_EXP2 = 7
    Softmax_TMEM_ST = 8
    Softmax_SUM = 9
    Correction = 10
    EpiLDTMEM = 11
    TMAStore = 12


event_type_names = [
    "issue-tma-q",
    "issue-tma-k",
    "issue-tma-v",
    "issue-mma-qk",
    "issue-mma-pv",
    "softmax-max",
    "softmax-fma",
    "softmax-exp2",
    "softmax-tmem-st",
    "softmax-sum",
    "correction",
    "epi-ld-tmem",
    "tma-store",
]

WG_NUMBER = 4
WARP_NUMBER = 4
NUM_THREADS = (32 * WARP_NUMBER) * WG_NUMBER

N_COLS_TMEM = 512
TMEM_PIPE_DEPTH = 2
SMEM_PIPE_DEPTH_Q = 2
SMEM_PIPE_DEPTH_KV = 3

BLK_M = 128
BLK_N = 128
BLK_K = 64
SOFTMAX_LD_CHUNK = 32
SOFTMAX_ST_CHUNK = 32
EPI_TILE = 64
TMEM_EPI_LD_SIZE = 16
USE_S0_S1_BARRIER = False


MMA_M = 128
MMA_N = 128
MMA_K = 16

F16_BYTES = 2
F32_BYTES = 4
F128_BYTES = 16
a_type_qk = tvm.DataType("float16")
b_type_qk = tvm.DataType("float16")
d_type_qk = tvm.DataType("float32")
a_type_pv = tvm.DataType("float16")
b_type_pv = tvm.DataType("float16")
d_type_pv = tvm.DataType("float32")


# fmt: off
def get_flash_attention4_kernel(batch_size, seq_len_q, seq_len_kv, num_qo_heads, num_kv_heads, head_dim, is_causal=False):

    BATCH_SIZE = batch_size
    SEQ_LEN_Q = seq_len_q
    SEQ_LEN_KV = seq_len_kv
    NUM_QO_HEADS = num_qo_heads
    NUM_KV_HEADS = num_kv_heads
    HEAD_DIM = head_dim

    # GQA parameters
    GQA_RATIO = NUM_QO_HEADS // NUM_KV_HEADS  # e.g., 4 for num_qo_heads=32, num_kv_heads=8
    SEQ_Q_PER_TILE = BLK_M // GQA_RATIO       # e.g., 32 sequence positions per tile

    HEAD_DIM // MMA_K
    NUM_BLK_K = HEAD_DIM // BLK_K
    NUM_EPI_TILE = HEAD_DIM // EPI_TILE
    CTA_GROUP = 1

    # Block info for causal masking (following flash_attn/cute/block_info.py)
    def get_n_block_max(m_block_idx, causal):
        """Maximum KV block index (exclusive) for this Q block."""
        n_block_max = ceildiv(SEQ_LEN_KV, BLK_N)
        if not causal:
            return n_block_max
        # For causal: only process KV blocks up to diagonal
        # SEQ_Q_PER_TILE is already BLK_M // GQA_RATIO, so already in sequence coordinates
        m_idx_max = (m_block_idx + 1) * SEQ_Q_PER_TILE * SMEM_PIPE_DEPTH_Q
        n_idx = m_idx_max + SEQ_LEN_KV - SEQ_LEN_Q
        return Tx.min(n_block_max, ceildiv(n_idx, BLK_N))

    def get_n_block_min_causal_mask(m_block_idx):
        """KV block index where causal masking stops being needed.
        Blocks with index < this value don't need causal masking.
        """
        # SEQ_Q_PER_TILE is already in sequence coordinates (BLK_M // GQA_RATIO)
        m_idx_min = m_block_idx * SEQ_Q_PER_TILE * SMEM_PIPE_DEPTH_Q
        n_idx = m_idx_min + SEQ_LEN_KV - SEQ_LEN_Q
        return Tx.max(0, n_idx // BLK_N)


    # L2 cache optimization for LPT scheduling (causal attention)
    L2_SIZE = 50 * 1024 * 1024  # 50MB L2 cache
    SIZE_ONE_KV_HEAD = SEQ_LEN_KV * HEAD_DIM * 2 * F16_BYTES  # K+V size per head
    L2_SWIZZLE = 1 if L2_SIZE < SIZE_ONE_KV_HEAD else (1 << int(math.log2(L2_SIZE // SIZE_ONE_KV_HEAD)))

    SSCALE_TOTAL_SIZE = 2 * SMEM_PIPE_DEPTH_Q * BLK_M
    assert TMEM_PIPE_DEPTH * MMA_N <= N_COLS_TMEM, "TMEM columns exceeded"

    def ceildiv(a, b):
        return (a + b - 1) // b

    def combine_int_frac_ex2(x_rounded, frac_ex2):
        func_name = "combine_int_frac_ex2"
        source_code = f"""
__device__ __forceinline__ float {func_name}(float x_rounded, float frac_ex2) {{
  float out;
  asm volatile(
    "{{\\n\\t"
    ".reg .s32 x_rounded_i, frac_ex_i, x_rounded_e, out_i;\\n\\t"
    "mov.b32 x_rounded_i, %1;\\n\\t"
    "mov.b32 frac_ex_i, %2;\\n\\t"
    "shl.b32 x_rounded_e, x_rounded_i, 23;\\n\\t"
    "add.s32 out_i, x_rounded_e, frac_ex_i;\\n\\t"
    "mov.b32 %0, out_i;\\n\\t"
    "}}\\n"
    : "=f"(out) : "f"(x_rounded), "f"(frac_ex2));
  return out;
}}
"""
        return Tx.cuda.func_call(
            func_name, x_rounded, frac_ex2, source_code=source_code, return_type="float32"
        )

    @Tx.inline
    def ex2_emulation_2(out, idx, x, y):
        # Polynomial coefficients for exp2 approximation (degree 3)
        poly_ex2_deg3 = Tx.meta_var(
            (
                1.0,
                0.695146143436431884765625,
                0.227564394474029541015625,
                0.077119089663028717041015625,
            )
        )
        fp32_round_int = Tx.meta_var(float(2**23 + 2**22))

        # Clamp inputs to avoid overflow (we assume x, y <= 127.0)
        xy_clamped: Tx.f32[2]
        xy_clamped[0] = Tx.max(x, -127.0)
        xy_clamped[1] = Tx.max(y, -127.0)

        # Round down to get integer part (stored as float with integer in lower bits)
        xy_rounded: Tx.f32[2]
        Tx.add(xy_rounded, xy_clamped, fp32_round_int, rounding_mode="rm")

        # Subtract to get the rounded-back value (round to nearest even)
        xy_rounded_back: Tx.f32[2]
        Tx.sub(xy_rounded_back, xy_rounded, fp32_round_int, rounding_mode="rn")

        # Compute fractional part: xy_frac = xy_clamped - xy_rounded_back
        xy_frac: Tx.f32[2]
        Tx.sub(xy_frac, xy_clamped, xy_rounded_back, rounding_mode="rn")

        # Horner's method: ((poly[3]*x + poly[2])*x + poly[1])*x + poly[0]
        xy_frac_ex2: Tx.f32[2]
        xy_frac_ex2[0] = poly_ex2_deg3[3]
        xy_frac_ex2[1] = poly_ex2_deg3[3]
        Tx.fma(xy_frac_ex2, xy_frac_ex2, xy_frac, poly_ex2_deg3[2])
        Tx.fma(xy_frac_ex2, xy_frac_ex2, xy_frac, poly_ex2_deg3[1])
        Tx.fma(xy_frac_ex2, xy_frac_ex2, xy_frac, poly_ex2_deg3[0])

        # Combine integer and fractional parts: shift integer left by 23 bits and add to fractional exp2
        out[idx] = combine_int_frac_ex2(xy_rounded[0], xy_frac_ex2[0])
        out[idx + 1] = combine_int_frac_ex2(xy_rounded[1], xy_frac_ex2[1])

    @Tx.prim_func(tirx=True, persistent=True)
    def flash_attention4(
        Q: Tx.Buffer((BATCH_SIZE, SEQ_LEN_Q, NUM_QO_HEADS, HEAD_DIM), "float16"),
        K: Tx.Buffer((BATCH_SIZE, SEQ_LEN_KV, NUM_KV_HEADS, HEAD_DIM), "float16"),
        V: Tx.Buffer((BATCH_SIZE, SEQ_LEN_KV, NUM_KV_HEADS, HEAD_DIM), "float16"),
        O: Tx.Buffer((BATCH_SIZE, SEQ_LEN_Q, NUM_QO_HEADS, HEAD_DIM), "float16"),  # noqa: E741
        profiler_buffer: Tx.Buffer((PROFILER_BUFFER_SIZE,), "uint64"),
    ):
        # For GQA: each tile processes SEQ_Q_PER_TILE seq positions (not BLK_M)
        num_q_blocks_total = Tx.meta_var(ceildiv(SEQ_LEN_Q, SEQ_Q_PER_TILE))
        num_q_blocks_per_cta = Tx.meta_var(SMEM_PIPE_DEPTH_Q)
        num_q_blocks = Tx.meta_var(ceildiv(num_q_blocks_total, num_q_blocks_per_cta))

        # Task scheduling
        num_total_tasks = Tx.meta_var(BATCH_SIZE * NUM_KV_HEADS * num_q_blocks)

        # use non-persistent kernel for causal attention
        max_ctas: Tx.let = 148
        cta_count: Tx.let = Tx.min(max_ctas, num_total_tasks) if not is_causal else num_total_tasks

        with Tx.kernel():
            bx = Tx.cta_id([cta_count], parent="kernel")
            wg_id = Tx.warpgroup_id([4], parent="cta")
            warp_id = Tx.warp_id([4], parent="warpgroup")
            lane_id = Tx.thread_id([32], parent="warp")
            tid_in_wg = Tx.thread_id([128], parent="warpgroup")
            pool = Tx.PoolAllocator()
            # Allocate Q buffer with alignment
            Q_smem = pool.alloc_mma((SMEM_PIPE_DEPTH_Q, BLK_M, HEAD_DIM), "float16")
            # Allocate K and V buffers (they share the same offset)
            K_smem = pool.alloc_mma((SMEM_PIPE_DEPTH_KV, BLK_N, HEAD_DIM), "float16")
            V_smem = K_smem.view(SMEM_PIPE_DEPTH_KV, BLK_N, HEAD_DIM)
            # Allocate O buffer
            O_smem = pool.alloc_mma((TMEM_PIPE_DEPTH, BLK_M, HEAD_DIM), "float16")
            # Allocate sScale buffer (ACC_SCALE/ROW_SUM shared + ROW_MAX)
            sScale = pool.alloc((SSCALE_TOTAL_SIZE,), "float32", align=1024)
            tmem_addr = pool.alloc([1], "uint32")

            ACC_SCALE_BASE: Tx.let = 0
            ROW_SUM_BASE: Tx.let = 0  # Shares with ACC_SCALE


            # Phase/stage scalars
            kv_pipe = PipelineState("kv", SMEM_PIPE_DEPTH_KV)
            phase_q: Tx.int32
            phase_s_full: Tx.int32
            phase_tmem: Tx.int32
            phase_s0_s1: Tx.int32
            phase_q_load: Tx.int32

            q_load = Pipe.tma(pool, SMEM_PIPE_DEPTH_Q, empty_phase_offset=1, name="q")
            kv_load = Pipe.tma(pool, SMEM_PIPE_DEPTH_KV, empty_phase_offset=1, name="kv")
            p_o_rescale = Pipe.mbar(pool, 2, full_count=256, name="p_o_rescale")
            s_ready = Pipe.tcgen05(pool, 2, name="s")
            o_ready = Pipe.tcgen05(pool, 2, name="o")
            softmax_corr = Pipe.mbar(pool, 2, full_count=128, empty_count=128, empty_phase_offset=1, name="softmax_corr")
            corr_epi = Pipe.mbar(pool, TMEM_PIPE_DEPTH, full_count=128, empty_count=32, empty_phase_offset=1, name="corr_epi")
            p_ready_2 = Pipe.mbar(pool, 2, full_count=128, name="p2")
            bar_s0_s1_sequence = MBarrier(pool, 8)
            tmem_free = Pipe.mbar(pool, 1, full_count=1, name="tmem_dealloc")
            pool.commit()

            profiler = CudaProfiler(profiler_buffer, write_stride=PROFILER_WRITE_STRIDE, num_groups=NUM_GROUPS, profiler_enabled=PROFILER_ON)

            tmem_pool = Tx.TMEMPool(pool, total_cols=N_COLS_TMEM, cta_group=CTA_GROUP, warp_id=warp_id, wg_id=wg_id, tmem_addr=tmem_addr)
            tmem = tmem_pool.alloc((128, N_COLS_TMEM), "float32")
            tmem_pool.move_base_to(0)
            tmem_as_f16 = tmem_pool.alloc((128, N_COLS_TMEM * 2), "float16")
            tmem_pool.commit()
            Tx.cuda.trap_when_assert_failed(tmem_addr[0] == Tx.uint32(0))

            # Staged TMEM regions: S and O are f32 views, P is an f16 alias of S's physical space
            TMEM_STAGE_STRIDE = Tx.meta_var(MMA_N)  # 128 f32-columns between stages
            S_region = Tx.meta_var(tmem_pool.region(tmem, col_start=0, width=MMA_N, stages=SMEM_PIPE_DEPTH_Q, stride=TMEM_STAGE_STRIDE))
            O_region = Tx.meta_var(tmem_pool.region(tmem, col_start=MMA_N * SMEM_PIPE_DEPTH_Q, width=MMA_N, stages=SMEM_PIPE_DEPTH_Q, stride=TMEM_STAGE_STRIDE))
            P_region = Tx.meta_var(tmem_pool.region(tmem_as_f16, col_start=MMA_N, width=BLK_N, stages=SMEM_PIPE_DEPTH_Q, stride=TMEM_STAGE_STRIDE * 2))

            # Create appropriate scheduler based on causal mode
            scheduler = (
                FlashAttentionLPTScheduler(
                    "fa_scheduler",
                    num_batches=BATCH_SIZE,
                    num_heads=NUM_KV_HEADS,
                    num_m_blocks=num_q_blocks,
                    l2_swizzle=L2_SWIZZLE,
                ) if is_causal else FlashAttentionLinearScheduler(
                    "fa_scheduler",
                    num_batches=BATCH_SIZE,
                    num_heads=NUM_KV_HEADS,
                    num_m_blocks=num_q_blocks,
                    num_ctas=cta_count,
                )
            )

            scheduler.init(bx)  # Initialize with CTA ID

            if wg_id == 3 and warp_id == 1:
                profiler.init(0)
            elif wg_id == 3 and warp_id == 2:
                profiler.init(1)
            elif wg_id == 3 and warp_id == 0:
                profiler.init(2)
            elif wg_id <= 1:
                profiler.init(3 + wg_id)
            elif wg_id == 2:
                profiler.init(5)

            kv_pipe.init(is_producer=False)
            phase_q = 0
            phase_tmem = 0
            phase_s_full = 0
            if USE_S0_S1_BARRIER:
                phase_s0_s1 = Tx.if_then_else(wg_id == 1, 0, 1)
            phase_q_load = 0

            bar_s0_s1_sequence.init(32)

            Tx.ptx.fence.proxy_async("shared::cta")
            Tx.ptx.fence.mbarrier_init()
            Tx.cuda.cta_sync()
            if wg_id == 2:
                for i_q in Tx.unroll(2):
                    p_o_rescale.full.arrive(i_q)

            num_kv_blocks: Tx.let = ceildiv(SEQ_LEN_KV, BLK_N)

            while scheduler.valid():
                # Extract indices from scheduler
                m_block_idx = Tx.meta_var(scheduler.m_block_idx)
                batch_idx = Tx.meta_var(scheduler.batch_idx)
                kv_head_idx = Tx.meta_var(scheduler.head_idx)
                # m_start refers to SEQ_Q positions (not BLK_M rows)
                m_start = Tx.meta_var(m_block_idx * SEQ_Q_PER_TILE * SMEM_PIPE_DEPTH_Q)
                # Tx.attr({"tirx.scope_partition": True})

                if wg_id == 3:
                    Tx.ptx.setmaxnreg(False, 48)
                    with WarpRole(warp_id, 1):

                        @Tx.inline
                        def load_q(i_q):
                            # Use phase_q_load for Q prefetch barrier synchronization
                            q_load.empty.wait(i_q, phase_q_load)
                            # stage_q[0] ->  0 -> 1 -> 0 -> 1 -> ...

                            tma_copy_q = Tx.meta_var({"dispatch": "tma", "mbar": q_load.full.buf.ptr_to([i_q]), "cta_group": CTA_GROUP})
                            # GQA: Load each qo_head with 2D TMA copy
                            # SMEM layout: row i corresponds to (seq = i // GQA_RATIO, head = i % GQA_RATIO)
                            profiler.start(ProfileEventType.IssueTMA_Q, lane_id == 0)
                            Q_smem_3d = Q_smem.view(SMEM_PIPE_DEPTH_Q, SEQ_Q_PER_TILE, GQA_RATIO, HEAD_DIM)
                            with Tx.elected():
                                Tx.copy_async(
                                    Q_smem_3d[i_q, :, :, :], Q[batch_idx, m_start + i_q * SEQ_Q_PER_TILE : m_start + (i_q + 1) * SEQ_Q_PER_TILE, kv_head_idx * GQA_RATIO: (kv_head_idx + 1) * GQA_RATIO, :],
                                    **tma_copy_q,
                                )
                                q_load.full.arrive(i_q, CTA_GROUP * BLK_M * HEAD_DIM * F16_BYTES)  # ar(0,x)
                            profiler.end(ProfileEventType.IssueTMA_Q, lane_id == 0)

                        @Tx.inline
                        def load_k(i_kv):
                            kv_load.empty.wait(kv_pipe.stage, kv_pipe.phase)
                            tma_copy_k = Tx.meta_var({"dispatch": "tma", "mbar": kv_load.full.buf.ptr_to([kv_pipe.stage]), "cta_group": CTA_GROUP})
                            profiler.start(ProfileEventType.IssueTMA_K, lane_id == 0)
                            with Tx.elected():
                                Tx.copy_async(K_smem[kv_pipe.stage, :, :], K[batch_idx, i_kv * BLK_N : (i_kv + 1) * BLK_N, kv_head_idx, :],
                                    **tma_copy_k,
                                )
                                kv_load.full.arrive(kv_pipe.stage, CTA_GROUP * BLK_N * HEAD_DIM * F16_BYTES)
                            profiler.end(ProfileEventType.IssueTMA_K, lane_id == 0)
                            kv_pipe.move_to_next_stage()

                        @Tx.inline
                        def load_v(i_kv):
                            kv_load.empty.wait(kv_pipe.stage, kv_pipe.phase)
                            tma_copy_v = Tx.meta_var({"dispatch": "tma", "mbar": kv_load.full.buf.ptr_to([kv_pipe.stage]), "cta_group": CTA_GROUP})
                            profiler.start(ProfileEventType.IssueTMA_V, lane_id == 0)
                            with Tx.elected():
                                Tx.copy_async(
                                    V_smem[kv_pipe.stage, :, :],
                                    V[batch_idx, i_kv * BLK_N : (i_kv + 1) * BLK_N, kv_head_idx, :],
                                    **tma_copy_v,
                                )
                                kv_load.full.arrive(kv_pipe.stage, CTA_GROUP * BLK_N * HEAD_DIM * F16_BYTES)
                            profiler.end(ProfileEventType.IssueTMA_V, lane_id == 0)
                            kv_pipe.move_to_next_stage()

                        # For causal, compute reduced trip count for loads
                        load_trip_count: Tx.int32
                        load_trip_count = get_n_block_max(m_block_idx, is_causal) if is_causal else num_kv_blocks

                        load_q(0)
                        load_k(load_trip_count - 1)
                        load_q(1)
                        # Flip phase_q_load after Q stages complete (for persistent kernel)
                        phase_q_load ^= 1
                        load_v(load_trip_count - 1)
                        for _i in Tx.serial(load_trip_count - 1, unroll=False):
                            i_kv: Tx.let = load_trip_count - 2 - _i
                            load_k(i_kv)
                            load_v(i_kv)

                    with WarpRole(warp_id, 2):
                        for i_q in Tx.unroll(SMEM_PIPE_DEPTH_Q):  # stage=0,1
                            corr_epi.full.wait(i_q, phase_tmem)
                            if i_q == 0:
                                profiler.start(ProfileEventType.TMAStore, lane_id == 0)
                            # GQA: m_start_global refers to SEQ_Q positions
                            m_start_global = Tx.meta_var(m_start + i_q * SEQ_Q_PER_TILE)
                            # TMA O store: Store each qo_head with 2D TMA copy
                            # SMEM layout: row i corresponds to (seq = i // GQA_RATIO, head = i % GQA_RATIO)
                            O_smem_3d = O_smem.view(TMEM_PIPE_DEPTH, SEQ_Q_PER_TILE, GQA_RATIO, HEAD_DIM)
                            with Tx.elected():
                                Tx.copy_async(
                                    O[batch_idx, m_start_global : m_start_global + SEQ_Q_PER_TILE, kv_head_idx * GQA_RATIO: (kv_head_idx + 1) * GQA_RATIO, :],
                                    O_smem_3d[i_q, :, :, :],
                                    dispatch="tma",
                                )
                            Tx.ptx.cp_async.bulk.commit_group()
                        for i_q in Tx.unroll(SMEM_PIPE_DEPTH_Q):
                            Tx.ptx.cp_async.bulk.wait_group(1 - i_q)
                            corr_epi.empty.arrive(i_q)
                        profiler.end(ProfileEventType.TMAStore, lane_id == 0)
                        phase_tmem ^= 1

                    with WarpRole(warp_id, 0):
                        acc: Tx.int32
                        acc = 0

                        @Tx.inline
                        def gemm_qk(q_stage, kv_stage):
                            with Tx.warp():
                                Tx.gemm_async(
                                    S_region[q_stage],
                                    Q_smem[q_stage, 0:BLK_M, 0:HEAD_DIM],
                                    K_smem[kv_stage, 0:BLK_N, 0:HEAD_DIM],
                                    dispatch="tcgen05",
                                    cta_group=CTA_GROUP,
                                )
                            if Tx.ptx.elect_sync():
                                s_ready.full.arrive(q_stage)

                        @Tx.inline
                        def gemm_pv(i_q, kv_stage, should_accumulate):
                            # TODO: gemm_async causes more spills
                            K_SPLIT = Tx.meta_var(6 * MMA_K)  # 96 — first 6 MMA iterations
                            # First part: k=0..5 (P cols 0..95, V rows 0..95)
                            with Tx.warp():
                                Tx.gemm_async(
                                    O_region[i_q],
                                    P_region[i_q, 0:K_SPLIT],
                                    V_smem[kv_stage, 0:K_SPLIT, 0:HEAD_DIM],
                                    transB=True,
                                    accum=should_accumulate,
                                    dispatch="tcgen05",
                                    cta_group=CTA_GROUP,
                                )
                            # Wait for last 1/4 of P
                            p_ready_2.full.wait(i_q, phase_tmem)
                            # Second part: k=6..7 (P cols 96..127, V rows 96..127)
                            with Tx.warp():
                                Tx.gemm_async(
                                    O_region[i_q],
                                    P_region[i_q, K_SPLIT:BLK_N],
                                    V_smem[kv_stage, K_SPLIT:BLK_N, 0:HEAD_DIM],
                                    transB=True,
                                    accum=True,
                                    dispatch="tcgen05",
                                    cta_group=CTA_GROUP,
                                )

                        for i_q in Tx.unroll(SMEM_PIPE_DEPTH_Q):
                            q_load.full.wait(i_q, phase_q_load)
                            if i_q == 0:
                                # for 2 q, confirm k is loaded
                                kv_load.full.wait(kv_pipe.stage, kv_pipe.phase)
                            gemm_qk(i_q, kv_pipe.stage)
                            if i_q == 1:
                                # finish twice qk mma
                                if Tx.ptx.elect_sync():
                                    kv_load.empty.arrive(kv_pipe.stage)
                        kv_pipe.move_to_next_stage()

                        # For causal, compute reduced trip count
                        mma_trip_count: Tx.int32
                        mma_trip_count = get_n_block_max(m_block_idx, is_causal) if is_causal else num_kv_blocks

                        for i_kv in Tx.serial(
                            mma_trip_count - 1, unroll=False
                        ):
                            stage_v: Tx.let = kv_pipe.stage
                            phase_v: Tx.let = kv_pipe.phase
                            kv_pipe.move_to_next_stage()
                            stage_k = Tx.meta_var(kv_pipe.stage)
                            phase_k = Tx.meta_var(kv_pipe.phase)

                            for i_q in Tx.unroll(SMEM_PIPE_DEPTH_Q):
                                if i_q == 0:
                                    # wait for v is loaded
                                    kv_load.full.wait(stage_v, phase_v)
                                # wait for o_full to be ready
                                p_o_rescale.full.wait(i_q, phase_tmem)
                                gemm_pv(i_q, stage_v, acc)
                                if i_q == 1:
                                    # finish twice pv mma
                                    if Tx.ptx.elect_sync():
                                        kv_load.empty.arrive(stage_v)
                                if i_q == 0:
                                    # for 2 q, confirm k is loaded
                                    kv_load.full.wait(stage_k, phase_k)
                                gemm_qk(i_q, stage_k)
                                if i_q == 1:
                                    # finish twice qk mma
                                    if Tx.ptx.elect_sync():
                                        kv_load.empty.arrive(stage_k)
                            acc = 1
                            kv_pipe.move_to_next_stage()
                            phase_tmem ^= 1

                        for i_q in Tx.unroll(SMEM_PIPE_DEPTH_Q):
                            if i_q == 0:
                                # wait for v is loaded
                                kv_load.full.wait(kv_pipe.stage, kv_pipe.phase)
                            # wait for o_full to be ready
                            p_o_rescale.full.wait(i_q, phase_tmem)
                            gemm_pv(i_q, kv_pipe.stage, acc)
                            if i_q == 1:
                                # finish twice pv mma
                                if Tx.ptx.elect_sync():
                                    kv_load.empty.arrive(kv_pipe.stage)
                            if Tx.ptx.elect_sync():
                                o_ready.full.arrive(i_q)
                        kv_pipe.move_to_next_stage()
                        phase_tmem ^= 1

                        for i_q in Tx.unroll(SMEM_PIPE_DEPTH_Q):
                            if Tx.ptx.elect_sync():
                                q_load.empty.arrive(i_q)

                        # Flip phase_q_load after Q stages complete (for persistent kernel)
                        phase_q_load ^= 1

                elif wg_id < 2:
                    with Tx.warpgroup():
                        # here phase_q and stage_q represent phase_tmem and stage_tmem

                        Tx.ptx.setmaxnreg(True, 200)

                        scale_log2 = Tx.meta_var(math.log2(math.e) / math.sqrt(HEAD_DIM))
                        rescale_threshold = Tx.meta_var(8.0)

                        row_max: Tx.f32[1]
                        row_sum: Tx.f32[1]

                        @Tx.inline
                        def mask_r2p(s_chunk_buf, col_limit, ncol: Tx.int32):
                            """Apply mask using R2P-style bit manipulation.

                            Optimizes: for j in range(N): buf[j] = -inf if j >= col_limit else buf[j]
                            Into: bitmask operations that compile to R2P PTX instruction.

                            Following flash_attn/cute/mask.py mask_r2p() lines 13-40:
                            Process in 24-element chunks because shift by 31+ bits is problematic.
                            For ncol=128: chunks 0-4 have 24 elements, chunk 5 has 8 elements.

                            The bit test `mask & (1 << i)` compiles to the R2P (Register to Predicate)
                            PTX instruction, which is more efficient than per-column comparisons.
                            """
                            ncol = Tx.meta_var(ncol)
                            CHUNK_SIZE: Tx.let = 24  # Max safe shift amount (< 32)
                            num_chunks: Tx.let = ceildiv(ncol, CHUNK_SIZE)

                            with Tx.thread():
                                s_chunk_local = s_chunk_buf.local(ncol)
                                for s in Tx.unroll(num_chunks):
                                    # Compute col_limit for this chunk (clamped to [0, chunk_cols])
                                    col_limit_s: Tx.let = Tx.min(Tx.max(col_limit - s * CHUNK_SIZE, 0), CHUNK_SIZE)
                                    mask: Tx.uint32
                                    # Create bitmask: col_limit=5 -> 0b11111 (bits 0-4 set)
                                    mask = Tx.shift_left(Tx.int32(1), col_limit_s) - 1

                                    # Apply mask to each column in this chunk
                                    for i in Tx.unroll(CHUNK_SIZE):
                                        if i < ncol - s * CHUNK_SIZE:
                                            c: Tx.let = s * CHUNK_SIZE + i
                                            in_bound: Tx.let = Tx.bitwise_and(mask, Tx.shift_left(Tx.int32(1), i))
                                            s_chunk_local[c] = Tx.Select(Tx.cast(in_bound, "bool"), s_chunk_local[c], Tx.float32(-float("inf")))

                        @Tx.inline
                        def apply_causal_mask(s_chunk_buf, m_blk_idx, n_blk_idx):
                            """Apply causal mask to attention scores.

                            Following flash_attn/cute/mask.py apply_mask_sm100() lines 384-400:
                            causal_row_offset = 1 + seqlen_k - n_block * tile_n - seqlen_q
                            row_idx = thread_row + m_block * tile_m
                            col_limit_right = row_idx + causal_row_offset
                            Mask if col >= col_limit_right

                            Coordinate Mapping:
                            - BLK_M = 128 packed rows per tile
                            - SEQ_Q_PER_TILE = BLK_M // GQA_RATIO (e.g., 32 for GQA_RATIO=4)
                            - Each warpgroup handles one Q stage with SEQ_Q_PER_TILE sequence positions
                            - tid_in_wg (0-127) maps to packed rows: (seq_pos, head) = (tid//GQA_RATIO, tid%GQA_RATIO)
                            """
                            # Convert thread index to sequence position within warpgroup
                            seq_pos_in_wg: Tx.let = tid_in_wg // GQA_RATIO

                            # Global sequence position
                            # wg_id 0/1 handles different Q stages (each stage has SEQ_Q_PER_TILE positions)
                            # m_block covers SEQ_Q_PER_TILE * SMEM_PIPE_DEPTH_Q sequence positions
                            row_idx: Tx.let = (m_blk_idx * SEQ_Q_PER_TILE * SMEM_PIPE_DEPTH_Q +
                                    wg_id * SEQ_Q_PER_TILE +
                                    seq_pos_in_wg)

                            # Causal row offset (from mask.py:385)
                            # For seq_len_q == seq_len_kv: causal_row_offset = 1 - n_block * BLK_N
                            causal_row_offset: Tx.let = 1 + SEQ_LEN_KV - n_blk_idx * BLK_N - SEQ_LEN_Q

                            # Column limit: mask if col >= col_limit_right
                            col_limit_right: Tx.let = row_idx + causal_row_offset

                            # Use R2P-style masking instead of per-column comparison
                            mask_r2p(s_chunk_buf, col_limit_right, BLK_N)

                        @Tx.inline
                        def softmax_step(i_kv, apply_mask=False, is_first=False):
                            s_chunk_buf: Tx.f32[BLK_N]
                            s_chunk = s_chunk_buf.view(128, BLK_N, layout=wg_local_layout(BLK_N))
                            p_chunk_buf_f32: Tx.f32[BLK_N // 2]
                            p_chunk_buf = Tx.decl_buffer((BLK_N,), dtype="float16", data=p_chunk_buf_f32.data)
                            p_chunk = p_chunk_buf.view(128, BLK_N, layout=wg_local_layout(BLK_N))

                            s_ready.full.wait(wg_id, phase_s_full)  # noqa: F823
                            profiler.start(ProfileEventType.Softmax_MAX, tid_in_wg == 0)
                            tile_max: Tx.f32[1]
                            for chunk_idx in Tx.unroll(BLK_N // SOFTMAX_LD_CHUNK):
                                Tx.copy_async(s_chunk[:, chunk_idx * SOFTMAX_LD_CHUNK : (chunk_idx + 1) * SOFTMAX_LD_CHUNK], S_region[wg_id, chunk_idx * SOFTMAX_LD_CHUNK : (chunk_idx + 1) * SOFTMAX_LD_CHUNK])

                            # Apply causal mask if needed
                            if apply_mask:
                                apply_causal_mask(s_chunk_buf, m_block_idx, i_kv)

                            row_max_old: Tx.f32
                            row_max_old = row_max[0]
                            with Tx.thread():
                                if is_first:
                                    Tx.max(tile_max, s_chunk_buf)
                                else:
                                    tile_max[0] = row_max_old
                                    Tx.max(tile_max, s_chunk_buf, accum=True)
                            row_max_new: Tx.f32
                            acc_scale: Tx.f32
                            acc_scale_: Tx.f32  # For slack check
                            row_max_safe: Tx.f32
                            row_max_new = tile_max[0]
                            row_max_safe = Tx.if_then_else(tile_max[0] == -float("inf"), 0.0, tile_max[0])

                            if is_first:
                                acc_scale = Tx.float32(1.0)
                            else:
                                acc_scale_ = (row_max_old - row_max_safe) * scale_log2

                                # if the difference is too small, don't rescale
                                if acc_scale_ >= -rescale_threshold:
                                    row_max_new = row_max_old
                                    row_max_safe = row_max_old
                                    acc_scale = Tx.float32(1.0)
                                else:
                                    acc_scale = Tx.ptx.exp2(acc_scale_)

                            # row_max is the max value of the tile
                            # and row_max_scaled is the max value of the tile after scaled
                            # scale_log2 is the log2 of the scale factor
                            row_max[0] = row_max_new
                            row_max_scaled: Tx.let = row_max_safe * scale_log2
                            profiler.end(ProfileEventType.Softmax_MAX, tid_in_wg == 0)

                            # Write acc_scale to sScale and arrive immediately (no wait here)
                            if tid_in_wg < BLK_M and not is_first:
                                sScale_idx: Tx.let = ACC_SCALE_BASE + tid_in_wg + wg_id * BLK_M
                                sScale[sScale_idx] = acc_scale
                            softmax_corr.full.arrive(wg_id)
                            profiler.start(ProfileEventType.Softmax_FMA, tid_in_wg == 0)
                            Tx.fma(s_chunk, s_chunk, scale_log2, -row_max_scaled)
                            profiler.end(ProfileEventType.Softmax_FMA, tid_in_wg == 0)
                            if USE_S0_S1_BARRIER:
                                bar_s0_s1_sequence.wait(wg_id * 4 + warp_id, phase_s0_s1)  # noqa: F823
                            profiler.start(ProfileEventType.Softmax_EXP2, tid_in_wg == 0)
                            for frag_idx in Tx.unroll(4):
                                with Tx.thread():
                                    s_chunk_local = s_chunk_buf.local(BLK_N)
                                    for i in Tx.unroll(BLK_N // 4 // 2):
                                        idx = Tx.meta_var(frag_idx * BLK_N // 4 + 2 * i)
                                        if i * 2 % 16 < 16 - 4 or frag_idx >= 4 - 1 or apply_mask:
                                            s_chunk_local[idx] = Tx.ptx.exp2(s_chunk_local[idx])
                                            s_chunk_local[idx + 1] = Tx.ptx.exp2(s_chunk_local[idx + 1])
                                        else:
                                            ex2_emulation_2(s_chunk_local, idx, s_chunk_local[idx], s_chunk_local[idx + 1])
                                Tx.cast(p_chunk[:, frag_idx * BLK_N // 4 : (frag_idx + 1) * BLK_N // 4], s_chunk[:, frag_idx * BLK_N // 4 : (frag_idx + 1) * BLK_N // 4])
                            if USE_S0_S1_BARRIER:
                                bar_s0_s1_sequence.arrive((1 - wg_id) * 4 + warp_id)
                            profiler.end(ProfileEventType.Softmax_EXP2, tid_in_wg == 0)
                            profiler.start(ProfileEventType.Softmax_TMEM_ST, tid_in_wg == 0)
                            for i in Tx.unroll(3):
                                Tx.copy_async(P_region[wg_id, i * BLK_N // 4 : (i + 1) * BLK_N // 4], p_chunk[:, i * BLK_N // 4 : (i + 1) * BLK_N // 4])
                            Tx.ptx.tcgen05.wait.st()
                            p_o_rescale.full.arrive(wg_id)
                            Tx.copy_async(P_region[wg_id, 3 * BLK_N // 4 : BLK_N], p_chunk[:, 3 * BLK_N // 4 : BLK_N])
                            Tx.ptx.tcgen05.wait.st()
                            p_ready_2.full.arrive(wg_id)

                            profiler.end(ProfileEventType.Softmax_TMEM_ST, tid_in_wg == 0)

                            # Wait for correction warp to finish reading previous acc_scale
                            softmax_corr.empty.wait(wg_id, phase_q)  # noqa: F823

                            profiler.start(ProfileEventType.Softmax_SUM, tid_in_wg == 0)
                            phase_s_full ^= 1
                            phase_q ^= 1
                            with Tx.thread():
                                if is_first:
                                    Tx.sum(row_sum, s_chunk_buf)
                                else:
                                    row_sum[0] = row_sum[0] * acc_scale
                                    Tx.sum(row_sum, s_chunk_buf, accum=True)
                            profiler.end(ProfileEventType.Softmax_SUM, tid_in_wg == 0)
                            if USE_S0_S1_BARRIER:
                                phase_s0_s1 ^= 1

                        softmax_corr.empty.wait(wg_id, phase_q)
                        phase_q ^= 1
                        # Compute block ranges for this Q block
                        n_block_max: Tx.let = get_n_block_max(m_block_idx, is_causal)
                        n_block_min_causal: Tx.let = get_n_block_min_causal_mask(m_block_idx) if is_causal else n_block_max

                        # Phase 1: Last KV block (n_block_max - 1) with causal mask
                        # This block may have both seqlen boundary AND causal masking
                        softmax_step(n_block_max - 1, apply_mask=is_causal, is_first=True)

                        # Update n_block_max after Phase 1
                        n_block_max_after_p1: Tx.let = n_block_max - 1

                        # Phase 2: Blocks with partial causal masking
                        # These are blocks in [n_block_min_causal, n_block_max - 1)
                        num_phase2_blocks: Tx.let = Tx.max(n_block_max_after_p1 - n_block_min_causal, 0)
                        for i in Tx.serial(num_phase2_blocks, unroll=False):
                            n_block: Tx.let = n_block_max_after_p1 - 1 - i
                            softmax_step(n_block, apply_mask=True)

                        # Update n_block_max after Phase 2
                        n_block_max_after_p2: Tx.let = Tx.min(n_block_max_after_p1, n_block_min_causal)

                        # Phase 3: Unmasked blocks (no causal mask overhead)
                        # These are blocks in [0, n_block_min_causal)
                        for i in Tx.serial(n_block_max_after_p2, unroll=False):
                            n_block: Tx.let = n_block_max_after_p2 - 1 - i
                            softmax_step(n_block, apply_mask=False)
                        if tid_in_wg < BLK_M:
                            sScale[ROW_SUM_BASE + tid_in_wg + wg_id * BLK_M] = row_sum[0]
                        softmax_corr.full.arrive(wg_id)
                with WarpgroupRole(wg_id, 2, regs=64):

                    softmax_corr.full.wait(0, phase_q)
                    softmax_corr.empty.arrive(0)
                    softmax_corr.full.wait(1, phase_q)
                    phase_q ^= 1

                    # For causal, compute reduced trip count for correction warp
                    corr_trip_count: Tx.let = get_n_block_max(m_block_idx, is_causal) if is_causal else num_kv_blocks

                    for i_kv in Tx.serial(corr_trip_count - 1, unroll=False):
                        for i_q in Tx.unroll(2):
                            softmax_corr.full.wait(i_q, phase_q)
                            profiler.start(ProfileEventType.Correction, tid_in_wg == 0)
                            acc_scale: Tx.f32
                            should_rescale: Tx.i32

                            if tid_in_wg < BLK_M:
                                acc_scale = sScale[ACC_SCALE_BASE + tid_in_wg + i_q * BLK_M]
                                should_rescale = Tx.Select(acc_scale < Tx.float32(1.0), 1, 0)
                            else:
                                should_rescale = 0

                            any_needs_rescale: Tx.let = Tx.ptx.any_sync(0xFFFFFFFF, should_rescale)
                            if any_needs_rescale != 0:
                                if tid_in_wg < BLK_M:
                                    RESCALE_TILE = Tx.meta_var(16)

                                    o_row = Tx.alloc_buffer((128, RESCALE_TILE), "float32", layout=wg_local_layout(RESCALE_TILE), scope="local")

                                    for d_tile in Tx.unroll(ceildiv(HEAD_DIM, RESCALE_TILE)):
                                        d_start: Tx.let = d_tile * RESCALE_TILE
                                        if d_start < HEAD_DIM:
                                            Tx.copy_async(o_row, O_region[i_q, d_start : d_start + RESCALE_TILE])
                                            Tx.mul(o_row, o_row, acc_scale)
                                            Tx.copy_async(O_region[i_q, d_start : d_start + RESCALE_TILE], o_row)
                                    Tx.ptx.tcgen05.wait.st()

                            p_o_rescale.full.arrive(i_q)
                            softmax_corr.empty.arrive(1 - i_q)
                            profiler.end(ProfileEventType.Correction, tid_in_wg == 0)
                        # flip epi producer phase
                        phase_q ^= 1
                    softmax_corr.empty.arrive(1)

                    for i_q in Tx.unroll(2):
                        # 1. Wait for softmax to signal row_sum is ready
                        softmax_corr.full.wait(i_q, phase_q)

                        # 2. Read row_sum and release softmax_corr_empty immediately
                        row_sum: Tx.let = sScale[ROW_SUM_BASE + tid_in_wg + i_q * BLK_M]
                        softmax_corr.empty.arrive(i_q)

                        # 3. Wait for O_full and epi_empty (after releasing softmax)
                        o_ready.full.wait(i_q, phase_tmem)
                        corr_epi.empty.wait(i_q, phase_tmem)

                        profiler.start(ProfileEventType.EpiLDTMEM, tid_in_wg == 0)
                        acc_O_mn_row_is_zero_or_nan: Tx.let = tvm.tirx.any(row_sum == Tx.float32(0.0), row_sum != row_sum)
                        norm_scale: Tx.let = Tx.ptx.rcp(Tx.Select(acc_O_mn_row_is_zero_or_nan, Tx.float32(1.0), row_sum))
                        o_row_f32 = Tx.alloc_buffer((128, TMEM_EPI_LD_SIZE), "float32", layout=wg_local_layout(TMEM_EPI_LD_SIZE), scope="local")
                        o_row_f16 = Tx.alloc_buffer((128, TMEM_EPI_LD_SIZE), "float16", layout=wg_local_layout(TMEM_EPI_LD_SIZE), scope="local")

                        for d_tile in Tx.unroll(ceildiv(HEAD_DIM, TMEM_EPI_LD_SIZE)):
                            d_start: Tx.let = d_tile * TMEM_EPI_LD_SIZE
                            if d_start < HEAD_DIM:
                                Tx.copy_async(o_row_f32, O_region[i_q, d_start : d_start + TMEM_EPI_LD_SIZE])
                                Tx.mul(o_row_f32, o_row_f32, norm_scale)
                                Tx.cast(o_row_f16, o_row_f32)
                                Tx.copy(O_smem[i_q, tid_in_wg, d_tile * TMEM_EPI_LD_SIZE : d_tile * TMEM_EPI_LD_SIZE + TMEM_EPI_LD_SIZE], o_row_f16, vec_len=8)

                            profiler.end(ProfileEventType.EpiLDTMEM, tid_in_wg == 0)
                        Tx.ptx.fence.proxy_async("shared::cta")

                        # arrive epi_full
                        corr_epi.full.arrive(i_q)
                        # Signal for the next work tile that O buffers in tmem are already read
                        p_o_rescale.full.arrive(i_q)
                    phase_tmem ^= 1
                    phase_q ^= 1

                scheduler.next_tile()

            # Deallocate TMEM after all tasks complete
            tmem_pool.dealloc()

            Tx.cuda.cta_sync()

    return flash_attention4
# fmt: on


def prepare_data(batch_size, seq_len_q, seq_len_kv, num_qo_heads, num_kv_heads, head_dim):
    torch.manual_seed(0)
    Q = torch.randn((batch_size, seq_len_q, num_qo_heads, head_dim), dtype=torch.float16)
    K = torch.randn((batch_size, seq_len_kv, num_kv_heads, head_dim), dtype=torch.float16)
    V = torch.randn((batch_size, seq_len_kv, num_kv_heads, head_dim), dtype=torch.float16)
    O = torch.zeros((batch_size, seq_len_q, num_qo_heads, head_dim), dtype=torch.float16)  # noqa: E741

    return Q, K, V, O


# ── Standard kernel interface ──────────────────────────────────────────

KERNEL_META = {
    "name": "flash_attention4",
    "category": "attention",
    "compute_capability": 10,
}

CONFIGS = [
    {
        "batch_size": 1,
        "seq_len": sl,
        "num_qo_heads": 32,
        "num_kv_heads": kv,
        "head_dim": 128,
        "is_causal": causal,
        "label": f"s{sl}_h32kv{kv}{'_causal' if causal else ''}",
    }
    for sl in [1024, 2048, 4096, 8192]
    for kv in [4, 8, 16, 32]
    for causal in [False, True]
]


def get_kernel(
    batch_size, seq_len, num_qo_heads, num_kv_heads, head_dim, is_causal=False, **kwargs
):
    return get_flash_attention4_kernel(
        batch_size,
        seq_len,
        seq_len,
        num_qo_heads,
        num_kv_heads,
        head_dim,
        is_causal=is_causal,
    )


def run_test(batch_size, seq_len, num_qo_heads, num_kv_heads, head_dim, is_causal=False, **kwargs):
    """Compile, run, and verify flash attention 4 kernel."""
    from tirx_kernels.runner import compile_kernel

    Q, K, V, _ = prepare_data(batch_size, seq_len, seq_len, num_qo_heads, num_kv_heads, head_dim)
    prim_func = get_flash_attention4_kernel(
        batch_size,
        seq_len,
        seq_len,
        num_qo_heads,
        num_kv_heads,
        head_dim,
        is_causal=is_causal,
    )
    ex = compile_kernel(prim_func)

    dev = tvm.cuda(0)
    Q_tvm = tvm.runtime.tensor(Q.cpu().numpy(), device=dev)
    K_tvm = tvm.runtime.tensor(K.cpu().numpy(), device=dev)
    V_tvm = tvm.runtime.tensor(V.cpu().numpy(), device=dev)
    O_tvm = tvm.runtime.tensor(
        np.zeros((batch_size, seq_len, num_qo_heads, head_dim), dtype=np.float16), dev
    )
    profiler_buf = tvm.runtime.tensor(np.zeros(PROFILER_BUFFER_SIZE, dtype=np.uint64), dev)

    ex(Q_tvm, K_tvm, V_tvm, O_tvm, profiler_buf)
    torch.cuda.synchronize()

    # Reference: naive scaled-dot-product attention
    Q_t = Q.float().transpose(1, 2)
    K_t = K.float().transpose(1, 2)
    V_t = V.float().transpose(1, 2)
    if num_qo_heads != num_kv_heads:
        repeat_factor = num_qo_heads // num_kv_heads
        K_t = K_t.repeat_interleave(repeat_factor, dim=1)
        V_t = V_t.repeat_interleave(repeat_factor, dim=1)
    scale = 1.0 / math.sqrt(head_dim)
    scores = torch.matmul(Q_t, K_t.transpose(-2, -1)) * scale
    if is_causal:
        mask = torch.triu(torch.ones(seq_len, seq_len, dtype=torch.bool), diagonal=1)
        scores.masked_fill_(mask, float("-inf"))
    attn = torch.softmax(scores, dim=-1)
    ref = torch.matmul(attn, V_t).transpose(1, 2).to(torch.float16)
    np.testing.assert_allclose(O_tvm.numpy(), ref.cpu().numpy(), rtol=1e-2, atol=1e-2)

```
