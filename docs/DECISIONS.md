---
title: Decisions
kind: log
status: current
updated: 2026-10-30
---

# Decisions

Short records: what was decided, why, and what was rejected. Newest last.

### D1. No runtime dependencies
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

The runtime uses the Python standard library only. Native runtimes (wasmtime, wasm3, WAMR/iwasm)
were considered and rejected for the runtime: wasmtime is tens of MB, WAMR does not fit, and any
native piece breaks platforms like Pythonista. Development tools are free to use (D11).

### D2. Translate, do not interpret
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: BENCHMARKS.md, CoreMark

Measured on CoreMark (CPython): pywasm (interpreter) 0.58 it/s, w2py translation 86, so ×150; on PyPy
×400, because a tracing JIT optimises straight code far better than an interpreter loop (warpy, an
RPython interpreter with a meta-tracing JIT: 192 it/s). Superinstructions were considered and do not
apply: the translation already has no dispatch left.

### D3. Python source as the `pyc` target's intermediate form, compiled by the host
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

The translator emits Python source and lets `compile()` make the bytecode. Hand-written bytecode would
be fragile across Python versions and gains nothing (CPython's compiler does not optimise, but neither
would we). The same source serves CPython, PyPy and MicroPython (with a flavour). Text format (WAT) as
input to the translator was rejected: the binary is stricter and simpler to parse; `.wat` may be
accepted later through a separate parser.

### D4. Speed on CPython comes from a JIT in Python, not from more Python
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: BENCHMARKS.md, CoreMark

The ceiling of translated Python on CPython is ~1.5–2× the PoC (boxed ints, ~30–60 ns per operation,
`struct` memory access ~70–90 ns). A JIT written in Python, emitting machine code into executable
`mmap` memory and entering it through `ctypes` (both stdlib), reached 15 337 it/s (≈ 80 % of
wasmtime). Accepted with its costs: per-architecture work and platforms that forbid JIT, both handled
by D5.

### D5. Targets behind one interface, chosen automatically, falling back per module
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

`pyc` always; `mpy` on MicroPython; `jit-<arch>` where the architecture matches and executable memory
works. Architectures are added one by one; a module using a feature a JIT lacks runs on `pyc`.
*Per-module fallback superseded by D25 (one target per engine/store, parity).*

### D6. Follow Wasmtime: model, API, features, traps
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

Engine/Store/Module/Linker/Instance and wasmtime-py's names; the `wasmtime` binary's CLI (wasmtime-py
50 has none); Wasmtime's feature switches and trap codes. Wasmtime is the specification of behaviour
wherever the wasm spec leaves room.

### D7. Component model: fused modules only
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

No component parser or canonical ABI in w2py. Components are fused with `meld` into one core module;
WASI 0.2 comes from the WASI host (D8). Requires multi-memory. p1 programs may go the same way through the
preview1 adapter.

### D8. WASI host: open
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

Not decided. The candidate is the Python twin of fusedwasi (natify-sh/fusedwasi): one function per
import, memories as buffers, the same code as the C headers used by wasmext. It has not been used with
w2py yet. Whatever is chosen, w2py only binds names and memories (`Linker.define_wasi`), and the
choice must not set the minimum Python of the package (3.11, D19).

2026-10-30 (maintainer): fusedwasi 0.1.0a1 is runtime-independent and already works with wasmtime,
wasm3 and wasmext, so it is expected to fit w2py as well; the choice is confirmed in the WASI phase by
running it on w2py.

### D9. Cache compiled artifacts
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

Keyed by the module hash, w2py version, target and target environment, and code-affecting config. The
same format is `Module.serialize`. Measured: `pyc` cold 111 ms → 0.5 ms cached. Serialized files and
fat files (embedding the wasm): D18.

### D10. Never crash the interpreter on deep recursion
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

Stack depth is bounded per store with a deterministic `STACK_OVERFLOW` trap; `sys.setrecursionlimit` is
not changed globally; `RecursionError` is a safety net only (ARCHITECTURE.md).

### D11. wasmtime is a development dependency: the test oracle
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

Differential tests run every target against a pinned wasmtime; wabt, wasm-tools, pywasm, meld,
MicroPython and QEMU are development tools too. None of them is a runtime dependency.

