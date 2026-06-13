# Session Log

Last session: [2026-06-13] — Repo re-sync + kernel-picture analysis program

## What was done this session
1. **Git re-sync.** `git pull` revealed origin/main had been force-rewritten ~8 months ahead of the
   local line. Backed up stale local source edits to branch `backup/pre-sync-2026-06-13` (commit
   `63d00ce`), reset `main` to origin/main (`6d7ff8f`). Untracked result dirs left intact.

2. **Familiarisation.** Read METHODOLOGY.md, NATURAL_GRADIENT_COLLOCATION.md, the CTNN
   `architecture_diagnostics/DIAGNOSTIC_SUMMARY.md`, results.tex "What the networks learn", the SR
   code (`sr_preconditioner.py`: Woodbury/CG/MinSR; `Stochastic_Reconfiguration.py`), and the CTNN
   V-cycle architecture (`jastrow_architectures.py`).

3. **Brainstorm** for three new thesis angles (SR↔NTK↔NG; why CTNN>FFNN; what networks learn),
   unified under the tangent-kernel picture (`O`, `S=OᵀO`, `K=OOᵀ`). Catalogued experiments A1–A6,
   B1–B9, C1–C9, X1–X6.

4. **Wrote the vision/phased plan:** `plans/2026-06-13_kernel-analysis-program.md`. Focus on
   VMC/SR-trained (genuine GS) wavefunctions, with a GS-quality gate, dual-track VMC-vs-collocation
   comparison, and a kernel-picture lens. Phases: N=2 ω=1.0 → N=2 all ω → N=6 → N=12 → N=20, with a
   consolidation gate before each scale-up.

## Next session
**Recommended starting point:** Phase A — secure an analysis-grade `N=2, ω=1.0` GS (must hit E=3.0
exact), and stand up infrastructure I1–I3 (`O/S/K` builder, GS-quality evaluator, imaginary-time
direction probe). Then run A1/A2/A3 and check the kernel story against the exact N=2 solution.
**Open questions:** Do SR-trained and collocation-trained models reach the same wavefunction or just
the same energy? Does `cos(δθ_SR, imag-time)` ≈ 1 hold at N=2 as the theory (T1–T3) predicts?
**Caveats to control:** several published single-seed N=6 results (100% kinetic, random=zero messages)
need seed sweeps; N=20 reduced architecture confounds cross-N claims.
**Context freshness:** current

See ARCHIVE.md for full history.
