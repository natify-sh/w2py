---
title: Benchmarks
kind: log
status: current
updated: 2026-10-30
---

# Benchmarks

Everything measured during the PoC, with its conditions. Numbers from different sessions differ by up
to ~20 % (shared cloud machine); compare within a session.

**Machine**: cloud container, x86-64 Linux, Intel Xeon @ 2.10 GHz, 2 vCPU.
**Software**: CPython 3.13.17 (also 3.8.20, 3.9.25, 3.10.20 from uv), PyPy 7.3.19 (3.10), MicroPython
1.29.0 unix port (standard build), wasmtime-py 50.0.1, pywasm3 0.5.0, pywasm 2.2.3, lupa 2.8 (Lua 5.4,
5.5, LuaJIT 2.1), mypy/mypyc 2.4.0, warpy (kanaka, 2019) translated with RPython from PyPy `main` under
CPython 2.7.18.

**Workload**: CoreMark 1.0, `poc/in/core.wasm` (zig cc wasm32 -O3, 19 KB); it/s as CoreMark prints it.
Every run listed passed CoreMark's own self-check (crclist 0xe714, crcmatrix 0x1fd7, crcstate 0x8e3a;
crcfinal depends on the iteration count).

## CoreMark

| engine | it/s | notes |
|---|---|---|
| wasmtime (Cranelift) | 16 589 / **19 044** | first / last session |
| **w2jit2: stdlib JIT with registers, CPython 3.13 / 3.8** | 15 088, **15 337 / 15 437** | last session; ~80 % of wasmtime, 6.3× wasm3 |
| **package `jit-x86_64`** (step 3c: one-pass core, explicit bounds checks, stack checks, interrupt polls, trap-by-return) | 16 299 / 16 315 / 15 100 | 2026-10-30, alternated with `w2jit2` in one session: 16 949 / 16 023 / 16 411 (medians 16 299 vs 16 411, −0.7 %, within noise); details below |
| package `jit-x86_64` (step 3d: + tables, references, `call_indirect`, bulk memory) | 16 571 / 15 385 / 15 879 | 2026-10-30, alternated with `w2jit2` in one session: 16 058 / 15 819 / 16 569 (medians 15 879 vs 16 058, −1.1 %, within noise); details below |
| w2jit: stdlib JIT, every value in memory | 3 874–3 898 (3.13), 3 882 (3.8) | |
| w2py → PyPy 7.3.19 | 2 873; 2 300–2 900 later | noisy |
| wasm3 (pywasm3) | 1 850–2 035 / **2 433** | first / last session |
| w2luajit → LuaJIT 2.1 | 1 873 | was 67 with `goto`-based loops |
| w2py --mypyc → native extension | 1 734–1 814 | needs `librt` at run time (dropped) |
| w2lua → Lua 5.4 / 5.5 | 271 / 246 | was 244 with `goto`-based loops |
| warpy (RPython, meta-tracing JIT) | 186–193 | MVP-only; patched for 4 post-MVP ops |
| w2py → CPython 3.13 | 78 → 86 → ~100 | first PoC → codegen optimisations → last run |
| w2py → CPython 3.8 / 3.9 / 3.10 | 86.6 / 81.9 / 82.6 | `--legacy` (no `:=`) on 3.8: 89 |
| w2py → MicroPython 1.29 | .py 66 · .mpy 69 · `@native` 94 | native .mpy needs the big printf function left as bytecode |
| w2py `--trust-align` (memoryview casts) | CPython 74 · PyPy 137 | rejected |
| pywasm 2.2.3 | CPython 0.58 · PyPy 6.1 | PyPy run < 10 s (formally invalid for CoreMark) |

### Package JIT, first CoreMark checkpoint (JIT step 3c)

Conditions: 2026-10-30, the same cloud machine type but 4 vCPU, CPython 3.13.17, CoreMark self-check
passed in every run (crcfinal 0x4983). Runner: `python3 tools/run_coremark_jit.py poc/in/core.wasm` (the package API; host
`millis`/`print` through the host bridge), alternated round by round with `python3 poc/run_jit2.py poc/in/core.wasm`.

