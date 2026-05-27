# 1. Introduction

**PTO** is a virtual instruction set designed for the Ascend NPU — a hardware-abstracted programming model that exposes the full capability of the Cube, Vector, and Scalar compute units through a unified operation set. **PTODSL** is the Python frontend for PTO. It wraps the PTO instruction set in a Python-embedded DSL with tracing-based compilation, so you can write PTO programs using familiar Python syntax. Under the hood, PTODSL traces your kernel function into PTO IR, which the PTOAS compiler then lowers, optimizes, and emits as NPU executables. In short: PTO defines the *what* (the instruction set), PTODSL provides the *how* (the authoring experience), and together they give you direct access to all three NPU compute units without leaving Python.

## 1.1 Target hardware

The Ascend NPU is organized around three compute units and a shared on-chip buffer, connected through the Memory Transfer Engine (MTE):

```
                          ┌─────────────────────────┐
                          │     Global Memory (GM)    │
                          │       (off-chip HBM)      │
                          └────────────┬──────────────┘
                                       │
                            ┌──────────┴──────────┐
                            │    MTE (DMA engine)  │
                            └──────────┬──────────┘
                                       │
                          ┌────────────┴──────────────┐
                          │   Unified Buffer (UB)      │
                          │     (on-chip scratchpad)   │
                          └──┬───────────┬──────────┬──┘
                             │           │          │
                    ┌────────┴──┐  ┌─────┴──────┐  │
                    │ LEFT/RIGHT│  │            │  │
                    │  /ACC/BIAS│  │  Vector    │  │
                    │           │  │  (SIMD)    │  │
                    │   Cube    │  │            │  │
                    │           │  └────────────┘  │
                    └───────────┘                  │
                                        ┌──────────┴──┐
                                        │   SIMT      │
                                        │ (scalar PG)  │
                                        └─────────────┘
```

| Unit | Role | Typical workload |
|------|------|------------------|
| **Cube** | Matrix multiplication | GEMM, convolution |
| **SIMD** | Row-wise vector math | activation, normalization, reduction |
| **SIMT** | Scalar-programmable unit | pointwise tile walks, metadata |

- **Global Memory (GM)** is off-chip HBM. All input and output tensors reside here.
- **Unified Buffer (UB)** is the on-chip scratchpad shared by all three compute units. Tile buffers and intermediate results live here during kernel execution.
- **MTE** (Memory Transfer Engine) handles DMA transfers between GM and UB, and between UB regions.
- **Cube** has its own private on-chip buffers — LEFT, RIGHT, ACC, and BIAS — for staging matrix operands and accumulators.
- **SIMD** executes row-wise vector instructions directly on UB-resident data.
- **SIMT** is a scalar-programmable processor group that executes scalar instructions across many work-items in parallel. It is well-suited for per-element control logic, tile boundary metadata, and pointwise blends.

PTODSL gives you direct access to all three units and the data-movement
surfaces around them, without abstracting away the hardware boundaries.

## 1.2 Authoring model

PTODSL's public kernel model is **one entry point, two modes**:

```
Python Wrapper              L0  user-facing wrapper (NumPy, torch-npu, pure Python)
  └─ @pto.jit(mode="auto")         tile-first authoring, compiler-managed staging
  └─ @pto.jit(mode="explicit")     micro-instruction authoring, user-managed staging
       ├─ Tile Ops                 tile.load, tile.store, tile.add, ...
       ├─ MTE Ops                  mte_load / mte_store / mte_gm_ub / ...
       ├─ @pto.cube                matrix products (mad, mte_l1_l0a, mte_l0c_ub, ...)
       ├─ @pto.simd                row-wise vector math (vlds, vadd, vexp, vsts, ...)
       └─ @pto.simt                scalar-like compute (lds, sts, pointwise blends, ...)
```

### Python wrapper

The outermost layer is plain Python. It handles ergonomic runtime concerns: allocating output tensors, extracting shapes and strides from framework tensors, compiling the JIT kernel, and launching it. Because the wrapper is just Python, you can freely mix in NumPy, torch-npu, or any other Python framework for pre- and post-processing, data preparation, or composing multiple kernel launches. It knows nothing about NPU internals — it is just a convenience function that most end users will call.

<!-- ptodsl-doc-test: {"mode":"launch_fragment","fixture":"launch.flash_attention_wrapper","symbol":"flash_attention"} -->
```python
def flash_attention(Q, K, V, *, O=None, causal=False):
    if O is None:
        O = pto.empty_like(Q)
    batch, seq_q, heads, dim = Q.shape
    _, seq_k, _, _ = K.shape
    compiled = flash_attention_kernel.compile(
        BLOCK_Q=128, BLOCK_KV=128, CAUSAL=causal
    )
    compiled[batch * heads, stream](
        Q.data_ptr(),
        K.data_ptr(),
        V.data_ptr(),
        O.data_ptr(),
        batch,
        seq_q,
        seq_k,
        heads,
        dim,
    )
    return O
```

