# N1,9 — Property 2

> Single reference point verification report  
> Generated 2026-03-25

## Reference Point

- **Model:** `ACASXU_run2a_1_9_batch_2000.onnx`
- **Property:** prop2
- **Reference point (property midpoint):** `[0.639929, 0.0, 0.0, 0.475, -0.475]`
- **Network prediction:** class **0** (Clear-of-Conflict)
- **Network outputs at midpoint:** `[-0.0192, -0.0178, -0.018, -0.0174, -0.0173]`
  - Predicted class has the **lowest** output (ACAS Xu uses argmin)

## Robustness Summary

For each target class, what is the **largest ε** at which this reference point is verified (Y/UNSAT)?

### Best result per target (across all rules and α)

| Target | Class Name | Best Rule | α | Max Verified ε | Status |
|--------|------------|-----------|---|----------------|--------|
| 1 | Weak Left | `ALWAYS_OFF (α=0.9)` | 0.9 | 0.05 | ✅ Verified up to ε=0.05 |
| 2 | Weak Right | `ALWAYS_OFF (α=0.9)` | 0.9 | 0.05 | ✅ Verified up to ε=0.05 |
| 3 | Strong Left | `ALWAYS_OFF (α=0.9)` | 0.9 | 0.05 | ✅ Verified up to ε=0.05 |
| 4 | Strong Right | `ALWAYS_OFF (α=0.9)` | 0.9 | 0.05 | ✅ Verified up to ε=0.05 |

**Overall:** This reference point is **fully robust** (all 4 targets verified) up to **ε = 0.05** (with appropriate NAP rules).

---

## Detailed Results Per Target

### Target 1 (Weak Left)

*Can the network be fooled from class 0 (Clear-of-Conflict) to class 1 (Weak Left) within an ε-ball?*