### D12. Dropped and parked
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

* **mypyc target** — dropped: needs `librt` at run time (a dependency) and a native build is better
  served by wasm2c/wasmext.
* **Lua / LuaJIT backends** — parked as an experiment proving the IR is language-neutral (LuaJIT
  1 873 it/s); not part of w2py. Superseded by D20 (rejected).
* **`--trust-align` memoryview access** — rejected: no gain on CPython, ×20 slower on PyPy.
* **Function inlining in `pyc`** — opt-in only: neutral on CPython 3.13, ~+5 % on PyPy.
* **pywasm as the base** — rejected as a base (interpreter, ×150–400 slower, needs Python ≥ 3.11 — `match`, `typing.Self` — no
  MicroPython); used as a second oracle and a reference.

### D13. MicroPython where possible
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

A separate `mpy` target, best effort, ahead-of-time `.mpy` first; `@native` measured faster than
CPython; viper is the research direction.

### D14. Long calls: JIT releases the GIL and polls for interrupts; `pyc` needs yield points
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

Measured: a ctypes `CFUNCTYPE` entry releases the GIL (another thread ran throughout a 19.6 s guest
call) but a SIGINT cannot stop machine code (the call ran to its end). So JIT code polls an
interrupt/epoch word; `pyc` holds the GIL by nature and gets yield points (and, if parallelism is
needed, subinterpreters / free-threaded builds / a process). One thread per store at a time
(ARCHITECTURE.md, "Long calls and the GIL").

### D15. The JIT artifact is a language-neutral, versioned contract
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

Compiled code depends on nothing Python-specific (byte-identical output under CPython 3.8 and 3.13), so
its boundary is fixed and versioned in ARTIFACT.md: (1) **ISA levels** — portable artifacts use the
architecture's baseline (x86-64-v1, ARMv8.0-A) with baseline sequences for higher-level instructions;
`native` only for local caches; the loader checks the CPU; (2) **artifact format v1** — self-contained,
with entry trampolines for every calling convention of the architecture, function/trap tables,
segments; (3) **context ABI v1** — entry signature, context words, host-function signature, trap
codes. Hosts in other languages (C, Dart, LuaJIT, …) may load artifacts; a C reference loader keeps the
contract honest. *Narrowed by D18*: the contract is first of all the format of cache entries and
serialized files read by the w2py runtime; other-language loaders and the C loader are optional.

### D16. Our own thin IR; wasm is the portable IR; no LLVM
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

Wasm already is a typed, validated, producer-optimised IR, so no LLVM-class optimiser is needed (a
baseline JIT reached ~80 % of Cranelift). A thin IR of our own carries what wasm lacks: **HIR** (trees,
structured control flow, analyses) shared by all targets, and **LIR** (machine-neutral linear
operations) shared by all JIT architectures. Structured rather than a CFG (Python has no `goto`); no SSA
(little gain on optimised wasm, and it would have to be deconstructed for Python). Optimisations only
when measured to pay; bounds-check elimination first. LLVM, Cranelift IR and Binaryen IR were rejected
as runtime dependencies (LLVM stays a candidate build-time tool for copy-and-patch stencils).

### D17. The shared layers stay language-neutral; other languages are not in scope
Status: accepted · Date: 2026-10-26 · Supersedes: — · Evidence: —

HIR, LIR and the JIT artifact keep nothing Python-specific: the target's integer model is a parameter of
the analyses, backends hold everything language-specific, artifacts are loadable from any FFI-capable
language. Evidence that it works: the PoC's Lua 5.4 / LuaJIT backends reuse the front end. Only
Python-family targets (`pyc`, `mpy`, JITs loaded from Python) are in scope; the principle is cheap
insurance, not a commitment.

### D18. No embedded runtime: the Wasmtime model, not the wasmext model
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: —

w2py generates code when a module is loaded, so what it generates is a derivative owned by the engine,
as in Wasmtime — not a product that lives without the tool, as wasm2c + a C build is in wasmext (there
the output must carry its runtime). Consequences:

* **The runtime lives only in the package**: `Store`, memories, tables, globals, traps, WASI, the JIT
  entry and context. Generated code (a `pyc` code object, a JIT artifact) holds code and metadata and
  uses the runtime of its own w2py version. The PoC's `RUNTIME` string emitted into every module is a
  PoC shortcut, not the design.
* **Portable form: a serialized file** (`Module.serialize`, `w2py compile`), like Wasmtime's `.cwasm`;
  it runs only on a w2py runtime. Named `<name>.<target>.<ext>`, the target including what decides
  whether it can run there (`core.jit-x86_64-v1.w2a`, `core.pyc-cp313.w2a`; `.w2a` is a working
  extension until the project has a name). The header, not the file name, is authoritative.
* **Fat files**: optionally the file embeds the original wasm (ARTIFACT.md, section `WASM`). A fat file
  is never refused: on any mismatch — w2py or target version, bytecode magic, ISA level, a known-bad
  compiler version — the runtime regenerates from the embedded wasm (and may cache the result), so the
  file always runs, only slower the first time. A thin file is refused on a mismatch, as in Wasmtime.
* **Version skew (RISKS.md, R4) reduces to one rule**: accept an exact match, otherwise regenerate from
  the wasm (cache: the wasm is at hand; fat file: embedded) or refuse (thin file). No compatibility
  windows and no versioned helper namespaces; the interface between generated code and the runtime is
  internal and may change between any two versions.
* ARTIFACT.md stays the format of cache entries and serialized files; loaders in other languages and
  the C reference loader become optional (D15 narrowed).
* Possible exception, later and optional: a standalone export with minimal embedded helpers for
  MicroPython devices, where the runtime package costs flash.

### D19. Minimum Python 3.11; tested 3.11–3.15, 3.15t and PyPy 3.11
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: —

`requires-python = ">=3.11"`. CI runs CPython 3.11, 3.12, 3.13, 3.14, 3.15, the free-threaded 3.15t,
and PyPy 3.11; actions are pinned by commit SHA. Tooling (ruff, pyright) targets 3.11.

* **Why**: current versions only. The free-threaded build matters for "one thread per store" and long
  calls (ARCHITECTURE.md). wasmtime 50 needs ≥ 3.9 and `wabt-package` ≥ 3.11 anyway, so a lower floor
  would need skip markers for the oracle.
* **Rejected: a 3.8 floor.** It worked in the PoC (the 3.8 measurements stay as history), but EOL
  versions cost CI time and block newer syntax and typing.
* Generated `pyc` code's floor follows the package floor unless a target says otherwise; the
  MicroPython flavour is separate.

### D20. Lua / LuaJIT rejected as a target
Status: accepted · Date: 2026-10-30 · Supersedes: D12 (the Lua item) · Evidence: BENCHMARKS.md, CoreMark

Lua 5.4 and LuaJIT are not w2py targets, now or later. The experiment gave little for its cost
(Lua 5.4 271 it/s, LuaJIT 1 873 it/s, against ~15 000 for the x86-64 JIT and no use from Python);
it stays in `poc/` (`w2lua.py`, `w2luajit.py`, `run_lua.py`) as a record and as evidence for D17.
D17 (language-neutral shared layers) is unchanged.

### D21. No WAT parser of our own; WAT through wasm-tools, optionally
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: —

w2py reads the binary format only and will not contain a text-format (WAT) parser: a full WAT grammar
(folded expressions, every proposal, GC type syntax, annotations) is a project of its own and adds
nothing to the compiler or the targets. Who needs WAT uses `wasm-tools parse`. In phase 6 the public
API may accept WAT when the optional extra `wasm-tools-package` is installed, calling it
automatically; without it, text input gets a clear error (a deliberate deviation from wasmtime-py,
which accepts WAT everywhere). The package keeps no runtime dependency (D1): the extra is optional.
Tests write modules in WAT and build them with `wasm-tools` at development time. The 662 spec
commands that test only WAT parsing (text `assert_malformed`, S0001) stay `skip` permanently: with
the extra they would test wasm-tools, not w2py. This settles D3's "`.wat` may be accepted later".
Known consequences: wasmtime-py's own tests (the API axis in TESTING.md) write modules in WAT, so
that CI job installs the extra; the CLI's `run file.wat` and `wast` need it too; text errors come
from wasm-tools. Where no native wasm-tools wheel runs, a later option is to run `wasm-tools.wasm`
(wasm-tools built for WASI) on w2py itself once WASI works: native wasm-tools if installed, else the
wasm build on our own engine (maintainer: a good idea; phase 6 or later).

