# Asynchronous GEMM Pipeline
:label:`chap_gemm_async`

The synchronous tiled GEMM becomes an asynchronous pipeline through TMA async loads, software pipelining, and persistent tile scheduling.

The SMEM/TMEM/register layouts follow the same patterns as Step 1 in :numref:`chap_gemm_basics`. :numref:`chap_layouts` defines `tma_shared_layout`, the TMEM `(1@TLane, 1@TCol)` axes, and the warpgroup view `(1@tid_in_wg, 1)`.

## Step 4: TMA Async Load
:label:`chap_tma_async`

The first asynchronous step replaces synchronous `Tx.copy` with TMA hardware. One thread issues the command, and the hardware performs the tile movement. Benchmarks use M=N=K=4096.

**Topics.**

- Replacing synchronous `Tx.copy` with asynchronous TMA: `Tx.copy_async(..., dispatch="tma")`

- Single-thread TMA load dispatch via a `tid == 0` predicate (and why `elect_sync()` alone is subtly wrong here)

- mbarrier-based byte-counting synchronization: `arrive.expect_tx` / `try_wait`

- TMA store writeback: TMEM -> register file -> cast -> Dsmem -> TMA store -> GMEM, with proper sync at each stage

### TMA Issue Pattern

The code change from Step 3 is small, but it changes who moves the data:

**Before (Step 3)** — all 128 threads copy, then `cta_sync`:
```python
with Tx.cta():
    Tx.copy(Asmem[:, :], A[m_st:m_st+BLK_M, i*BLK_K:(i+1)*BLK_K])   # all 128 threads
    Tx.copy(Bsmem[:, :], B[n_st:n_st+BLK_N, i*BLK_K:(i+1)*BLK_K])
Tx.cuda.cta_sync()
```

**After (Step 4)** — a single thread issues TMA, mbarrier synchronizes:
```python
tid = warp_id * 32 + lane_id                 # 0..127 within the warpgroup
with Tx.thread(tid == 0):   # exactly 1 thread
    Tx.copy_async(Asmem, A[...], dispatch="tma")
    Tx.copy_async(Bsmem, B[...], dispatch="tma")
    mbarrier.arrive.expect_tx(byte_count)       # tell barrier how many bytes
mbarrier.try_wait(phase)                         # all threads wait until TMA completes
```

A common pitfall is to reach for `elect_sync()` here. `elect.sync` is a *per-warp* PTX instruction, so `with Tx.thread(Tx.filter(lane_id, Tx.ptx.elect_sync()))` gives you **one elected thread per warp = 4 threads in a 4-warp warpgroup**, not 1. On the TMA load side, that would increment the expected byte count multiple times, so these kernels pick a single issuer with `tid == 0`. (Note: `Tx.filter` takes a *variable* — `lane_id`, `warp_id`, etc. — not an axis token. The axis-name imports like `from tvm.tirx.layout import tid_in_wg` are for `1@tid_in_wg`-style layout expressions only.)

**Why faster**: Step 4 still waits after each TMA load, so the speedup is not from load/compute overlap yet. It comes from *how* data is moved:

- **`Tx.copy` occupies SM instruction pipelines** — 128 threads each compute addresses and issue global load / shared store instructions, consuming warp scheduler bandwidth on memory operations.
- **TMA is a dedicated DMA engine** — one `cp.async.bulk` instruction triggers the hardware to transfer the entire tile. Address generation, coalescing, and swizzle are handled in hardware via the TMA descriptor, not by thread ALU.
- The net effect: the SM spends fewer thread instructions on tile movement, and the hardware copy path handles the bulk transfer.

### What Changes

Three things change when the load moves from synchronous thread copies to TMA:

| | `Tx.copy` (Steps 1–3) | `Tx.copy_async` (Step 4+) |
|---|---|---|
| **Who executes** | All threads in the scope | TMA hardware engine — one thread issues, hardware does the rest |
| **Dispatch** | software (default) | `dispatch="tma"` |
| **Sync** | `cta_sync()` (all threads arrived) | `mbarrier.try_wait(phase)` (TMA engine completion) |
| **Scope** | `with Tx.cta():` | `with Tx.thread(tid == 0):` |

The two sync primitives are not interchangeable. `cta_sync()` is `__syncthreads()` — it says "all CTA threads have arrived here", carries an implicit release/acquire fence for SMEM, but says **nothing** about async hardware. `mbarrier.try_wait(phase)` is *event* sync — it waits for the async engine to signal completion via byte counting, and the engine's arrival carries the release→acquire edge to downstream consumers (e.g., the MMA that reads the just-loaded SMEM). Step 4 uses both: `cta_sync` between warpgroup TMEM reads, and `try_wait` for "TMA done".

![TMA Async Load: Synchronization Flow](../img/tma_sync_flow.png)

**TMA load** (top of the kernel): one selected thread issues both `copy_async` calls, then calls `arrive.expect_tx(total_bytes)` to tell the mbarrier how many bytes to expect. The TMA hardware arrives on the mbarrier as bytes land. All threads then `try_wait(phase)` until ready.

**TMA store** (writeback): the protocol is intentionally different. TMA loads use mbarriers (byte counting); TMA stores use **commit-group / wait-group**. After casting registers to fp16, writing them into `Dsmem`, fencing, and `warpgroup_sync(10)`, one selected thread issues `Tx.copy_async(D[...], Dsmem, dispatch="tma")`, then `cp_async.bulk.commit_group()` + `cp_async.bulk.wait_group(0)` ensure the store has drained before SMEM is reused.