| Rule | ε=0.02 | ε=0.05 | ε=0.10 | ε=0.20 |
|------|--------|--------|--------|--------|
| `none (baseline)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_OFF (α=0.9)` | 🟢 Y (0s) | 🟢 Y (29s) | 🔴 N (1s) | 🔴 N (2s) |
| `ALWAYS_OFF (α=0.95)` | 🟢 Y (1s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_OFF (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_ON (α=0.9)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_ON (α=0.95)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_ON (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) |
| `ALWAYS_ON+OFF (α=0.9)` | 🟢 Y (0s) | 🟢 Y (24s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_ON+OFF (α=0.95)` | 🟢 Y (1s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (0s) |
| `ALWAYS_ON+OFF (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `Impl L0→L1 (α=0.9)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L0→L1 (α=0.95)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L0→L1 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L1→L2 (α=0.9)` | 🔴 N (0s) | 🔴 N (2s) | 🔴 N (1s) | 🔴 N (9s) |
| `Impl L1→L2 (α=0.95)` | 🔴 N (0s) | 🔴 N (3s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L1→L2 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L2→L3 (α=0.9)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (17s) |
| `Impl L2→L3 (α=0.95)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (37s) |
| `Impl L2→L3 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (4s) |
| `Impl L3→L4 (α=0.9)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (14s) |
| `Impl L3→L4 (α=0.95)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L3→L4 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) | 🔴 N (3s) |
| `Impl L4→L5 (α=0.9)` | 🟢 Y (0s) | 🟢 Y (29s) | 🔴 N (2s) | 🔴 N (2s) |
| `Impl L4→L5 (α=0.95)` | 🟢 Y (1s) | 🟢 Y (102s) | 🔴 N (2s) | 🔴 N (3s) |
| `Impl L4→L5 (α=0.99)` | 🔴 N (1s) | 🔴 N (13s) | 🔴 N (2s) | 🔴 N (2s) |

### Target 2 (Weak Right)

*Can the network be fooled from class 0 (Clear-of-Conflict) to class 2 (Weak Right) within an ε-ball?*

| Rule | ε=0.02 | ε=0.05 | ε=0.10 | ε=0.20 |
|------|--------|--------|--------|--------|
| `none (baseline)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_OFF (α=0.9)` | 🟢 Y (0s) | 🟢 Y (30s) | 🔴 N (1s) | 🔴 N (0s) |
| `ALWAYS_OFF (α=0.95)` | 🟢 Y (1s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_OFF (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_ON (α=0.9)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_ON (α=0.95)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) |
| `ALWAYS_ON (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) |
| `ALWAYS_ON+OFF (α=0.9)` | 🟢 Y (0s) | 🟢 Y (26s) | 🔴 N (1s) | 🔴 N (0s) |
| `ALWAYS_ON+OFF (α=0.95)` | 🟢 Y (1s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_ON+OFF (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `Impl L0→L1 (α=0.9)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L0→L1 (α=0.95)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L0→L1 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) | 🔴 N (3s) |
| `Impl L1→L2 (α=0.9)` | 🔴 N (0s) | 🔴 N (2s) | 🔴 N (9s) | 🔴 N (11s) |
| `Impl L1→L2 (α=0.95)` | 🔴 N (0s) | 🔴 N (3s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L1→L2 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L2→L3 (α=0.9)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (3s) | 🔴 N (30s) |
| `Impl L2→L3 (α=0.95)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (40s) |
| `Impl L2→L3 (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L3→L4 (α=0.9)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (17s) |
| `Impl L3→L4 (α=0.95)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L3→L4 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) | 🔴 N (2s) |
| `Impl L4→L5 (α=0.9)` | 🟢 Y (0s) | 🟢 Y (30s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L4→L5 (α=0.95)` | 🟢 Y (1s) | 🟡 T/o (120s) | 🔴 N (2s) | 🔴 N (3s) |
| `Impl L4→L5 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (3s) |

### Target 3 (Strong Left)

*Can the network be fooled from class 0 (Clear-of-Conflict) to class 3 (Strong Left) within an ε-ball?*

| Rule | ε=0.02 | ε=0.05 | ε=0.10 | ε=0.20 |
|------|--------|--------|--------|--------|
| `none (baseline)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_OFF (α=0.9)` | 🟢 Y (0s) | 🟢 Y (31s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_OFF (α=0.95)` | 🟢 Y (1s) | 🔴 N (1s) | 🔴 N (0s) | 🔴 N (1s) |
| `ALWAYS_OFF (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_ON (α=0.9)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_ON (α=0.95)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) |
| `ALWAYS_ON (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) |
| `ALWAYS_ON+OFF (α=0.9)` | 🟢 Y (0s) | 🟢 Y (24s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_ON+OFF (α=0.95)` | 🟢 Y (1s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (0s) |
| `ALWAYS_ON+OFF (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `Impl L0→L1 (α=0.9)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (2s) | 🔴 N (2s) |
| `Impl L0→L1 (α=0.95)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) | 🔴 N (2s) |
| `Impl L0→L1 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L1→L2 (α=0.9)` | 🔴 N (0s) | 🔴 N (3s) | 🔴 N (24s) | 🔴 N (7s) |
| `Impl L1→L2 (α=0.95)` | 🔴 N (0s) | 🔴 N (3s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L1→L2 (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L2→L3 (α=0.9)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (16s) |
| `Impl L2→L3 (α=0.95)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (23s) |
| `Impl L2→L3 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L3→L4 (α=0.9)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L3→L4 (α=0.95)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L3→L4 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L4→L5 (α=0.9)` | 🟢 Y (0s) | 🟢 Y (30s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L4→L5 (α=0.95)` | 🟢 Y (1s) | 🟡 T/o (120s) | 🔴 N (2s) | 🔴 N (2s) |
| `Impl L4→L5 (α=0.99)` | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (3s) |

### Target 4 (Strong Right)

*Can the network be fooled from class 0 (Clear-of-Conflict) to class 4 (Strong Right) within an ε-ball?*

| Rule | ε=0.02 | ε=0.05 | ε=0.10 | ε=0.20 |
|------|--------|--------|--------|--------|
| `none (baseline)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_OFF (α=0.9)` | 🟢 Y (0s) | 🟢 Y (31s) | 🔴 N (0s) | 🔴 N (1s) |
| `ALWAYS_OFF (α=0.95)` | 🟢 Y (1s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_OFF (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_ON (α=0.9)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_ON (α=0.95)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) |
| `ALWAYS_ON (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `ALWAYS_ON+OFF (α=0.9)` | 🟢 Y (0s) | 🟢 Y (25s) | 🔴 N (1s) | 🔴 N (1s) |
| `ALWAYS_ON+OFF (α=0.95)` | 🟢 Y (1s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (0s) |
| `ALWAYS_ON+OFF (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (0s) |
| `Impl L0→L1 (α=0.9)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) | 🔴 N (2s) |
| `Impl L0→L1 (α=0.95)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) | 🔴 N (2s) |
| `Impl L0→L1 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L1→L2 (α=0.9)` | 🔴 N (0s) | 🔴 N (3s) | 🔴 N (7s) | 🔴 N (11s) |
| `Impl L1→L2 (α=0.95)` | 🔴 N (0s) | 🔴 N (2s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L1→L2 (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L2→L3 (α=0.9)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (2s) | 🔴 N (36s) |
| `Impl L2→L3 (α=0.95)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (56s) |
| `Impl L2→L3 (α=0.99)` | 🔴 N (0s) | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (5s) |
| `Impl L3→L4 (α=0.9)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (2s) | 🔴 N (27s) |
| `Impl L3→L4 (α=0.95)` | 🟢 Y (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (3s) |
| `Impl L3→L4 (α=0.99)` | 🔴 N (0s) | 🔴 N (1s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L4→L5 (α=0.9)` | 🟢 Y (0s) | 🟢 Y (30s) | 🔴 N (1s) | 🔴 N (2s) |
| `Impl L4→L5 (α=0.95)` | 🟢 Y (2s) | 🟡 T/o (120s) | 🔴 N (2s) | 🔴 N (3s) |
| `Impl L4→L5 (α=0.99)` | 🔴 N (1s) | 🔴 N (9s) | 🔴 N (2s) | 🔴 N (3s) |

---

## Per-Layer Results (ε=0.02 only, α=0.90)

Which layer pair contributes most to verification?

| Layer Pair Rule | Targets Verified (of 4) |
|-----------------|------------------------|
| `Impl L0→L1 (α=0.9)` | 0/4 |
| `Impl L1→L2 (α=0.9)` | 0/4 |
| `Impl L2→L3 (α=0.9)` | 4/4 |
| `Impl L3→L4 (α=0.9)` | 4/4 |
| `Impl L4→L5 (α=0.9)` | 4/4 |