### D22. Platform tiers: iOS/Pythonista and MicroPython are tier 3
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: —

The primary platforms are CPython and PyPy on the operating systems of the CI matrix (TESTING.md).
iOS/Pythonista and MicroPython are **tier 3**: best effort, never a reason to constrain the design
or to block a step. On iOS/Pythonista wasm runs through the separate PyPI package `wasmhost`
(JavaScriptCore's `WebAssembly` via JSContext), not through w2py. The `mpy` target (ROADMAP phase 7)
keeps its place in the order of work at tier 3. D1 is unchanged: no runtime dependencies stays a rule
for every platform.

### D23. A JIT target is an architecture, not an OS
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: —

There is one JIT target per architecture and ISA baseline (`jit-x86_64`, `jit-aarch64`,
`jit-riscv64`, …), not one per operating system: the same artifact runs on Linux, macOS, the BSDs and
Windows. The code is position-independent and reaches everything through the context register
(ARTIFACT.md); the OS differences stay at the edges:
* calling convention: one entry trampoline per host convention inside the artifact (`sysv`/`win64`,
  `aapcs64`/`win-arm64`); host calls from wasm go through the same per-convention bridge;
* executable memory (`mmap`, `VirtualAlloc`, `MAP_JIT` + W^X switching) and the guard-page fault
  handler (signals vs vectored exceptions) belong to the loader/runtime, not to the code; explicit
  bounds checks behave the same everywhere;
* the code generator avoids what any supported OS reserves, so one artifact suits all of them: e.g.
  `x18` on AArch64 (Darwin, Windows), and frames that would need stack probes on Windows (machine
  frames stay small; values live on the host-allocated value stack). The context-ABI spec lists
  these rules per architecture.
Rejected: `jit-x86_64-sysv` / `jit-x86_64-win64` as separate targets (TARGETS.md before this): two
code generators or two artifacts for one CPU, with no gain.
Everything platform-specific is resolved by the runtime; the code depends on the architecture (and
its declared ISA level) only. Letting the OS into the code — e.g. using a register that only some
OSes leave free — is discussed only when a measurement shows a substantial gain on real workloads,
and then as an opt-in variant declared in the artifact, the way ISA levels are (ARTIFACT.md): a
generic variant that runs everywhere on the architecture and a flagged one that runs only where its
condition holds (as MicroPython's native `.mpy` has a generic RISC-V target and RISC-V with platform
feature flags).

### D24. Baseline ISA first; anything above it is an optional, declared variant
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: —

JIT code generators target the architecture's minimal baseline (ARTIFACT.md: x86-64-v1, ARMv8.0-A,
and each new architecture's declared baseline), so one compiled artifact runs on every CPU of the
architecture — portability comes almost for free. Extensions (SSE4.1, AVX, BMI, LZCNT, LSE, …) are
added later, operation by operation, only where a measurement shows a substantial gain, and always as
an optional variant behind a level declared in the artifact, next to a baseline path that stays
mandatory. What the PoC already uses above the baseline is kept as such an optional variant rather
than lost (`roundsd` for `f64.trunc`). CI disassembles generated code and fails on any instruction
above the declared level. With D23 (no OS in the code) this keeps an artifact dependent on the
architecture and its declared level only.

### D25. One target per engine and store; `pyc` and the JIT at feature parity
Status: accepted · Date: 2026-10-30 (amended 2026-10-30: no computation helpers) · Supersedes: D5 (per-module fallback) · Evidence: —

Targets are never mixed: the target is chosen per engine, so every module and store of an engine runs
on it (the Wasmtime model: an engine owns the compiler). `auto` chooses from the environment only —
`jit-<arch>` where the architecture is supported and executable memory works, otherwise `pyc` — never
from a module's content. No per-module fallback: memories, tables and globals then never cross two
representations, and one call graph has one trap model. Inside `pyc`, the memory's backing store
follows the environment: an `mmap` buffer where `mmap` is available, a `bytearray` where it is not,
with identical semantics; which one is the default is decided by a measurement (grow without copying,
access speed through `struct`/`memoryview`).
For this to cost nothing, **`pyc` and every `jit-<arch>` support the same features, 1:1**: a feature
is complete when it passes on both. The goal is a complete implementation, not passing tests: a JIT
computes natively (floats and conversions included, at the ISA baseline, D24) and calls into the
Python runtime only for runtime **services** that change engine state (`memory.grow`, `table.grow`,
table/segment initialisation — what Wasmtime's own libcalls do); it never hands a computation it has
not implemented to a Python helper. What it cannot compile yet is `Unsupported`, visible as
`unsupported: <feature>` in its expected failures, and `auto` selects a JIT only when its expected
failures equal `pyc`'s in the claimed groups. `pyc` closes its own gaps (e.g. NaN payloads) rather
than relying on the JIT. CI compares the expected-failures files of `pyc` and each JIT; a difference
is a gap on one side to close, not a permanent state. Tier-3 targets (`mpy`, D22) are exempt.

### D26. The JIT core is one pass; LIR is the backend's call interface
Status: accepted · Date: 2026-10-30 · Supersedes: D16 (LIR as a materialised list) · Evidence: S0002, "Proposed decision" (measured)

The shared JIT core reads each validated function body once — lazy value stack, control stack,
pinned locals, labels — and drives a small per-architecture backend interface (Winch / Liftoff
style, as `poc/w2jit2.py`). The LIR of D16 is that interface, not a list with virtual registers: an
extra LIR build + liveness + linear scan costs at least +50–80 % compile time in Python (measured on
core.wasm, webp_codec.wasm, resvg.wasm; `poc/bench/compile/lir_proto.py`), while what it could buy
is bounded: `w2jit2` is at 80–86 % of Cranelift on CoreMark and guard pages bring ~91 % — the gap is
mostly bounds checks, addressed by guard pages and bounds-check elimination, and wasm arrives already
optimised by its producer. The interface is three-operand, has no flags (compare-and-branch /
compare-and-set are whole operations), and lets each backend own its register roles, so a second
architecture does not inherit x86-isms. An allocator over a materialised LIR is added only if a
measurement on real workloads shows a substantial gain.

### D27. `pyc` caps a table at 10 000 000 elements (deviation from Wasmtime)
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: wasmtime-py 50.0.1 grew a funcref table by 10 000 001 and then to 120 000 001 elements without failing

`table.grow` on `pyc` returns −1 when the new size would exceed 10 000 000 elements (or the table's
max, or 2³²−1). A `pyc` table is a Python list (8 bytes per slot plus the objects), so an unbounded
grow can exhaust the interpreter's memory instead of failing the instruction; Wasmtime has no such
default cap (measured). The cap becomes a store limit (`StoreLimits.table_elements`) in phase 6; the
JIT targets will use the same number until then so `pyc` and JIT behave alike (D25).

### D28. `pyc` keeps floats as Python floats; f32 NaN payloads ride in the double's high bits
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: spec run on pyc +83 (NaN/conversion causes), CoreMark unchanged

f32 and f64 stay Python floats in `pyc` (no f32-as-integer representation: it would make f32
arithmetic 3–5× slower). An f32 NaN is held as the double NaN with the same sign and its 23-bit
payload shifted left by 29, the quiet bit as is; conversions between f32 bits and floats use integer
bit arithmetic on the NaN path only (`struct` `'<f'` quiets signalling NaNs). NaNs are quieted only
where Wasmtime quiets them: arithmetic, promote/demote (`x*1.0`), floor/ceil/trunc/nearest; moves,
loads/stores, reinterpret, select, neg/abs/copysign keep bits exactly. f32 arithmetic is computed in
double and re-rounded to f32 once per operation (proved exact for add/sub/mul/div/sqrt); i64→f32 is
rounded once (sticky bit). A JIT libcall for an f32 operation reuses the same helpers (D25 parity).

### D29. JIT bounds checks: guard pages by default where the handler is verified; explicit checks as the fallback
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: BENCHMARKS.md "Guard pages in the JIT" (PoC: explicit ~78 %, guard pages ~91 % of wasmtime on CoreMark)

The bounds-check mode is a compile-time property of JIT code, recorded in the artifact and the cache
key (`guard` or `explicit`). As in Wasmtime (`signals_based_traps = true` by default), the default is
`guard` wherever the platform has a verified fault handler; `explicit` is the fallback and the only
mode of a new architecture, of platforms without a handler table entry yet, and of `memory64`.
Guard code never runs without its handler: before the first entry the runtime checks that our
handler is installed and still ours (a cheap `sigaction` query; Windows: the vectored handler) and
otherwise compiles the module `explicit` (never crash the interpreter). Layout as Wasmtime: 4 GiB
reservation per 32-bit memory plus a 32 MiB guard; static offsets beyond the guard keep an explicit
check. `Config.signals_based_traps = False` selects `explicit` (API.md). Implemented in phase 5 (risks:
RISKS.md R6); phase 3 is `explicit` only and must not close this path (trap stubs reachable from a
fault handler, `SAVED_SP` kept, the mode field in the artifact).

### D30. Cross-instance tail calls go through a shared `tail_switch` trampoline (context word 9)
Status: accepted (maintainer, 2026-10-30) · Date: 2026-10-30 · Supersedes: — · Evidence: `tests/jit/test_tail.py` (1e5 A↔B hops on a 256 KiB thread; with the restore frame per hop the same test ends in `STACK_OVERFLOW`)

Tail calls between wasm functions compiled by the JIT never grow either stack, as in Wasmtime.
Deviation (temporary): a `return_call` to a function import is a call plus a return through the host
bridge, so tail recursion through an imported wasm function grows the stack (A `return_call`s an
imported `pong` that `return_call_indirect`s back: Wasmtime runs 10⁶ rounds, both w2py targets trap
`STACK_OVERFLOW` at 10³). It is closed by calling an imported function of another JIT instance of the
same store directly through its function record. A `return_call*`  moves its arguments to its frame
base, drops its native frame and jumps. When the callee's function record has another context, r15
must change, but a direct `call` site in the original caller relies on r15/r13/r14 being its own
afterwards. The jump therefore goes through `tail_switch`, one trampoline per process whose address is
in context word 9 `TAIL_SWITCH`. The first switch of a chain pushes the caller's r15 and makes a real
`call` whose return point (`restore`) pops it and reloads r13/r14. A later switch whose return
address is already `restore` only changes the context and jumps, so A → B → A → … runs in constant
stack. Every `ret` returns to its own `call` (CET shadow stacks, R2). This is an amendment of context
ABI v1 without a version bump: S0003 fixes v1 in phase 5, and word 9 was reserved and zero.
Rejected: (A) a restore frame (push r15, call, pop, ret) emitted at each cross-instance tail call, with
no ABI change. It costs 16 bytes of native stack per hop that does not return, so mutual tail recursion
across instances ends in `STACK_OVERFLOW` after ~32k hops (512 KiB budget). Also rejected: making r15
caller-saved at every call (Cranelift's `tail` convention), which costs a save/restore at every direct
call on the hot path.

### D31. The JIT fallback warns once (`JitUnavailableWarning`)
Status: accepted · Date: 2026-10-30 · Supersedes: — · Evidence: tests/test_fallback.py (MDWE), CI `spec` job

When `auto` finds a `jit-*` target for this machine's architecture whose probe fails (executable memory
forbidden, ...), it selects `pyc` (D25) and says so once per process per target and reason:
`warnings.warn("w2py: jit-x86_64 unavailable (<reason>); using pyc", JitUnavailableWarning)`, a
`RuntimeWarning` defined in `targets/base.py` (phase 6 re-exports it). No message on an architecture
without a JIT target, or when the target was chosen explicitly; an explicit `jit-*` that cannot run is
an `Unsupported` error. Rejected: `print` to stderr (cannot be filtered or turned into an error, noisy in
libraries); `logging` (silent by default, so the one case where speed silently drops would go unseen).