**Implementation.**

```{.python .input}

import tvm
from tvm.script import tirx as Tx
from tvm.tirx.layout import TileLayout, S, TLane, TCol, tid_in_wg
from tvm.tirx.operator.tile_primitive.cuda.tma_utils import tma_shared_layout, SwizzleMode
```

Constants and swizzled SMEM layouts for A, B, and D tiles (see :numref:`chap_layouts` for the helper and swizzle modes):

```{.python .input}
a_type = tvm.DataType("float16")
b_type = tvm.DataType("float16")
d_type = tvm.DataType("float16")
acc_type = tvm.DataType("float32")
M, N, K = 4096, 4096, 4096

BLK_M, BLK_N, BLK_K = 128, 128, 64
MMA_M, MMA_N, MMA_K = 128, 128, 16
F16_SIZE = 2

A_layout = tma_shared_layout(a_type, SwizzleMode.SWIZZLE_128B_ATOM, (BLK_M, BLK_K))
B_layout = tma_shared_layout(b_type, SwizzleMode.SWIZZLE_128B_ATOM, (BLK_N, BLK_K))
D_layout = tma_shared_layout(d_type, SwizzleMode.SWIZZLE_128B_ATOM, (BLK_M, BLK_N))
```

The kernel — TMA async load replaces synchronous copy, TMA store replaces direct GMEM writes:

```{.python .input}
@Tx.prim_func
def hgemm_v4(
    A: Tx.Buffer((M, K), a_type),
    B: Tx.Buffer((N, K), b_type),
    D: Tx.Buffer((M, N), d_type),
):
    with Tx.kernel():
        bx, by = Tx.cta_id([M // BLK_M, N // BLK_N])
        wg_id = Tx.warpgroup_id([1])
        warp_id = Tx.warp_id_in_wg([4])
        lane_id = Tx.lane_id([32])

        # --- SMEM allocation (now includes Dsmem for TMA store) ---
        pool = Tx.SMEMPool()
        tmem_addr = pool.alloc((1,), "uint32")
        tma_bar = pool.alloc((1,), "uint64", align=8)
        mma_bar = pool.alloc((1,), "uint64", align=8)
        pool.move_base_to(1024)
        Asmem = pool.alloc((BLK_M, BLK_K), a_type, layout=A_layout)
        Bsmem = pool.alloc((BLK_N, BLK_K), b_type, layout=B_layout)
        Dsmem = pool.alloc((BLK_M, BLK_N), d_type, layout=D_layout)
        pool.commit()

        # --- Barrier + TMEM init ---
        if warp_id == 0 and lane_id == 0:
            Tx.ptx.mbarrier.init(mma_bar.ptr_to([0]), 1)
            Tx.ptx.mbarrier.init(tma_bar.ptr_to([0]), 1)
        if warp_id == 0:
            Tx.ptx.tcgen05.alloc(Tx.address_of(tmem_addr), n_cols=512, cta_group=1)

        Tx.ptx.fence.proxy_async("shared::cta")
        Tx.ptx.fence.mbarrier_init()
        Tx.cuda.cta_sync()

        tmem = Tx.decl_buffer(
            (128, 512), "float32", scope="tmem", allocated_addr=tmem_addr[0],
            layout=TileLayout(S[(128, 512) : (1@TLane, 1@TCol)])
        )

        m_st = Tx.meta_var(bx * BLK_M)
        n_st = Tx.meta_var(by * BLK_N)
        phase_tma: Tx.int32 = 0
        phase_mma: Tx.int32 = 0

        # --- Inline helpers ---
        @Tx.inline
        def tma_load(k_st):
            tma_config = Tx.meta_var({
                "dispatch": "tma", "cta_group": 1,
                "mbar": tma_bar.ptr_to([0])
            })
            Tx.copy_async(Asmem[:, :],
                          A[m_st : m_st + BLK_M, k_st : k_st + BLK_K],
                          **tma_config)
            Tx.copy_async(Bsmem[:, :],
                          B[n_st : n_st + BLK_N, k_st : k_st + BLK_K],
                          **tma_config)
            Tx.ptx.mbarrier.arrive.expect_tx(
                tma_bar.ptr_to([0]),
                (BLK_M * BLK_K + BLK_N * BLK_K) * F16_SIZE
            )

        @Tx.inline
        def mma(accum):
            Tx.gemm_async(
                tmem[:, :BLK_N], Asmem[:, :], Bsmem[:, :],
                accum=accum, dispatch="tcgen05", cta_group=1
            )
            Tx.ptx.tcgen05.commit(mma_bar.ptr_to([0]), cta_group=1)

        # --- K-loop with TMA async ---
        tid = Tx.meta_var(warp_id * 32 + lane_id)
        for k in range(K // BLK_K):
            k_st = Tx.meta_var(k * BLK_K)

            # Single thread issues TMA load
            with Tx.thread(tid == 0):
                tma_load(k_st)

            # Wait for TMA to finish; the mbarrier release carries SMEM
            # visibility to the subsequent MMA, so no extra fence is needed.
            Tx.ptx.mbarrier.try_wait(tma_bar.ptr_to([0]), phase_tma)

            # Single thread issues MMA
            with Tx.thread(tid == 0):
                mma(accum=k != 0)

            # Wait for MMA to finish
            Tx.ptx.mbarrier.try_wait(mma_bar.ptr_to([0]), phase_mma)
            phase_tma ^= 1
            phase_mma ^= 1

        # --- TMA Store Writeback ---
        Dreg = Tx.alloc_local((BLK_N,), acc_type)
        Dreg_f16 = Tx.alloc_local((BLK_N,), d_type)
        Dreg_wg = Dreg.view(128, BLK_N,
                            layout=TileLayout(S[(128, BLK_N) : (1@tid_in_wg, 1)]))

        # Read TMEM -> registers (async; wait.ld then cta_sync to ensure read completes)
        with Tx.warpgroup():
            Tx.copy_async(Dreg_wg[:, :], tmem[:, :BLK_N])
            Tx.ptx.tcgen05.wait.ld()
            Tx.cuda.cta_sync()
        # Cast fp32 -> fp16
        with Tx.thread():
            Tx.cast(Dreg_f16[:], Dreg[:])
        # Write registers -> Dsmem, flush, then sync
        with Tx.thread():
            Tx.copy(Dsmem[warp_id * 32 + lane_id, 0:BLK_N], Dreg_f16[:])
            Tx.ptx.fence.proxy_async("shared::cta")
            Tx.cuda.warpgroup_sync(10)
        # TMA store: Dsmem -> GMEM. This path uses one selected issuer and drains the
        # store group before Dsmem is reused.
        with Tx.thread(tid == 0):
            Tx.copy_async(D[m_st : m_st + BLK_M, n_st : n_st + BLK_N],
                          Dsmem[:, :], dispatch="tma")
            Tx.ptx.cp_async.bulk.commit_group()
            Tx.ptx.cp_async.bulk.wait_group(0)
        Tx.cuda.warpgroup_sync(10)

        # --- Deallocate TMEM ---
        Tx.cuda.cta_sync()
        if warp_id == 0:
            Tx.ptx.tcgen05.relinquish_alloc_permit(cta_group=1)
            Tx.ptx.tcgen05.dealloc(tmem_addr[0], n_cols=512, cta_group=1)
```

