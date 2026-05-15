# ptodsl — PTO Python IR Builders

A lightweight, pip-installable DSL package for building PTO MLIR IR modules
in Python.  The API is inspired by Triton / CuteDSL: kernels are ordinary
Python functions decorated with `@pto.to_ir`, type annotations carry PTO
types as lazy descriptors, and control-flow maps 1-to-1 to MLIR operations.

---

## Directory layout

```
ptodsl/
├── ptodsl/              # pip-installable package
│   ├── __init__.py      # exports: pto, scalar
│   ├── pto.py           # main pto.* namespace
│   ├── scalar.py        # pto.scalar.* arith helpers
│   ├── _bootstrap.py    # MLIR path setup + context factory
│   ├── _types.py        # lazy dtype descriptors and type constructors
│   ├── _ops.py          # PTO operation wrappers
│   ├── _control_flow.py # vecscope, for_, if_, yield_ context managers
│   └── _module.py       # @pto.to_ir decorator + module builders
├── examples/
│   ├── tadd_lowlevel.py    # TADD – raw MLIR Python binding calls
│   ├── tadd_dsl.py         # TADD – @pto.to_ir DSL style
│   ├── softmax_lowlevel.py # Softmax – raw MLIR Python binding calls
│   └── softmax_dsl.py      # Softmax – @pto.to_ir DSL style
├── pyproject.toml       # pip install -e .
├── check_ir.py          # IR correctness test runner
└── README.md
```

---

## Prerequisites

```bash
# Install ptoas (first time only)
cd $PTOAS_REPO_ROOT          # e.g. export PTOAS_REPO_ROOT=/workdir/ptoas_a5
bash quick_install.sh

# Set up environment in every new shell
source set_ptoas_env.sh
```

---

## Install the package

```bash
cd $PTOAS_REPO_ROOT/ptodsl
pip install -e .
```

---

## Running the IR check

```bash
# From $PTOAS_REPO_ROOT/ptodsl/
python3 check_ir.py

# From the repository root ($PTOAS_REPO_ROOT)
python3 ptodsl/check_ir.py
```

Expected output:

```
ptodsl IR check
==================================================
  PASS  TADD  low-level
  PASS  TADD  dsl-style
  PASS  softmax low-level
  PASS  softmax dsl-style
==================================================
Result: ALL PASS
```

Exit code is `0` on full pass, `1` on any failure.  A unified diff of up to
60 diverging lines is printed for each failing case.

---

## DSL-style API quick reference

```python
from ptodsl import pto
s = pto.scalar   # arith shorthand alias
```

### Kernel decorator

```python
@pto.to_ir(name="MyKernel", kernel_kind="vector", arch="a5")
def MyKernel():
    ...

@pto.to_ir(name="Softmax", kernel_kind="vector", arch="a5", func_attr="pto.aicore")
def Softmax(arg0: pto.ptr(pto.float32, "gm"), n: pto.int32):
    ...

print(MyKernel)          # prints MLIR text
mod = MyKernel.build()   # returns mlir.ir.Module
```

`func_attr="pto.aicore"` selects a flat single-module structure with the
`pto.aicore` function attribute (softmax style).  Without it, a nested
double-module is emitted (TADD style).

### Type descriptors (lazy – safe to use in annotations)

| Expression | MLIR type |
|---|---|
| `pto.float32` | `f32` |
| `pto.int32` | `i32` |
| `pto.int64` | `i64` |
| `pto.index` | `index` |
| `pto.ptr(pto.float32, "gm")` | `!pto.ptr<f32, gm>` |
| `pto.ptr(pto.float32, "ub")` | `!pto.ptr<f32, ub>` |

### Type constructors (eager – require active context)

```python
vf32     = pto.vreg_type(64, pto.float32)   # !pto.vreg<64xf32>
tile_col = pto.tile_buf_type([8,1], pto.float32, [-1,1], blayout="ColMajor")
tile_w   = pto.tile_buf_type([8,128], pto.float32, [-1,-1])
```

### Constants

```python
c0     = pto.const(0)               # index
c1_i32 = pto.const(1, dtype=pto.int32)
c64_i64= pto.const(64, dtype=pto.int64)
```

### Control flow

