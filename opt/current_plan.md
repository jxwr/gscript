# Optimization Plan: Float Parameter Guards + GuardType CSE

> Created: 2026-04-07 03:15
> Status: active
> Cycle ID: 2026-04-07-float-param-guard
> Category: tier2_float_loop
> Initiative: opt/initiatives/tier2-float-loops.md (Phase 12: Parameter Type Specialization)

## Target

| Benchmark | Current (JIT) | LuaJIT | Gap | Target |
|-----------|--------------|--------|-----|--------|
| nbody | 0.261s | 0.034s | 7.7x | 0.245s (−6%) |
| matmul | 0.120s | 0.022s | 5.5x | 0.115s (−4%) |
| spectral_norm | 0.046s | 0.007s | 6.6x | 0.044s (−4%) |
| All tier2 benchmarks | — | — | — | broad −2-6% |

## Root Cause

**1. Float parameters typed as `:any` (primary — nbody)**

TypeSpecialize Phase 0 (`insertParamGuards`) detects int-like parameters (used
with ConstInt) and inserts GuardType(TypeInt). It does NOT detect float-like
parameters. In nbody's `advance(dt)`, the `dt` parameter has type `:any`
throughout the entire function. This blocks 7 arithmetic operations:

- Inner j-loop: `Div(dt, dsq*distance)` → generic Div (5M iterations)
- Position update: `Mul(dt, b.vx)` × 3 + `Add(b.x, result)` × 3 → 6 generic ops (2.5M iterations)

The Div result IS inferred as TypeFloat (GScript Lua semantics: division always
returns float), so the cascade from Div doesn't propagate. But the 6 position
update ops are fully generic because Mul(any, float) → TypeUnknown.

**Data**: Production diagnostic (TestDiag_NbodyProduction) confirmed:
- 33 typed arithmetic ops (from feedback-typed GetField → GuardType → TypeSpecialize)
- 7 generic arithmetic ops (all involving `v0 = LoadSlot slot[0]`, the `dt` parameter)

**2. Redundant GuardType instructions (secondary)**

The graph builder inserts OpGuardType after each GetField/GetTable when feedback
is monomorphic. LoadElimination CSEs redundant GetField calls (same obj+field),
but the multiple GuardType instructions on the CSE'd result are NOT eliminated.

In nbody's j-loop: bj.mass (v48) is guarded 3 times for TypeFloat. Two guards
are redundant (~6 insns × 5M iterations = 30M wasted instructions).

**3. OpSqrt and OpGetTable not LICM-hoistable (tertiary)**

`canHoistOp` in pass_licm.go does not include OpSqrt or OpGetTable. While
neither impacts nbody directly (sqrt depends on variant dsq, and GetTable keys
are variant), both are general improvements that benefit other benchmarks.

## Prior Art

**V8 (TurboFan):**
Feedback-based parameter specialization. `BytecodeGraphBuilder` reads FeedbackVector
for argument types at call sites. `SpeculativeNumberAdd/Sub/Mul` nodes include
type checks. Turboshaft's `TypedOptimizations` uses type narrowing to specialize
operations where one operand has known type. `JSCallReducer` inserts `CheckFloat64Hole`
/ `CheckSmi` at function entry for parameters.

**LuaJIT:**
Trace JIT records concrete types during trace recording. Parameters enter the trace
with their recorded types — no separate "parameter guard" mechanism. If type changes
on re-entry, side exit occurs. Simpler model but only works for trace JIT.

**SpiderMonkey (Warp):**
CacheIR snapshots from Baseline JIT encode argument types. WarpBuilder reads these
to insert GuardTo(Double/Int32) at function entry. Similar to V8's approach.

**Our constraints vs theirs:**
V8/SpiderMonkey use call-site feedback to type parameters before entering the optimized
function. GScript does not have call-site type feedback — only per-PC result feedback
from GetField/GetTable. The workaround: use-site type inference. If a parameter is
used in arithmetic with typed operands (after feedback guards), infer the parameter
must also be that type.

## Approach

### Task 1: Float parameter guards in TypeSpecialize (pass_typespec.go)

Add `insertFloatParamGuards` method that runs AFTER Phase 1's first type propagation:

1. Find LoadSlot params that Phase 0 didn't guard (still TypeAny/TypeUnknown)
2. Scan all numeric ops: if a param is used in arithmetic where the OTHER operand
   has inferred TypeFloat, mark param as float-like
3. Insert GuardType(param, TypeFloat) at the entry block, right after the LoadSlot
4. Replace all uses of the param with the guard's output (except in the guard itself)
5. Re-run Phase 1 type propagation to cascade the new types

This fixes nbody's `dt` and generalizes to any function with float parameters.

### Task 2: GuardType CSE in LoadElim (pass_load_elim.go)

Extend LoadEliminationPass to track GuardType by (value_id, guard_type):

```
guardAvailable: map[(argID, guardType)] → guardResultID
```

When a GuardType(v, T) is encountered and (v.ID, T) is already in the map,
replace all uses of the new guard's result with the existing guard's result.
Clear guardAvailable on OpCall/OpSelf (same as field available map).

### Task 3: OpSqrt + OpGetTable in LICM (pass_licm.go)

- Add `case OpSqrt: return true` to `canHoistOp`. Pure single-input float op.
- Add `case OpGetTable: return true` with alias checking (no in-loop SetTable on
  same table, no in-loop Call). Same pattern as GetField/GetGlobal.
- GetTable alias check: `setTables[objID]` tracks tables with in-loop SetTable.

### Task 4: Tests

- TestTypeSpec_FloatParamGuard: function with float param used in Div/Mul with
  float operands → verify param gets GuardType(TypeFloat) → downstream ops typed
- TestLoadElim_GuardTypeCSE: redundant GuardType on same value → verify eliminated
- TestLICM_Sqrt: loop with invariant sqrt → verify hoisted to preheader
- TestLICM_GetTable: loop with invariant table+key GetTable → verify hoisted

## Expected Effect

**Prediction calibration**: Instruction-count estimates halved for ARM64 superscalar.
Previous round (21) predicted broad 8-23% from R(0) pin and got 8.1% on nbody — within
range. This round targets a smaller, more precisely measurable effect.

- nbody: 7 generic ops → typed. Per generic Div: ~15 insns overhead. Per generic Mul/Add:
  ~10 insns overhead. Total: 15 + 6×10 = 75 insns per function call × 500K calls = 37.5M insns.
  Plus 1 Div per j-iter: 15 × 5M = 75M. Total ~112M insns. At 6 IPC, 3GHz: ~6ms.
  Halved for superscalar: **~3ms → ~1-2% improvement on nbody (0.261→0.256s)**.
- Guard CSE: 2 redundant guards × 3 insns × 5M = 30M insns. Halved: **~1ms → 0.4%**.
- Combined nbody estimate: **−2-3% (0.261→0.253s)**. Conservative — branch elimination
  has outsized impact on M4's wide pipeline, could be −4-6%.
- matmul/spectral/broad: any function with float params benefits. Magnitude depends on
  whether those functions have untyped params in hot paths.

## Failure Signals

- Signal 1: nbody benchmark unchanged after Task 1 → dt is NOT the bottleneck, investigate
  with ARM64 disasm → pivot to cross-block shape propagation
- Signal 2: Multiple benchmarks regress → GuardType insertion is deopt-thrashing → revert,
  add call-site feedback instead of speculative guards
- Signal 3: matmul already has typed arithmetic in production → Task 4 diagnostic confirms
  remaining bottleneck is per-GetTable overhead, not typing → document for next round

## Task Breakdown

- [x] 1. **Float param guards** — file: `pass_typespec.go` — test: `TestTypeSpec_FloatParamGuard`
- [x] 2. **GuardType CSE** — file: `pass_load_elim.go` — test: `TestLoadElim_GuardTypeCSE`
- [x] 3. **LICM OpSqrt + OpGetTable** — file: `pass_licm.go` — test: `TestLICM_Sqrt`, `TestLICM_GetTable`
- [x] 4. **Integration test + benchmark** — run full benchmark suite, verify no regressions

## Budget

- Max commits: 4 functional (+1 revert slot)
- Max files changed: 5 (3 pass files + 2 test files)
- Abort condition: 3 commits without benchmark movement or any benchmark regression >5%

## Results (filled after VERIFY)
| Benchmark | Before | After | Change |
|-----------|--------|-------|--------|

## Lessons (filled after completion/abandonment)