### `@pto.jit` — the kernel entry

Decorating a function with `@pto.jit` marks it as a launchable PTO kernel. This decoration means:

- **Compilation**: the function body is traced once to record all PTO instructions, then lowered through the PTOAS compiler pipeline into an optimized NPU executable.
- **Caching**: compiled kernels are cached by specialization key (function identity + entry annotation signature + constexpr parameter values), so repeated calls with the same configuration skip recompilation.
- **Launch binding**: the compiled kernel can be invoked with a grid and stream — `compiled[grid, stream](args...)` — which launches the executable on the NPU with the given SPMD grid.

The public `@pto.jit` entry contract is pointer-first. Device buffers are explicit GM pointers (`pto.ptr(..., "gm")`), launch-varying shape/stride metadata travels as runtime scalars, and the kernel body materializes `TensorView` descriptors with `make_tensor_view(ptr, shape=..., strides=...)`. Compile-time constants remain keyword-only `pto.constexpr` parameters:

<!-- ptodsl-doc-test: {"mode":"compile","symbol":"flash_attention_kernel","compile":{"BLOCK_Q":128,"BLOCK_KV":128,"CAUSAL":false}} -->
```python
from ptodsl import pto


@pto.jit(target="a5")
def flash_attention_kernel(
    Q_ptr: pto.ptr(pto.f32, "gm"),
    K_ptr: pto.ptr(pto.f32, "gm"),
    V_ptr: pto.ptr(pto.f32, "gm"),
    O_ptr: pto.ptr(pto.f32, "gm"),
    batch: pto.i32,
    seq_q: pto.i32,
    seq_k: pto.i32,
    heads: pto.i32,
    dim: pto.i32,
    *,
    BLOCK_Q: pto.constexpr = 128,
    BLOCK_KV: pto.constexpr = 128,
    CAUSAL: pto.constexpr = False,
):
    q_view = pto.make_tensor_view(
        Q_ptr,
        shape=[batch, seq_q, heads, dim],
        strides=[seq_q * heads * dim, heads * dim, dim, 1],
    )
    # ... tile allocation, block partitioning, and sub-kernel dispatch ...
    return
```

`@pto.jit` is the only host-visible kernel entry. Its `mode` selects the
programming model:

- `mode="auto"` (the default) is **tile-centric**. You allocate tiles, partition
  GM views, use Tile Ops (`tile.load`, `tile.store`, `tile.add`, ...), and call
  compute sub-kernels. The compiler manages staging and scheduling around the
  tile abstraction.
- `mode="explicit"` is **tile + micro-instruction**. You keep the same tile
  surface from `auto`, but also gain access to the full micro-instruction
  set — MTE ops (`mte_load`, `mte_store`, ...), explicit synchronization,
  and direct pointer manipulation — so you can reach below the tile abstraction
  and control individual instructions when needed.

In both modes, `@pto.jit` is where you allocate tiles (`alloc_tile`) and use
Tile Ops. The difference is that `explicit` additionally opens up the
micro-instruction surface — MTE ops, explicit sync, and pointer-level
control — so you can mix tile operations with hand-authored instructions in
the same kernel.

The SPMD launch contract is also owned here: the runtime grid (e.g., `batch * heads` blocks) is declared at the call site, and block/subblock indices are queried via `pto.get_block_idx()` and friends.

### Sub-kernels — `@pto.cube` / `@pto.simd` / `@pto.simt`

These are hardware-bound compute sub-kernels, each mapped to a specific NPU compute unit:

- **`@pto.cube`** consumes UB tiles and explicit cube-local scratch (LEFT, RIGHT, ACC, BIAS). Typical operations: `mad`, `mte_l1_l0a`, `mte_l1_l0b`, `mte_l0c_ub`.

- **`@pto.simd`** operates on vector registers (`vreg`). Typical operations: `vlds`, `vadd`, `vexp`, `vcgmax`, `vsts`. Vector registers never cross the simd function boundary — persistent state is written back to UB tiles.

- **`@pto.simt`** is a scalar-programmable processor group that executes scalar instructions across many work-items in parallel. Typical operations: `lds`, `sts`, scalar arithmetic and comparison. Well-suited for per-element tile walks, boundary metadata, and pointwise blends.

Each can be invoked as a named decorated function (`@pto.cube` /
`@pto.simd` / `@pto.simt`) or inline as a context manager
(`with pto.cube():`, `with pto.simd():`, `with pto.simt():`).