Compile and run:

```{.python .input}
import torch

target = tvm.target.Target("cuda")
with target:
    mod = tvm.IRModule({"main": hgemm_v4})
    lib = tvm.compile(mod, target=target, tir_pipeline="tirx")

device = torch.device('cuda')  # gpu(0)
torch.cuda.empty_cache()
torch.cuda.synchronize()
A_tensor = torch.randn(M, K, dtype=torch.float16, device=device)
B_tensor = torch.randn(N, K, dtype=torch.float16, device=device)
D_tensor = torch.zeros(M, N, dtype=torch.float16, device=device)

f = lib["main"]
f(tvm.runtime.from_dlpack(A_tensor), tvm.runtime.from_dlpack(B_tensor),
  tvm.runtime.from_dlpack(D_tensor))

D_ref = (A_tensor.float() @ B_tensor.float().T).half()
max_err = float((D_tensor - D_ref).abs().max())
print(f"Step 4 TMA Async GEMM: M={M}, N={N}, K={K}")
print(f"Max error vs torch reference: {max_err:.6f}")
assert max_err < 0.5, f"FAIL: max_err={max_err}"  # smoke test; fp16 4096x4096 typically gives ~0.25
print("PASS")

# Benchmark
ITERS = 10
args = [tvm.runtime.from_dlpack(A_tensor), tvm.runtime.from_dlpack(B_tensor), tvm.runtime.from_dlpack(D_tensor)]
for _ in range(3):
    f(*args)
torch.cuda.synchronize()
start = torch.cuda.Event(enable_timing=True)
end = torch.cuda.Event(enable_timing=True)
start.record()
for _ in range(ITERS):
    f(*args)
end.record()
torch.cuda.synchronize()
ms = start.elapsed_time(end) / ITERS
tflops = 2 * M * N * K / ms / 1e9
print(f"Performance: {ms:.3f} ms, {tflops:.1f} TFLOPS")
```

Note: The `max_err < 0.5` check is a **smoke test**, not a strict numerical verification. fp16 GEMM at 4096x4096 accumulates rounding error across 64 K-tiles, so the max absolute error can be much larger than in the 128x128 examples. For stricter validation, compare against the reference elementwise with both relative and absolute tolerances.

**Checks.**

- **TMA config**: `{"dispatch": "tma", "cta_group": 1, "mbar": tma_bar.ptr_to([0])}`

- **Byte count**: `(BLK_M * BLK_K + BLK_N * BLK_K) * 2` bytes (fp16 = 2 bytes per element)

- **mbarrier init**: `init(tma_bar.ptr_to([0]), 1)` — 1 expected arrival from `expect_tx`.

- **`@Tx.inline`**: Helper functions are inlined at compile time and can capture outer variables.

- **TMA store writeback sync**: After TMEM readback, the kernel uses synchronization to keep all threads aligned before staging results through Dsmem. After Dsmem writes, `fence.proxy_async` + `warpgroup_sync` hand the thread-written SMEM data to the TMA store path. The TMA store is then followed by `commit_group()` + `wait_group(0)` before Dsmem is reused.

### Understanding TMEM

TMEM (Tensor Memory) is a **per-SM** scratchpad used by the `tcgen05` MMA path (not per-warpgroup). The TMEM address space used in these kernels is 128 rows by 512 columns, shared by whichever warpgroups of the resident CTA(s) need it. The 128-row extent is tied to the `TLane` axis and matches one warpgroup's 128 threads, which is what makes the `tcgen05.ld` TMEM→RF read a warpgroup-cooperative operation. Two further properties of the allocation call itself:

- **`.shape`** determines how many bits per element. For fp32 accumulators, each cell is 32 bits.
- **`.num`** determines how many `.shape`-sized entries fit. The TIRX compiler maps these to TMEM columns.

When you declare `tmem = Tx.decl_buffer((128, 512), "float32", scope="tmem", allocated_addr=...)`, this creates a buffer view over a TMEM allocation whose base address came from `tcgen05.alloc`. To read TMEM into registers:

```python
Dreg_wg = Dreg.view(128, BLK_N,
    layout=TileLayout(S[(128, BLK_N) : (1@tid_in_wg, 1)]))
with Tx.warpgroup():
    Tx.copy_async(Dreg_wg[:, :], tmem[:, :BLK_N])
    Tx.ptx.tcgen05.wait.ld()
```

The layout `1@tid_in_wg` maps the 128 warpgroup threads to the 128-row TMEM view; axis matching with the TMEM `(1@TLane, 1@TCol)` layout is what lets `Tx.copy_async` lower to a `tcgen05.ld` readback. TMEM reads use warpgroup scope because this dispatcher is written for warpgroup-cooperative TMEM-to-local movement — not because TMEM itself is "owned" by a warpgroup (it is not; TMEM is SM-level). `tcgen05.ld` is **asynchronous** (the load is launched but the destination registers fill later), so the caller must follow `Tx.copy_async` with `Tx.ptx.tcgen05.wait.ld()` before reading the destination.

Note: If the K-loop runs inside an `elect_sync` or `tid == 0` scope, other threads skip ahead to the writeback. Always ensure `cta_sync()` is called **outside** any thread-guarded scope before reading TMEM, so the whole warpgroup is aligned on the same MMA epoch.

---

TMA async loads move data through the hardware copy engine, but the MMA unit still sits idle while waiting for each TMA transfer to complete. Software pipelining overlaps loading and computing.

## Step 5: Software Pipeline (PIPE_DEPTH=2)
:label:`chap_software_pipeline`

Without pipelining, the kernel alternates between loading and computing: MMA sits idle while TMA loads data, and vice versa. Software pipelining overlaps these operations using double-buffered shared memory. Benchmarks use M=N=K=4096.

**Topics.**

- Overlapping TMA loads with MMA computation using double buffering

- Multi-buffered shared memory: `Asmem[stage, :, :]`

- Pipeline stage and phase tracking

- Prefetch pattern: load first stages before entering main loop

### Pipeline Walkthrough

Without pipelining (Step 4), TMA and MMA execute serially — the MMA sits idle during every load, and TMA sits idle during every compute. With double buffering (`PIPE_DEPTH=2`), we allocate two SMEM stages so TMA can load the next tile into one stage while MMA computes from the other:

![*Pipeline PIPE_DEPTH=2*](../img/pipe_depth2.png)

**Implementation.**

Structural changes from Step 4:

```{.python .input}

import tvm
from tvm.script import tirx as Tx
from tvm.tirx.layout import TileLayout, S, TLane, TCol, tid_in_wg
from tvm.tirx.operator.tile_primitive.cuda.tma_utils import tma_shared_layout, SwizzleMode
```

The kernel is wrapped in a function `hgemm_v5(M, N, K)` that returns a TIRX kernel for given dimensions. The `PIPE_DEPTH=2` constant controls the number of pipeline stages (double buffering):