| round | package `jit-x86_64` | `w2jit2` (PoC) | package, no `test eax; jnz` after wasm calls |
|---|---|---|---|
| 1 | 16 299 | 16 949 | 16 853 |
| 2 | 16 315 | 16 023 | 15 307 |
| 3 | 15 100 | 16 411 | 15 640 |
| median | **16 299** | 16 411 | 15 640 |

* Trap-by-return (S0003: `test eax, eax; jnz unwind` after every wasm → wasm call) has no measurable
  cost: the build without it (a local patch, not kept) is not faster; the run-to-run noise is ~±5 %.
* Compile: 61–67 ms, 45 396 bytes of code (`w2jit2`: 28–29 ms, 39 357 bytes). The package adds
  stack-limit checks and an interrupt poll per function, the value-stack frame and the reload of the
  memory registers after host calls.

### Package JIT, second CoreMark checkpoint (JIT step 3d)

Conditions: 2026-10-30, 4 vCPU cloud machine, CPython 3.13.17, CoreMark self-check passed in every
run (crcfinal 0x4983 / 0xcc42 by iteration count). Same commands as the first checkpoint, alternated
round by round: `python3 tools/run_coremark_jit.py poc/in/core.wasm`, then
`python3 poc/run_jit2.py poc/in/core.wasm`.

| round | package `jit-x86_64` | `w2jit2` (PoC) |
|---|---|---|
| 1 | 16 571 | 16 058 |
| 2 | 15 385 | 15 819 |
| 3 | 15 879 | 16 569 |
| median | **15 879** | 16 058 |

* CoreMark has no table, `call_indirect` or bulk-memory instruction, so this checks that step 3d
  costs nothing elsewhere: the code is byte-for-byte the size of step 3c's (45 396 bytes, data area
  from 44 872); compile 60–64 ms. The −1.1 % is within the run-to-run noise (~±5 %).

### Package JIT: function imports through their records (JIT step 3f, D32)