The boundary contract is strict: vreg values do not escape a simd kernel, cube-local state does not leak into UB, and data crosses layer boundaries only through UB-backed tiles or typed UB pointers.

## 1.3 Tracing execution model

PTODSL uses a **tracing** compilation model. When you call `kernel.compile(...)`, PTODSL executes your Python function body once to record every PTO instruction into an intermediate representation — this pass is called *tracing*. The traced IR is then lowered and optimized into device code. Once compiled, invoking `compiled[grid, stream](args...)` launches the already-built device code directly on the NPU.

This has one critical implication for how you write control flow and scalar logic:

- **Python native control flow** (`for`, `if`, Python arithmetic) runs at trace time. A `for i in range(4)` loop gets unrolled — the device code contains four copies of the body, not a loop instruction. An `if` branch condition is evaluated at trace time, and only the taken branch is recorded.

- **`pto.for_` / `pto.if_`** are recorded as structured control-flow IR. They preserve loop and branch semantics into the compiler pipeline, where the PTOAS compiler may further optimize them — unrolling, folding, or keeping them as runtime control flow depending on what is known at compile time.

- **Python scalar expressions** (`alpha * x`, `1.0 / sqrt(d)`) are evaluated at trace time and their results are baked into the IR as constants — the compiler never sees the original expression.

- **PTO scalar instructions** (`scalar.load(...)`, `scalar.max(...)`, `scalar.exp(...)`) are recorded as scalar IR and enter the compiler pipeline, where they may be constant-folded or lowered to runtime scalar operations depending on whether their inputs are compile-time known.

A simple rule of thumb: **Python constructs are resolved before the compiler sees them. PTO constructs are recorded into IR and the compiler decides.**

Chapter 5 (Control Flow) and Chapter 6 (Scalar & Pointer Operations) cover this in detail.

## 1.4 A worked example

The flash attention kernel from Section 1.2 is not just an architectural diagram — it is a complete, runnable design sketch distributed with PTODSL (`examples/flash_attention_sketch.py`). Here is how the layers map to actual code:

**Top-level `@pto.jit` schedule** allocates tiles for the Q block, KV block,
online-softmax state (m/l/o ping-pong tiles), and cube-local scratch. It loops
over Q blocks (outer `pto.for_`) and KV blocks (inner `pto.for_` with carry
state), and uses `tile.load`/`tile.store` at the GM boundary.

**`mode="explicit"` orchestration path** stages the current K and V blocks with
`mte_load`, issues `pipe_barrier(Pipe.ALL)` at phase boundaries, then
sequences four sub-kernel calls: `qk_matmul` (cube),
`online_softmax_rows` (simd), `pv_matmul` (cube), `blend_output_rows` (simt).

**`@pto.cube`** performs `mte_l1_l0a` / `mte_l1_l0b` / `mad` /
`mte_l0c_ub` for both QK^T and P@V products.

**`@pto.simd`** implements the online softmax update: per-row max, exp, sum,
and alpha/beta computation using vector ops (`vlds`, `vcgmax`, `vexp`,
`vcgadd`, `vsts`).

**`@pto.simt`** blends the old and new output accumulators with per-element
`lds`/`sts` and scalar arithmetic.

Chapter 11 walks through this example in full detail.

## 1.5 Reading guide

| If you are... | Start with... |
|---------------|---------------|
| New to PTODSL | Chapter 2 (Quick Start), then Chapter 3 (Kernel Entries) |

| Writing your first kernel | Chapter 2 → Chapter 4 (Type System) → Chapter 5 (Control Flow) |
| Looking up a specific operation | Chapters 6–10 (organized by topic) |
| Understanding the flash attention reference | Chapter 11 |

**Chapter overview:**

| Chapter | Topic |
|---------|-------|
| 1 | Introduction (this chapter) |
| 2 | Quick Start — a minimal working kernel |
| 3 | Kernel entry and sub-kernels: `@pto.jit(mode=...)`, `@pto.cube`, `@pto.simd`, `@pto.simt` |
| 4 | Type system and buffer management: scalars, tiles, views, allocation |
| 5 | Control flow: trace-time Python vs device-side `pto.for_` / `pto.if_` |
| 6 | Scalar and pointer operations |
| 7 | Data movement: tile loads/stores, DMA, vector loads/stores, cube data movement |
| 8 | Compute operations: tile-level, vector, and cube arithmetic |
| 9 | Predicate and mask operations |
| 10 | Synchronization: barriers, flags, memory fences |
| 11 | Flash attention walkthrough |
| 12 | Additional examples |
| 13 | Migration from the old `@pto.vkernel`/`@pto.ckernel` API |
| 14 | Common errors and compatibility notes |