```python
with pto.vecscope():                # pto.vecscope { … }
    ...

with pto.for_(c0, c16, step=c1) as i:     # simple scf.for
    ...                                    # scf.yield inserted automatically

with pto.if_(has_rows):            # simple scf.if, no results
    ...                             # scf.yield inserted automatically
```

**Loops with loop-carried state** and **conditionals that produce values** use
a functional style inspired by [`jax.lax.fori_loop`](https://docs.jax.dev/en/latest/_autosummary/jax.lax.fori_loop.html)
and `jax.lax.cond`.  This avoids the `loop.iv` / `loop.iter_args` / `pto.yield_()` / `loop.results`
boilerplate that would otherwise be needed for `scf.for` with `iter_args`, and
the nested `with br.then_:` / `with br.else_:` / `br.results` ceremony for
`scf.if` with results:

```python
# pto.fori_loop  →  scf.for with iter_args
# Signature mirrors jax.lax.fori_loop(lower, upper, body_fun, init_val).
# body_fun(iv, *state) → new_state; scf.yield emitted automatically.
# `step` is keyword-only (JAX always steps by 1; MLIR requires an explicit step value).
final_max, final_sum = pto.fori_loop(
    c0, c128,
    chunk_step,                      # def chunk_step(chunk, rmax, rsum) -> (new_max, new_sum)
    (oldmax_bc, oldsum_bc),          # init_val
    step=c64,
)

# pto.cond  →  scf.if with results + else
# then_() and else_() are zero-arg callables; scf.yield emitted automatically.
next_max, next_sum = pto.cond(
    has_chunk,
    then_=compute_chunk,             # def that emits ops and returns values
    else_=lambda: (rmax, rsum),      # trivial pass-through of current state
)
```

`pto.cond` infers result types by calling `else_` once before creating the
``scf.if`` op — safe when `else_` is a trivial lambda that returns existing
SSA values (the common pattern).  For a non-trivial `else_`, pass explicit
types via `pto.cond(cond, then_=…, else_=…, types=(t1, t2))`.

### Scalar arithmetic (`s = pto.scalar`)

```python
s.muli(a, b)                 # arith.muli
s.addi(a, b)                 # arith.addi
s.subi(a, b)                 # arith.subi
s.index_cast(val)            # arith.index_cast → index
s.index_cast(pto.int32, val) # arith.index_cast → i32
s.cmpi_sgt(a, b)             # arith.cmpi sgt
s.cmpi("slt", a, b)          # arith.cmpi with named predicate
s.select(cond, t, f)         # arith.select
```

### PTO operations

```python
pto.castptr(addr, ptr_type)              # pto.castptr
pto.addptr(ptr, offset)                  # pto.addptr
pto.vlds(ptr, offset, vreg_type)         # pto.vlds
pto.vbrc_load(ptr, offset, vreg_type)    # pto.vlds {dist="BRC_B32"}
pto.vsts(v, ptr, offset, mask)           # pto.vsts
pto.vsts_1pt(v, ptr, offset, mask)       # pto.vsts {dist="1PT_B32"}
pto.plt_b32(scalar)                      # → (mask, scalar_out)
pto.pset_b32("PAT_ALL")                  # pto.pset_b32 → mask
pto.vadd(a, b, mask)   # infers result type from a.type
pto.vmul / vmax / vdiv / vcmax / vcadd / vdup / vexpdif  # similarly
pto.make_tensor_view(ptr, shape=…, strides=…)    # type inferred
pto.partition_view(tv, offsets=…, sizes=…)        # type inferred
pto.alloc_tile(tile_type, addr=…, valid_row=…, valid_col=…)
pto.tload(part, tile)
pto.tstore(tile, part)
pto.tile_ptr(tile, ptr_type)
pto.get_block_idx()           # → i64
pto.set_flag("MTE2", "V", event_id=0)
pto.wait_flag("MTE2", "V", event_id=0)
pto.barrier_all()
```

---

## How the IR check works

```
generated IR  ──┐
                ├── Module.parse() → canonical string ──── == ──── PASS/FAIL
reference .pto ──┘  (strips comments, normalises SSA names and attr order)
```

Constant declaration order is preserved after the round-trip; builders must
emit constants in the same order as the reference.  The diff output makes any
mismatch immediately visible.