Conditions: 2026-10-30, Intel Xeon @ 2.10 GHz, 4 vCPU cloud machine, CPython 3.13.17. HEAD
(3c2c853's `src/`, exported to a scratch directory and put first on `PYTHONPATH`) and the change,
alternated round by round in one session.

* **1e6 calls of an import from a wasm loop** (a scratch script: `(call $f (local.get 0))` in a
  `loop`, best of 5 runs per round, ns per iteration). A host function (`lambda a: [a[0] & 1]`):
  HEAD 1545 1469 1466 1449 1497 1628 1553 1472 1597, new 1602 1570 1617 1589 1490 1635 1475 1758
  1444: minima 1449 / 1444, medians 1497 / 1589 (the first three rounds) and 1525 / 1540 (the
  last six); no difference beyond the noise of the ctypes callback. The same loop calling a
  function of another JIT instance: HEAD 4757–5057 (through the host bridge and a nested entry),
  new **3** (a direct call with a context switch).
* **CoreMark** (`tools/run_coremark_jit.py poc/in/core.wasm`, self-check passed in every run,
  crcfinal 0x4983): HEAD 14 872 · 14 769 · 14 837, new 15 069 · 16 067 · 14 704 it/s (medians
  14 837 / 15 069: noise). Code 45 396 → 45 579 bytes (a thunk per import, longer import call
  sites).

## Compile and load times (CoreMark)

| step | time |
|---|---|
| `pyc`: parse 0.2 ms · codegen 53 ms · `compile()` 58 ms · exec 0.4 ms | cold ≈ 111 ms (19 KB wasm → 146 KB / 3 871 lines of Python) |
| `pyc` from a cached code object (`marshal.loads` + exec) | 0.5 ms (123 KB) |
| `mpy`: import of source / of `.mpy` | 59 ms / 2 ms (`.mpy` 37 KB bytecode; native `.mpy` 285–312 KB) |
| JIT `w2jit` / `w2jit2` | ~28–31 ms (3.13), ~50 ms (3.8); 71 KB / 39 KB of x86-64 |

## Micro-benchmarks behind the decisions

**Memory access in CPython 3.13** (`poc/bench/mem_access_cpython.py`, ns per op): `M[a]` 35 ·
`Struct.unpack_from` 86 · `memoryview.cast('I')[i]` 69 · `int.from_bytes(slice)` 209 · 4 bytes
composed 253 · `Struct.pack_into` 84 · memoryview store 77 · `(a+v) & 0xFFFFFFFF` 67 · `a+v` 34.

**Masking**: `l = l + 2` 31 ns · `l = (l + 2) & 0xFFFFFFFF` 64 ns · compare-and-adjust forms 45–51 ns
(this is why "single wrap" normalisation replaced masks: 675 → 158 masks in CoreMark, +15 %).

**mypyc** (ns per op): `Struct.unpack_from` 68 · bytearray composed 159 · `librt` `BytesWriter`
load 11.5 / store 13.5 · `i64` arithmetic 1.8.

**CPython vs MicroPython** (`poc/bench/ops_cpython_vs_micropython.py`, ns per iteration):

| operation | CPython 3.13 | MP bytecode | MP `@native` |
|---|---|---|---|
| arithmetic, values < 256 | 32–36 | 44 | 26 |
| arithmetic, i32-sized values | 56–62 | 46 | 25 |
| `unpack_from` load | 123–131 | 262 | 149 |
| `pack_into` store | 129–143 | 128 | 105 |
| function call | 35–53 | 99 | 57 |
| empty loop | 14 | 24 | 13 |

MicroPython keeps small ints inside the pointer (63 bits on 64-bit unix), CPython allocates every
result above 256: that is why MicroPython wins on arithmetic.

**MicroPython 32-bit load** (`poc/bench/micropython_viper_load.py`): `unpack_from` (native) 158 ns ·
bytes composed (native) 140 ns · **viper `ptr32` 3.4 ns**.

**Machine code from Python** (`poc/bench/jit_loop_feasibility.py`, one loop iteration = i32 add +
i32 load): CPython 3.13 222 ns → mmap+ctypes code 0.66 ns (×338); CPython 3.8 176 → 1.04 ns; PyPy 5.6
→ 0.89 ns.

**Crossing into machine code** (`poc/bench/ctypes_call_cost.py`, ns per call): plain Python call 47 ·
`CFUNCTYPE` 327 · `PYFUNCTYPE` 303 (CPython 3.13); 64 / 277 / 206 (3.8). PyPy's ctypes ≈ 13 µs per
call (use its built-in cffi there).

**Long calls and the GIL** (`w2jit2`, CoreMark `setup`, CPython 3.13): during a 19.6 s guest call another
Python thread ran 17 175 iterations of a `sleep(0.001)` loop (~876/s): the GIL is released. A SIGINT
sent ~3 s into the call did not stop it; the call returned normally after 20.6 s.

**pywasm spec suite**: 54 006 commands, 0 failures, 40 s on CPython 3.13 (assert_invalid /
assert_malformed — 3 956 of them — are not checked by its runner).

## `br_table` (a dense `switch`)

`poc/bench/switch/`: a bytecode VM in C (`vm.c`, a 32-case `switch` that clang lowers to one
`br_table` of 31 entries, 32 targets), built with `clang --target=wasm32 -O2`; `run_switch.py`
runs it on each mode. Millions of VM operations per second; all modes return the same checksum.
CPython 3.13, PyPy 7.3.19, same Xeon 2.1 GHz cloud machine, one session.

| mode | linear chain (before) | after | change |
|---|---|---|---|
| wasmtime (Cranelift) | 433 | — | reference |
| `w2jit2` | 105–132 | **392–406** (jump table) | ×3.5, 92–94 % of wasmtime (was ~25 %) |
| `pyc`, CPython 3.13 | 0.9–1.1 (0.69–0.82 s) | 1.0–1.1 (0.70–0.77 s) (balanced if-tree) | ~+10 %, within noise |
| `pyc`, PyPy 7.3 | 41–44 | 43–47 (balanced if-tree) | ~+5 %, within noise |

CoreMark is unchanged (its tables are small and not hot): `w2jit2` 16 403 / 16 649 it/s without,
16 779 / 16 435 with jump tables; `pyc` still passes CoreMark's self-check.

* **JIT**: `cmp ecx,n; jae default; lea rax,[rip+T]; movsxd rdx,[rax+rcx*4]; add rax,rdx; jmp rax`, a
  table of int32 offsets relative to itself (position-independent) followed by one stub per target.
  Used from 4 non-default entries (`W2PY_JT`, 0 = off). The indirect `jmp` needs `endbr64` at the
  stubs once CET IBT is enforced (RISKS.md, R2).
* **pyc**: dispatch is no longer the cost. Python has no goto, so a `switch` compiled to nested blocks
  leaves through the `_br` flag: after the dispatch every one of the 32 block levels runs two tests
  (`if _br == d` and `if not _br`), ~64 per operation against 5 for the tree. The fix is structural:
  recognise the switch idiom (a `br_table` to the immediately enclosing blocks whose case segments end
  in an unconditional branch) and emit each case body at the leaf of the tree, with no flags; or, more
  cheaply, number labels so that one test `if _br <= d` replaces the two. Not done. (`W2PY_BT`: tree
  above this many runs, 0 = off.)

## meld on the PoC (a real 1.7 MB Rust program)

meld 0.66.0 (pulseengine, Apache-2.0), `meld-core` built for `wasm32-unknown-unknown` with
`opt-level="z"`, LTO, behind a ~40-line wrapper (no imports). Task: fuse the `wasm32-wasip2` build of
meld itself (a 2.9 MB component) into a core module. Same Xeon 2.1 GHz cloud machine, one session.

| run | translate | load + `compile()` | fuse | output |
|---|---|---|---|---|
| wasmtime-py (Cranelift) | — | — | 1.05 s | 2 834 770 bytes, the reference |
| meld p1 CLI under wasmtime (WASI) | — | — | 1.09 s | 2 841 680 bytes (attestation with a wall-clock timestamp) |
| w2py `pyc`, PyPy 7.3.19 | 8.7 s (CPython) | 8.2 s | **44 s** | byte-identical to the reference |
| w2py `pyc`, CPython 3.13 | 8.7 s | 6.1 s | **253 s** | byte-identical to the reference |

The module: 4 336 functions, 1 267 `call_indirect`, `memory.copy` ×940, `memory.fill` ×16, no SIMD,
no multi-value, no `trunc_sat`; translated to 13.6 MB of Python source. The PoC JIT cannot run it yet
(no bulk memory, `memory.grow`, full i64). The fused result has one memory and 38 `wasi:*@0.2.9`
imports. Wrapper and how to reproduce: `poc/bench/meld/`.

## Compile time on large modules

`poc/bench/compile/jit_compile_time.py`: code generation only. The PoC JIT does not cover every opcode
yet (missing: `call_indirect`, i64 arithmetic and conversions, bulk memory, …); functions it cannot
compile are replaced by a trap stub and counted, and the full time is **projected** from the covered
functions by body bytes — an estimate, weakest for QuickJS (10 % covered). Modules from
natify-sh/py-wasmext (`dev` branch) and meld (above). CPython 3.13 and PyPy 7.3.19, Xeon 2.1 GHz,
2 cores, one session. wasmtime-py's Cranelift compiles functions in parallel on both cores.

| module | wasm | JIT covered | **w2py JIT**, CPython (projected) | w2py JIT, PyPy (projected) | wasmtime Cranelift | `pyc`: translate + `compile()` |
|---|---|---|---|---|---|---|
| CoreMark | 19 KB | 100 % | 0.03 s (measured) | — | — | — |
| Lua 5.4 | 321 KB | 54 % | 0.37–0.44 s | 1.54 s | 0.25 s | 0.40 + 1.60 s |
| QuickJS | 1.1 MB | 10 % | 1.4–1.6 s | 2.75 s | 0.58 s | 1.47 + 4.22 s |
| wat2wasm (wabt) | 1.26 MB | 32 % | 0.74–0.78 s | 1.14 s | 0.49 s | 0.80 + 0.97 s |
| wasm2c (wabt) | 1.25 MB | 27 % | 0.66 s | — | — | — |
| meld-core | 1.7 MB | 31 % | 2.07 s | 1.66 s | 0.96 s | 1.98 + 6.49 s |
| CPython 3.13 (WASI, brettcannon/cpython-wasi-build v3.13.0) | 28 MB file, 4.1 MB code, 9 752 functions | 72 % | 5.06 s | — | 3.11 s | 6.6 s, then **fails**: 742 nested blocks > CPython's 100 indentation levels (LESSONS.md 22) |

* The single-pass JIT in Python generates code at **~600–840 KB of wasm per second** — about 1.5–2.5×
  the wall time of Cranelift on two cores. A megabyte-sized module costs ~1–2 s on first load; from the
  cache it is a file read and an `mmap`.
* The JIT rate holds on the largest module (CPython: ~800 KB of code bodies per second, 6.7 MB of
  x86-64 for the covered 72 %).
* PyPy does not help the compiler (warm-up dominates; only the largest module gains).
* `pyc` is dominated by CPython's own `compile()` of the generated source (up to 6.5 s): caching the
  marshalled code object matters more for `pyc` than for the JIT.
* Not yet measured: the full JIT (more opcodes, bounds-check elimination) may be slower per byte;
  **lazy compilation** (a function compiled on its first call, as V8 does with Liftoff) would make the
  first-load cost proportional to the code actually used — ROADMAP.md, open question 13.

## WAMR (iwasm) next to w2py

`poc/bench/wamr/` (a minimal C host over `libiwasm`). WAMR 2.4.3 runtime for AOT (an `.aot` made by
`wamrc` 2.4.3 is refused by a runtime built from WAMR `main`: "unknown binary version"); fast
interpreter and Fast JIT from WAMR `main` (f8ed1f4). Same Xeon 2.1 GHz cloud machine, one session;
CoreMark passes its self-check in every row.

| engine | CoreMark it/s | switch VM, M ops/s | what it needs at run time |
|---|---|---|---|
| **iwasm AOT** (`wamrc` = LLVM, ahead of time) | **26 016 – 26 349** | **595 – 617** | `libiwasm` 134–244 KB AOT-only (x86-64, stripped) + an `.aot` per module × target × WAMR version |
| wasmtime (Cranelift) | 21 104 | 419 | a 29.7 MB library |
| **w2py JIT (`w2jit2`)** | **16 896** | **406** | the Python standard library |
| iwasm Fast JIT (x86-64 only) | 15 550 | 368 | `libiwasm` with Fast JIT |
| iwasm fast interpreter | 2 410 | 43 | `libiwasm` |

WAMR runtime sizes (x86-64 Linux, `MinSizeRel`, stripped; the CLI shows what a linked program keeps,
the `.so` is the whole archive): AOT only 134 KB CLI / 244 KB `.so`; + WASI 223 / 364 KB; + fast
interpreter 307 / 461 KB; + SIMD 356 / 506 KB.

* LLVM ahead of time beats Cranelift by ~25 % on CoreMark and ~45 % on the switch VM.
* The PoC JIT is ahead of WAMR's Fast JIT — the same class of compiler, written in C — on both.
* WAMR's fast interpreter runs at wasm3's speed (2 433 it/s, earlier table).

## Guard pages in the JIT (`poc/w2jit_guard.py`)

Same session, CoreMark it/s, alternating runs:

| engine | runs | vs wasmtime |
|---|---|---|
| wasmtime, guard pages (default) | 20 246 / 20 247 / 20 787 / 21 218 | 100 % |
| wasmtime, `signals_based_traps=False` (explicit checks) | 16 372 / 17 922 | 81–89 % |
| **w2py JIT, guard pages** (JIT-emitted SIGSEGV handler) | 18 349 / 19 989 / 19 221 / 18 923 / 19 279 | **~91 %** |
| w2py JIT, explicit checks | 15 252 / 15 581 / 15 981 / 16 084 / 16 636 | ~78 % |

Machine code 39 357 → 30 403 bytes. The switch VM (not memory-bound) does not change (397 vs 397–447
M ops/s, wasmtime 432–485). With explicit checks on both sides the PoC JIT and Cranelift are level:
the gap was the bounds checks, not the code.

## `wasm-opt -O3` (binaryen 125) on CoreMark

`wasm-opt --enable-nontrapping-float-to-int --enable-sign-ext --enable-mutable-globals -O3`: 29 → 10
functions (inlining), 8 527 → 8 097 instructions, 19.5 → 18.0 KB. Pairs in one session (it/s):

| engine | baseline | `-O3` | change |
|---|---|---|---|
| iwasm AOT | 24 472 | 23 405 | −4 % |
| wasmtime | 20 710 | 20 950 | +1 % |
| w2py JIT v2 | 16 780 | 16 477 | −2 % (`-Oz` +4 %, `-O4` −7 %) |
| iwasm Fast JIT | 13 540 | 13 213 | −2 % |
| w2py `pyc`, PyPy | 3 140 | 3 094–3 116 | −1 % |
| w2luajit, LuaJIT | 2 645 | 2 678 | +1 % |
| wasm3 | 2 479 | 2 306 | −7 % |
| iwasm fast interpreter | 2 256 | 2 066 | −8 % |
| w2lua, Lua 5.4 | 366 | 428 | +17 % |
| w2py `pyc`, CPython | 139 | 132 | −5 % |
| w2py, MicroPython | 82 | 83 | +1 % |

## Precompiled Lua

w2lua output loaded as source or as `string.dump` bytecode (stripped) inside lupa: load 2.4–2.9 ms →
0.1–0.2 ms (Lua 5.4, 130 → 76 KB), 1.8–2.6 → 0.0–0.1 ms (LuaJIT, 109 → 48 KB); CoreMark unchanged
(Lua 5.4 416–456, LuaJIT 2 547–2 754 it/s).

## `pyc` in the package vs the PoC (phase 0 port)

* Date: 2026-10-30 · commit: the "port PoC front end and pyc" step on `phase0-skeleton` · machine:
  Intel Xeon @ 2.10 GHz, 4 cores (`nproc`) · CPython 3.13.17.
* Commands: `uv run python tools/run_coremark_pyc.py poc/in/core.wasm` vs
  `cd poc && python3 w2py.py in/core.wasm out/core.py && python3 run_pyc.py out/core.pyc`.
* Result (CoreMark it/s, self-check passed, runs alternated): package 90.3, 96.1, 96.0, 98.5, 95.9,
  97.1, 99.7; PoC 99.6, 100.3, 91.0, 96.4, 95.4, 94.3, 101.7. Medians ≈ 97 / 96: same within noise
  (±5 it/s on this machine).
* Conditions: helpers imported from `w2py.targets.pyc.runtime` (D18) instead of pasted into the
  generated module; no measurable cost.

## `pyc`: checked `call_indirect` (table bounds, null, signature)

* Date: 2026-10-30 · machine: Intel Xeon @ 2.10 GHz, 4 cores · CPython 3.13.17 · command:
  `tools/run_coremark_pyc.py poc/in/core.wasm`, HEAD (unchecked) vs the change, from a worktree, alternated.
* Result (it/s): implementer 89.8 / 85.4, 92.9 / 90.4; orchestrator 90.4 / 95.7, 82.9 / 90.8,
  83.7 / 90.6 (HEAD / new). The two series disagree in sign; the run order (HEAD first) and a
  ±5 % noise dominate. Conclusion: no cost measurable on this machine; the check is required by the
  spec (BAD_SIGNATURE, INDIRECT_CALL_TO_NULL, TABLE_OUT_OF_BOUNDS) regardless.