```{.python .input}
PIPE_DEPTH = 2

def hgemm_v5(M, N, K):
    a_type = tvm.DataType("float16")
    b_type = tvm.DataType("float16")
    d_type = tvm.DataType("float16")
    acc_type = tvm.DataType("float32")
    F16_SIZE = 2
    BLK_M, BLK_N, BLK_K = 128, 128, 64
    K_TILES = K // BLK_K

    # Double-buffered layouts: first dimension is pipeline stage
    A_layout = tma_shared_layout(a_type, SwizzleMode.SWIZZLE_128B_ATOM,
                                  (PIPE_DEPTH, BLK_M, BLK_K))
    B_layout = tma_shared_layout(b_type, SwizzleMode.SWIZZLE_128B_ATOM,
                                  (PIPE_DEPTH, BLK_N, BLK_K))
    D_layout = tma_shared_layout(d_type, SwizzleMode.SWIZZLE_128B_ATOM,
                                  (BLK_M, BLK_N))

    @Tx.prim_func
    def kernel(
        A: Tx.Buffer((M, K), a_type),
        B: Tx.Buffer((N, K), b_type),
        D: Tx.Buffer((M, N), d_type),
    ):
        with Tx.kernel():
            bx, by = Tx.cta_id([M // BLK_M, N // BLK_N])
            wg_id = Tx.warpgroup_id([1])
            warp_id = Tx.warp_id_in_wg([4])
            lane_id = Tx.lane_id([32])

            # --- SMEM allocation ---
            pool = Tx.SMEMPool()
            tmem_addr = pool.alloc((1,), "uint32")
            # Double-buffered TMA barriers (one per stage), single MMA barrier
            tma_bar = pool.alloc((PIPE_DEPTH,), "uint64", align=8)
            mma_bar = pool.alloc((1,), "uint64", align=8)
            pool.move_base_to(1024)
            Asmem = pool.alloc((PIPE_DEPTH, BLK_M, BLK_K), a_type, layout=A_layout)
            Bsmem = pool.alloc((PIPE_DEPTH, BLK_N, BLK_K), b_type, layout=B_layout)
            Dsmem = pool.alloc((BLK_M, BLK_N), d_type, layout=D_layout)
            pool.commit()

            # Initialize barriers: PIPE_DEPTH for TMA, 1 for MMA
            if warp_id == 0:
                if lane_id == 0:
                    Tx.ptx.mbarrier.init(mma_bar.ptr_to([0]), 1)
                    for s in range(PIPE_DEPTH):
                        Tx.ptx.mbarrier.init(tma_bar.ptr_to([s]), 1)
            if warp_id == 0:
                Tx.ptx.tcgen05.alloc(Tx.address_of(tmem_addr), n_cols=512, cta_group=1)

            Tx.ptx.fence.proxy_async("shared::cta")
            Tx.ptx.fence.mbarrier_init()
            Tx.cuda.cta_sync()

            tmem = Tx.decl_buffer(
                (128, 512), acc_type, scope="tmem", allocated_addr=tmem_addr[0],
                layout=TileLayout(S[(128, 512) : (1@TLane, 1@TCol)])
            )

            m_st = Tx.meta_var(bx * BLK_M)
            n_st = Tx.meta_var(by * BLK_N)
            phase_tma: Tx.int32 = 0
            phase_mma: Tx.int32 = 0

            @Tx.inline
            def tma_load(stage, k_offset):
                tma_config = Tx.meta_var({
                    "dispatch": "tma", "cta_group": 1,
                    "mbar": tma_bar.ptr_to([stage])
                })
                Tx.copy_async(Asmem[stage, :, :],
                              A[m_st:m_st+BLK_M, k_offset:k_offset+BLK_K],
                              **tma_config)
                Tx.copy_async(Bsmem[stage, :, :],
                              B[n_st:n_st+BLK_N, k_offset:k_offset+BLK_K],
                              **tma_config)
                Tx.ptx.mbarrier.arrive.expect_tx(
                    tma_bar.ptr_to([stage]),
                    (BLK_M * BLK_K + BLK_N * BLK_K) * 2)

            @Tx.inline
            def mma(stage, accum):
                Tx.gemm_async(tmem[:, :BLK_N], Asmem[stage, :, :], Bsmem[stage, :, :],
                              accum=accum, dispatch="tcgen05", cta_group=1)
                Tx.ptx.tcgen05.commit(mma_bar.ptr_to([0]), cta_group=1)

            tid = Tx.meta_var(warp_id * 32 + lane_id)

            # === Prefetch: load first PIPE_DEPTH stages ===
            with Tx.thread(tid == 0):
                for s in range(min(PIPE_DEPTH, K_TILES)):
                    tma_load(s, s * BLK_K)

            # === Main loop ===
            for k in range(K_TILES):
                stage = k % PIPE_DEPTH

                # Wait for TMA to finish loading this stage
                Tx.ptx.mbarrier.try_wait(tma_bar.ptr_to([stage]), phase_tma)

                # MMA on this stage's data
                with Tx.thread(tid == 0):
                    mma(stage, accum=(k != 0))

                Tx.ptx.mbarrier.try_wait(mma_bar.ptr_to([0]), phase_mma)
                phase_mma ^= 1

                # Issue next prefetch load (k + PIPE_DEPTH)
                next_k = k + PIPE_DEPTH
                if next_k < K_TILES:
                    with Tx.thread(tid == 0):
                        tma_load(stage, next_k * BLK_K)

                # TMA phase flips when stage wraps around
                if stage == PIPE_DEPTH - 1:
                    phase_tma ^= 1

            # === TMA Store Writeback: TMEM -> RF -> Dsmem -> TMA -> GMEM ===
            Dreg = Tx.alloc_local((BLK_N,), acc_type)
            Dreg_f16 = Tx.alloc_local((BLK_N,), d_type)
            Dreg_wg = Dreg.view(128, BLK_N,
                                layout=TileLayout(S[(128, BLK_N) : (1@tid_in_wg, 1)]))
            with Tx.warpgroup():
                Tx.copy_async(Dreg_wg[:, :], tmem[:, :BLK_N])
                Tx.ptx.tcgen05.wait.ld()
                Tx.cuda.cta_sync()
            with Tx.thread():
                Tx.cast(Dreg_f16[:], Dreg[:])
            with Tx.thread():
                Tx.copy(Dsmem[warp_id * 32 + lane_id, 0:BLK_N], Dreg_f16[:])
                Tx.ptx.fence.proxy_async("shared::cta")
                Tx.cuda.warpgroup_sync(10)
            with Tx.thread(tid == 0):
                Tx.copy_async(D[m_st : m_st + BLK_M, n_st : n_st + BLK_N],
                              Dsmem[:, :], dispatch="tma")
                Tx.ptx.cp_async.bulk.commit_group()
                Tx.ptx.cp_async.bulk.wait_group(0)
            Tx.cuda.warpgroup_sync(10)

            # Deallocate TMEM
            Tx.cuda.cta_sync()
            if warp_id == 0:
                Tx.ptx.tcgen05.relinquish_alloc_permit(cta_group=1)
                Tx.ptx.tcgen05.dealloc(tmem_addr[0], n_cols=512, cta_group=1)

    return kernel
```

Compile and run:

```{.python .input}
import torch

M, N, K = 4096, 4096, 4096
kernel = hgemm_v5(M, N, K)

target = tvm.target.Target("cuda")
with target:
    mod = tvm.IRModule({"main": kernel})
    lib = tvm.compile(mod, target=target, tir_pipeline="tirx")

device = torch.device('cuda')  # gpu(0)
torch.cuda.empty_cache()
torch.cuda.synchronize()
A_tensor = torch.randn(M, K, dtype=torch.float16, device=device)
B_tensor = torch.randn(N, K, dtype=torch.float16, device=device)
D_tensor = torch.zeros(M, N, dtype=torch.float16, device=device)

f = lib["main"]
f(tvm.runtime.from_dlpack(A_tensor), tvm.runtime.from_dlpack(B_tensor),
  tvm.runtime.from_dlpack(D_tensor))

D_ref = (A_tensor.float() @ B_tensor.float().T).half()
max_err = float((D_tensor - D_ref).abs().max())
print(f"Step 5 Software Pipeline: M={M}, N={N}, K={K}")
print(f"Max error vs torch reference: {max_err:.6f}")
assert max_err < 0.5, f"FAIL: max_err={max_err}"  # smoke test; fp16 4096x4096 typically gives ~0.25
print("PASS")

# Benchmark
ITERS = 10
args = [tvm.runtime.from_dlpack(A_tensor), tvm.runtime.from_dlpack(B_tensor), tvm.runtime.from_dlpack(D_tensor)]
for _ in range(3):
    f(*args)
torch.cuda.synchronize()
start = torch.cuda.Event(enable_timing=True)
end = torch.cuda.Event(enable_timing=True)
start.record()
for _ in range(ITERS):
    f(*args)
end.record()
torch.cuda.synchronize()
ms = start.elapsed_time(end) / ITERS
tflops = 2 * M * N * K / ms / 1e9
print(f"Performance: {ms:.3f} ms, {tflops:.1f} TFLOPS")
```

### Pipeline Mechanics

The pipeline works in three phases:

**1. Prefetch**: Before the main loop, load the first `PIPE_DEPTH` stages:
```python
for s in range(min(PIPE_DEPTH, K_TILES)):
    tma_load(s, s * BLK_K)
```

**2. Main loop**: For each K tile, wait for its data, compute, and issue the next load:
```python
stage = k % PIPE_DEPTH
wait(tma_bar[stage], phase_tma)  # Data ready
mma(stage, accum)                # Compute
wait(mma_bar[0], phase_mma)      # MMA done (single barrier)
phase_mma ^= 1                   # Flip every iteration
tma_load(stage, next_k * BLK_K)  # Start next load (reuses this stage's buffer)
```

**3. Phase management**: The MMA barrier is single-buffered, so `phase_mma` flips every iteration. The TMA barriers are double-buffered, so `phase_tma` flips when the stage wraps:
```python
if stage == PIPE_DEPTH - 1:
    phase_tma ^= 1
```



---

With pipelining, TMA and MMA now overlap within a single tile. But for large matrices, one CTA per output tile still creates many short-lived CTAs and gives the program little control over tile order. Persistent kernels address this by launching a fixed pool of long-running CTAs that each process multiple tiles in a cache-friendly order.

## Step 6: Persistent Kernel + Tile Scheduler
:label:`chap_persistent_kernel`

With one CTA per output tile, large matrices (M=N=4096 -> 1024 CTAs) force the GPU to schedule many short-lived CTAs, and the kernel has little control over which nearby tiles run together. Persistent kernels address both issues. Benchmarks use M=N=K=4096.

**Topics.**

- Persistent kernel pattern: `SM_COUNT` CTAs that each loop over multiple tiles

- `ClusterPersistentScheduler2D` for L2-cache-friendly tile ordering

- Why persistent kernels improve performance for large matrices

### Persistent Scheduling

A persistent kernel launches a fixed pool of CTAs. In the B200 configuration used here that pool is `SM_COUNT=148`, one CTA per SM. Each CTA loops over multiple tiles using a tile scheduler that orders them for L2 cache locality --- processing nearby tiles together so they can reuse cached data.

```python
bx = Tx.cta_id([SM_COUNT])  # 1D grid, one CTA per SM

tile_scheduler = ClusterPersistentScheduler2D(
    "ts",
    num_m_tiles=M // BLK_M,
    num_n_tiles=N // BLK_N,
    l2_group_size=8,       # Group 8 nearby tiles together
    num_clusters=SM_COUNT
)
tile_scheduler.init(bx)
```

**Implementation.**

The structure combines Step 5's pipeline with a tile-level outer loop:

```{.python .input}

import tvm
from tvm.script import tirx as Tx
from tvm.tirx.layout import TileLayout, S, TLane, TCol, tid_in_wg
from tvm.tirx.operator.tile_primitive.cuda.tma_utils import tma_shared_layout, SwizzleMode
from tvm.tirx.lang.tile_scheduler import ClusterPersistentScheduler2D
```

The kernel function now takes `SM_COUNT` as a grid dimension instead of `(M//BLK_M, N//BLK_N)`, and uses a `ClusterPersistentScheduler2D` to assign tiles to CTAs:

```{.python .input}
SM_COUNT = 148  # Number of SMs on NVIDIA B200 GPU
PIPE_DEPTH = 2

def hgemm_v6(M, N, K):
    a_type = tvm.DataType("float16")
    b_type = tvm.DataType("float16")
    d_type = tvm.DataType("float16")
    acc_type = tvm.DataType("float32")
    F16_SIZE = 2
    BLK_M, BLK_N, BLK_K = 128, 128, 64
    K_TILES = K // BLK_K

    A_layout = tma_shared_layout(a_type, SwizzleMode.SWIZZLE_128B_ATOM,
                                  (PIPE_DEPTH, BLK_M, BLK_K))
    B_layout = tma_shared_layout(b_type, SwizzleMode.SWIZZLE_128B_ATOM,
                                  (PIPE_DEPTH, BLK_N, BLK_K))
    D_layout = tma_shared_layout(d_type, SwizzleMode.SWIZZLE_128B_ATOM,
                                  (BLK_M, BLK_N))

    @Tx.prim_func
    def kernel(
        A: Tx.Buffer((M, K), a_type),
        B: Tx.Buffer((N, K), b_type),
        D: Tx.Buffer((M, N), d_type),
    ):
        with Tx.kernel():
            # 1D grid: one CTA per SM (not a 2D grid anymore!)
            bx = Tx.cta_id([SM_COUNT])
            wg_id = Tx.warpgroup_id([1])
            warp_id = Tx.warp_id_in_wg([4])
            lane_id = Tx.lane_id([32])

            # --- SMEM allocation (same as Step 5) ---
            pool = Tx.SMEMPool()
            tmem_addr = pool.alloc((1,), "uint32")
            tma_bar = pool.alloc((PIPE_DEPTH,), "uint64", align=8)
            mma_bar = pool.alloc((1,), "uint64", align=8)
            pool.move_base_to(1024)
            Asmem = pool.alloc((PIPE_DEPTH, BLK_M, BLK_K), a_type, layout=A_layout)
            Bsmem = pool.alloc((PIPE_DEPTH, BLK_N, BLK_K), b_type, layout=B_layout)
            Dsmem = pool.alloc((BLK_M, BLK_N), d_type, layout=D_layout)
            pool.commit()

            # --- Barrier + TMEM init (same as Step 5) ---
            if warp_id == 0 and lane_id == 0:
                Tx.ptx.mbarrier.init(mma_bar.ptr_to([0]), 1)
                for s in range(PIPE_DEPTH):
                    Tx.ptx.mbarrier.init(tma_bar.ptr_to([s]), 1)
            if warp_id == 0:
                Tx.ptx.tcgen05.alloc(Tx.address_of(tmem_addr), n_cols=512, cta_group=1)
            Tx.ptx.fence.proxy_async("shared::cta")
            Tx.ptx.fence.mbarrier_init()
            Tx.cuda.cta_sync()

            tmem = Tx.decl_buffer(
                (128, 512), acc_type, scope="tmem", allocated_addr=tmem_addr[0],
                layout=TileLayout(S[(128, 512) : (1@TLane, 1@TCol)])
            )

            # Tile scheduler: assigns tiles to CTAs in L2-friendly order
            tile_scheduler = ClusterPersistentScheduler2D(
                "ts",
                num_m_tiles=M // BLK_M,
                num_n_tiles=N // BLK_N,
                l2_group_size=8,
                num_clusters=SM_COUNT
            )
            tile_scheduler.init(bx)

            tid = Tx.meta_var(warp_id * 32 + lane_id)

            @Tx.inline
            def tma_load(stage, k_offset, m_st, n_st):
                tma_config = Tx.meta_var({
                    "dispatch": "tma", "cta_group": 1,
                    "mbar": tma_bar.ptr_to([stage])
                })
                Tx.copy_async(Asmem[stage, :, :],
                              A[m_st:m_st+BLK_M, k_offset:k_offset+BLK_K],
                              **tma_config)
                Tx.copy_async(Bsmem[stage, :, :],
                              B[n_st:n_st+BLK_N, k_offset:k_offset+BLK_K],
                              **tma_config)
                Tx.ptx.mbarrier.arrive.expect_tx(
                    tma_bar.ptr_to([stage]),
                    (BLK_M * BLK_K + BLK_N * BLK_K) * 2)

            @Tx.inline
            def mma(stage, accum):
                Tx.gemm_async(tmem[:, :BLK_N], Asmem[stage, :, :], Bsmem[stage, :, :],
                              accum=accum, dispatch="tcgen05", cta_group=1)
                Tx.ptx.tcgen05.commit(mma_bar.ptr_to([0]), cta_group=1)

            # === Outer loop: iterate over tiles ===
            while tile_scheduler.valid():
                # Get current tile position from scheduler
                m_st = Tx.meta_var(tile_scheduler.m_idx * BLK_M)
                n_st = Tx.meta_var(tile_scheduler.n_idx * BLK_N)

                # === Inner loop: same pipeline as Step 5 ===
                phase_tma: Tx.int32 = 0
                phase_mma: Tx.int32 = 0

                # Prefetch first PIPE_DEPTH stages
                with Tx.thread(tid == 0):
                    for s in range(min(PIPE_DEPTH, K_TILES)):
                        tma_load(s, s * BLK_K, m_st, n_st)

                # Main K-loop
                for k in range(K_TILES):
                    stage = k % PIPE_DEPTH
                    Tx.ptx.mbarrier.try_wait(tma_bar.ptr_to([stage]), phase_tma)
                    with Tx.thread(tid == 0):
                        mma(stage, accum=(k != 0))
                    Tx.ptx.mbarrier.try_wait(mma_bar.ptr_to([0]), phase_mma)
                    phase_mma ^= 1
                    next_k = k + PIPE_DEPTH
                    if next_k < K_TILES:
                        with Tx.thread(tid == 0):
                            tma_load(stage, next_k * BLK_K, m_st, n_st)
                    if stage == PIPE_DEPTH - 1:
                        phase_tma ^= 1

                # === TMA Store Writeback: TMEM -> RF -> Dsmem -> TMA -> GMEM ===
                Dreg = Tx.alloc_local((BLK_N,), acc_type)
                Dreg_f16 = Tx.alloc_local((BLK_N,), d_type)
                Dreg_wg = Dreg.view(128, BLK_N,
                                    layout=TileLayout(S[(128, BLK_N) : (1@tid_in_wg, 1)]))
                with Tx.warpgroup():
                    Tx.copy_async(Dreg_wg[:, :], tmem[:, :BLK_N])
                    Tx.ptx.tcgen05.wait.ld()
                    Tx.cuda.cta_sync()
                with Tx.thread():
                    Tx.cast(Dreg_f16[:], Dreg[:])
                with Tx.thread():
                    Tx.copy(Dsmem[warp_id * 32 + lane_id, 0:BLK_N], Dreg_f16[:])
                    Tx.ptx.fence.proxy_async("shared::cta")
                    Tx.cuda.warpgroup_sync(10)
                with Tx.thread(tid == 0):
                    Tx.copy_async(D[m_st : m_st + BLK_M, n_st : n_st + BLK_N],
                                  Dsmem[:, :], dispatch="tma")
                    Tx.ptx.cp_async.bulk.commit_group()
                    Tx.ptx.cp_async.bulk.wait_group(0)
                Tx.cuda.warpgroup_sync(10)

                Tx.cuda.cta_sync()
                tile_scheduler.next_tile()  # Move to next tile

            # Deallocate TMEM
            Tx.cuda.cta_sync()
            if warp_id == 0:
                Tx.ptx.tcgen05.relinquish_alloc_permit(cta_group=1)
                Tx.ptx.tcgen05.dealloc(tmem_addr[0], n_cols=512, cta_group=1)

    return kernel
```

Compile and run:

```{.python .input}
import torch

M, N, K = 4096, 4096, 4096
kernel = hgemm_v6(M, N, K)

target = tvm.target.Target("cuda")
with target:
    mod = tvm.IRModule({"main": kernel})
    lib = tvm.compile(mod, target=target, tir_pipeline="tirx")

device = torch.device('cuda')  # gpu(0)
torch.cuda.empty_cache()
torch.cuda.synchronize()
A_tensor = torch.randn(M, K, dtype=torch.float16, device=device)
B_tensor = torch.randn(N, K, dtype=torch.float16, device=device)
D_tensor = torch.zeros(M, N, dtype=torch.float16, device=device)

f = lib["main"]
f(tvm.runtime.from_dlpack(A_tensor), tvm.runtime.from_dlpack(B_tensor),
  tvm.runtime.from_dlpack(D_tensor))

D_ref = (A_tensor.float() @ B_tensor.float().T).half()
max_err = float((D_tensor - D_ref).abs().max())
print(f"Step 6 Persistent Kernel: M={M}, N={N}, K={K}")
print(f"Max error vs torch reference: {max_err:.6f}")
assert max_err < 0.5, f"FAIL: max_err={max_err}"  # smoke test; fp16 4096x4096 typically gives ~0.25
print("PASS")

# Benchmark
ITERS = 10
args = [tvm.runtime.from_dlpack(A_tensor), tvm.runtime.from_dlpack(B_tensor), tvm.runtime.from_dlpack(D_tensor)]
for _ in range(3):
    f(*args)
torch.cuda.synchronize()
start = torch.cuda.Event(enable_timing=True)
end = torch.cuda.Event(enable_timing=True)
start.record()
for _ in range(ITERS):
    f(*args)
end.record()
torch.cuda.synchronize()
ms = start.elapsed_time(end) / ITERS
tflops = 2 * M * N * K / ms / 1e9
print(f"Performance: {ms:.3f} ms, {tflops:.1f} TFLOPS")
```

### Why Persistent Kernels Help

| Aspect | Grid-based (Step 5) | Persistent (Step 6) |
|--------|---------------------|---------------------|
| CTAs launched | `(M/128) x (N/128)` (e.g., 1024) | `SM_COUNT` (148) |
| Kernel launches | One launch total | One launch total |
| CTA scheduling | One CTA per output tile | Fixed CTA pool; each CTA processes multiple tiles |
| L2 cache | Tile order mostly follows CTA scheduling | Scheduler groups nearby tiles |
| SM residency | Many short-lived CTAs | One long-running CTA per SM in this B200 setup |

The `l2_group_size=8` parameter means the scheduler processes 8 adjacent tiles together before moving on, which improves the chance of reusing A and B tiles from L2.

### Phase Reset Between Tiles

Phase handling changes from Step 5: in a persistent kernel, each CTA processes **multiple tiles** in the `while tile_scheduler.valid()` loop. Reset the barrier phases (`phase_tma`, `phase_mma`) to 0 at the start of each tile. In Step 5, phases are initialized once because each CTA only processes one tile. In Step 6, if the phases are not reset inside the tile loop, the second tile's waits can use the wrong phase and either deadlock or read stale data from the previous tile.

For that reason, the `phase_tma: Tx.int32 = 0` and `phase_mma: Tx.int32 = 0` initialisers appear **inside** the `while` loop, not before it.

## Exercises

1. The byte count for `arrive.expect_tx` is `(BLK_M * BLK_K + BLK_N * BLK_K) * 2`. What happens if you compute this wrong (e.g., forget the `* 2` for fp16)?
2. Why do we need per-stage barriers (`tma_bar[0]` and `tma_bar[1]`) in Step 5 instead of a single shared barrier?
3. For a 4096x4096 matrix with BLK_M=BLK_N=128, how many tiles exist in Step 6? How many iterations does each persistent CTA perform on average?
