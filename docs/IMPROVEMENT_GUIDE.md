# kronos-semi: Improvement Guide

**Purpose.** This document is the ground-truth roadmap for transforming kronos-semi
from a KronosAI submission artifact into a production engine that sits behind a
COMSOL-Semiconductor-style web GUI. It is written to be consumed by both human
contributors and coding agents (Claude, Codex, Cursor, etc.); read it alongside
`PLAN.md` and `docs/ROADMAP.md`.

Nothing in here is aspirational hand-waving. Every milestone below states its
input, its acceptance test, and its dependency on prior milestones.

---

## 1. Honest current state (as of v0.16.0)

What exists and works:

- `semi/` package with a five-layer architecture; Layer 3 (pure-Python
  core) has no dolfinx dependency and is independently testable.
- JSON schemas v1.4.0 (Draft-07, the legacy loose schema retained one
  minor cycle for v1.x.y inputs) and v2.0.0 (Draft-07, strict,
  `additionalProperties: false`; the post-M14.3 default), both
  enforced via `jsonschema`. Schema fields cover mesh, regions,
  doping, contacts, physics, solver, output, plus the top-level
  `coordinate_system` field added in M14.2 and the `solver.backend` /
  `solver.compute` fields added in M15.
- Builtin meshes in 1D/2D/3D plus gmsh `.msh` loader with physical
  groups.
- Equilibrium Poisson, coupled drift-diffusion in Slotboom form, SRH
  recombination with configurable trap energy.
- Ohmic and ideal-gate contacts; multi-region Poisson with Si/SiO2
  via `create_submesh`.
- Adaptive bias-ramp continuation with halving and growth, bipolar
  sweep support.
- Transient solver in Slotboom primary unknowns: backward-Euler and
  BDF2, with the deep-steady-state runner matching `bias_sweep`
  within 1e-4 relative error and the `pn_1d_turnon` benchmark within
  5% (M13, M13.1; ADRs 0010, 0014).
- Small-signal AC sweep for two-terminal devices via the linearised
  `(J + jωM) δu = -dF/dV δV` system in real 2x2 block form; the
  `rc_ac_sweep` benchmark matches analytical depletion C within
  0.4% over [1 Hz, 1 MHz] (M14; ADR 0011).
- MOSCAP differential capacitance via AC admittance: the
  `mos_cap_ac` runner returns dQ/dV directly from `Im(Y) / (2πf)`,
  audit case 03 confirms byte-identity with `mos_cv` Q_gate (M14.1).
- Axisymmetric (cylindrical) 2D path: r-weighted Poisson and Slotboom
  drift-diffusion on the meridian half-plane; `benchmarks/moscap_axisym_2d/`
  reproduces Hu Fig. 5-18; runner dispatch in `mos_cap_ac.py` r-weights
  charge and sensitivity forms (M14.2; PRs #64, #65).
- Eight shipped benchmarks (`pn_1d`, `pn_1d_bias`, `pn_1d_bias_reverse`,
  `pn_1d_turnon`, `mos_2d`, `resistor_3d`, `rc_ac_sweep`,
  `moscap_axisym_2d`), each with a verifier asserting closed-form
  physical correctness.
- MMS verification for Poisson and DD across multiple variants and
  grids, discrete-conservation checks, mesh-convergence ladder, plus
  AC consistency and audit suites; 237+ pure-Python tests passing.
- Five Colab notebooks that install FEniCSx via fem-on-colab and run
  each benchmark end-to-end.
- On-disk result artifact contract: `manifest.json`, fields, IV CSVs,
  and convergence logs under `runs/<run_id>/`, schema-validated; a
  pure-Python reader round-trips without dolfinx (M9).
- HTTP server surface: `kronos_server/` with `POST /solve`,
  `GET /runs/{id}`, WebSocket `/runs/{id}/stream`, `GET /materials`,
  `GET /schema`; the server process imports no dolfinx at module
  scope (M10).
- Schema versioning: `schemas/input.v1.json` Draft-07 with full
  UI-facing annotations, every benchmark validates, the major-version
  gate refuses mismatched majors (M11).
- 2D MOSFET with Gaussian n+ source/drain implants on the multi-region
  Poisson + Slotboom DD stack. Pao-Sah linear-regime analytical
  verifier in `[V_T + 0.2, V_T + 0.6]` V at `V_DS = 0.05` V with a
  20% tolerance (M14.3).
- GPU linear-solver path via PETSc CUDA / HIP, AMGX or hypre BoomerAMG
  preconditioning (M15). Schema 1.4.0 adds `solver.backend` and
  `solver.compute`; manifest 1.1.0 adds KSP iters and linear-solve
  wall time; `semi/compute.py` runtime probe and dynamic
  `GET /capabilities` endpoint.

What does *not* exist:

- **No field-dependent mobility, Auger, Fermi-Dirac, Schottky
  contacts, or tunneling.** COMSOL Semiconductor has all of these.
  M16.1 through M16.7, one PR per model, each with an explicit
  numerical acceptance threshold.
- **No real 3D semiconductor device.** The 3D coverage today is the
  doped resistor (M7) and a pure-Poisson box (M15 acceptance test).
  No 3D MOSFET / FinFET / planar transistor. M19 closes this with a
  3D MOSFET benchmark on a gmsh-sourced unstructured mesh.
- **No heterojunctions.** Position-dependent χ and Eg are not yet
  supported. M17 (depends on M16.4 Fermi-Dirac because heterojunctions
  break the nondegenerate approximation at the barrier).
- **No Cartesian-2D MOSCAP variant** and no rigorous gate-driven HF
  C-V method. Tracked in [`docs/ROADMAP.md`](ROADMAP.md) §Deferred;
  superseded for practical purposes by M16.4 (which the rigorous HF
  C-V depends on at high doping) and M19 (3D MOSFET, which exercises
  the same multi-region infrastructure on a more important device).
- **No MPI parallel orchestration in the runners.** dolfinx supports
  MPI natively; bias-sweep, postprocess, and IV recording in
  `semi/runners/` and `semi/postprocess.py` need a collective-
  communication audit before mosfet_3d at ~1M DOFs is practical.
  M19.1.
- **No HTTP server hardening.** `kronos_server/app.py` carries a
  `# TODO(M10+): add auth, rate limiting, API keys before any public
  deployment`. M20.
- **One small production-hardening gap remaining**: the transient
  runner accepts no `V(t)` (audit case 06 is `pytest.skip`). M16.7
  closes it with a per-step contact-voltage callable / table; see
  the M16.7 entry in §4. The four gaps closed in M14.3 (strict
  schema, XDMF mesh ingest, Pao-Sah `mosfet_2d` verifier, and the
  ~792 LOC of dead-on-active-path Scharfetter-Gummel primitives in
  `semi/fem/sg_assembly.py`) shipped in v0.16.0.

Bottom line: the numerics are sound, the engine is addressable from
outside Python, results are consumable without a dolfinx install, the
schema is versioned and richly annotated, and the GPU linear-solve
lever is in place. The remaining work is filling out the Tier 1
physics catalogue (M16.1 through M16.7), shipping a real 3D
semiconductor device (M19), hardening the HTTP server for
multi-tenant deployment (M20), and extending to heterojunctions (M17).

---

## 2. Design principles (non-negotiable)

These are the constraints every subsequent milestone must respect. They are
the invariants that let a GUI be built without constantly re-ploughing the
engine.

**P1. The JSON is the contract.** The UI never calls Python functions
directly. The UI emits JSON, the engine consumes JSON, the engine emits a
result artifact. No shared memory, no pickled objects, no language coupling.

**P2. Results are plain files.** A completed simulation is a directory on
disk (or object-store prefix) containing a `manifest.json`, a `mesh.vtu` (or
`.bp` / `.xdmf+h5`), one `field_<name>.vtu` per scalar/vector field, and one
`iv.csv` per swept quantity. A UI reads these with stock libraries (vtk.js,
numpy, pandas); no dolfinx import ever happens on the UI side.

**P3. The engine is stateless between jobs.** Each `POST /solve` gets a fresh
MPI process (or worker pool slot). State that must persist across jobs lives
in the object store, never in RAM.

**P4. The schema versions.** Every JSON input carries
`"schema_version": "1.2.0"`. Engine refuses to run mismatched major versions
and warns on minor skew.

**P5. GPU is opt-in, not load-bearing.** The CPU path stays as the reference
and V&V truth. GPU accelerates the linear solver and the assembly of large
forms; it never changes what the result *is*, only how fast.

**P6. Nothing in the engine API leaks PETSc or UFL types.** The boundary types
are: JSON in, numpy arrays + mesh files + manifest dict out. Anything else is
an implementation detail.

---

## 3. Result artifact contract (ship this first, everything else depends on it)

Every successful solve writes a directory with this layout:

```
<run_id>/
├── manifest.json           # schema-versioned metadata
├── input.json              # exact JSON that was solved (copy)
├── mesh/
│   ├── mesh.xdmf           # topology + geometry
│   └── mesh.h5
├── fields/
│   ├── psi.bp              # potential (ADIOS2 BP5 or vtu)
│   ├── n.bp                # electron density
│   ├── p.bp                # hole density
│   ├── N_net.bp            # net doping
│   ├── E.bp                # electric field (vector)
│   └── J.bp                # current density (vector, per bias step)
├── iv/
│   └── <contact>.csv       # V, J_n, J_p, J_tot per sweep step
├── convergence/
│   └── snes.csv            # per-step Newton iter count, residual norms
└── logs/
    └── engine.log
```

### `manifest.json` schema (v1)

```json
{
  "schema_version": "1.0.0",
  "engine": {"name": "kronos-semi", "version": "0.9.0", "commit": "..."},
  "run_id": "2026-04-23T16-32-11Z_pn_bias_a1b2c3",
  "status": "completed",
  "wall_time_s": 12.4,
  "input_sha256": "...",
  "solver": {
    "type": "bias_sweep",
    "backend": "petsc-cpu-mumps",
    "n_dofs": 1200,
    "n_steps": 21,
    "converged": true
  },
  "fields": [
    {"name": "psi",   "units": "V",    "path": "fields/psi.bp",   "rank": 0},
    {"name": "n",     "units": "m^-3", "path": "fields/n.bp",     "rank": 0},
    {"name": "p",     "units": "m^-3", "path": "fields/p.bp",     "rank": 0},
    {"name": "E",     "units": "V/m",  "path": "fields/E.bp",     "rank": 1},
    {"name": "J",     "units": "A/m^2","path": "fields/J.bp",     "rank": 1}
  ],
  "sweeps": [
    {"kind": "voltage", "contact": "cathode",
     "path": "iv/cathode.csv", "n_steps": 21, "bipolar": false}
  ],
  "mesh": {
    "path": "mesh/mesh.xdmf", "dimension": 1,
    "n_cells": 400, "n_vertices": 401,
    "regions": [{"name": "silicon", "tag": 1, "material": "Si"}]
  },
  "warnings": []
}
```

The UI reads the manifest first; everything else is lazy-loaded.

---

## 4. Milestones (M9 onward; M1–M8 already shipped)

Each milestone is self-contained, has a single deliverable, and has an
acceptance test that can be demanded of a coding agent. Do them roughly in
order, but M9/M10 are load-bearing — everything after assumes them.

### M9 — Result artifact writer + manifest

**Status: Done (2026-04-23).** `semi/io/artifact.py`, `semi-run` CLI,
`schemas/manifest.v1.json`, pure-Python reader. Full deliverable,
acceptance tests, and scope preserved in §10.

---

### M10 — HTTP server: `POST /solve`, `GET /runs/{id}`

**Status: Done (M10).** `kronos_server/` package, FastAPI surface,
WebSocket progress channel, `ProcessPoolExecutor`-backed workers.
Full deliverable, acceptance tests, and scope preserved in §10.

---

### M11 — Schema versioning + UI-facing schema companion

**Status: Done (M11).** `schemas/input.v1.json` Draft-07 with full
UI annotations; `schema_version` enforced via the major-version gate
in `semi/schema.py`. Full deliverable, acceptance tests, and scope
preserved in §10.

---

### M12 — Mesh input beyond axis-aligned boxes

**Status: Done (M12).** Gmsh `.geo` / `.msh` ingest with content-hash
caching; 2D MOSFET benchmark with Gaussian n+ source/drain implants.
Full deliverable, acceptance tests, and scope preserved in §10.

---

### M13 — Transient solver

**Status: Done (2026-04-25).** Backward-Euler and BDF2 time stepping
on the coupled (psi, phi_n, phi_p) system; `pn_1d_turnon` benchmark.
Full deliverable, acceptance tests, and scope preserved in §10.

---

### M13.1 — Slotboom transient close-out

**Status: Done (2026-04-27).** Slotboom primary unknowns (ADR 0014,
supersedes ADR 0009) replace the M13 (n, p) Galerkin discretisation;
both `test_transient_steady_state_limit` and the BDF rate tests are
active and passing as of v0.14.1; the deep-steady-state runner
matches `bias_sweep` within 1e-4 relative error and the
`pn_1d_turnon` benchmark is within 5%.

---

### M14 — AC small-signal analysis

**Status: Done (2026-04-26, v0.14.0).** Linearised
`(J + jωM) δu = -dF/dV δV` in real 2x2 block form (PETSc-real build);
`rc_ac_sweep` benchmark matches analytical depletion C within 0.4%
over [1 Hz, 1 MHz]; ADR 0011 with sign-convention errata. See
[CHANGELOG.md](../CHANGELOG.md) `[0.14.0]` entry. Full deliverable,
acceptance tests, and scope preserved in §10.

---

### M14.1 — AC differential capacitance for MOSCAP

**Status: Done (2026-04-26, PR #38).** `semi/runners/mos_cap_ac.py`
returns dQ/dV directly from `Im(Y) / (2πf)`, replacing the noisier
`numpy.gradient(Q, V)` of `mos_cv` for the `mos_2d` C-V verifier;
audit case 03 confirms byte-identity with `mos_cv` Q_gate at all 42
gate voltages. See [CHANGELOG.md](../CHANGELOG.md) `[0.14.0]` /
`[Unreleased]` entries.

---

### M14.2 — Axisymmetric (cylindrical) 2D MOSCAP

**Status: Done (2026-04-30, PRs #64, #65).** Top-level
`coordinate_system` field (schema 1.3.0, `cartesian` default or
`axisymmetric`) with cross-field validation; r-weighted Poisson and
Slotboom drift-diffusion on the meridian half-plane
(`semi/physics/axisymmetric.py`); pure-Python MOSCAP analytical
helpers (`semi/cv.py`); `benchmarks/moscap_axisym_2d/` reproduces
Hu Fig. 5-18; runner dispatch in `mos_cap_ac.py` r-weights the
charge and sensitivity forms. See [CHANGELOG.md](../CHANGELOG.md)
`[Unreleased]` entry. The Cartesian-2D MOSCAP variant and rigorous
gate-driven HF C-V method (M14.2.x) are now in
[`docs/ROADMAP.md`](ROADMAP.md) §Deferred; superseded for practical
purposes by M16.4 and M19.

---

### M14.3: Housekeeping (cheap closes)

**Status: Done (v0.16.0, 2026-05-22).** Four production-hardening gaps
closed on branch `dev/m14.3-housekeeping`: Pao-Sah `mosfet_2d`
verifier with `I_D / W` tolerance 20% in `V_GS in [V_T + 0.2,
V_T + 0.6] V`; XDMF mesh ingest in
[`semi/mesh.py`](../semi/mesh.py); strict schema v2.0.0
(`additionalProperties: false`) with v1 deprecated for one minor
cycle; dead-on-active-path
[`semi/fem/sg_assembly.py`](../semi/fem/sg_assembly.py) (~792 LOC)
deleted and the coverage gate raised from 92 to 95. See
[CHANGELOG.md](../CHANGELOG.md) `[0.16.0]` entry.

---

### M15 — GPU linear solver path

**Status: Done (v0.15.0).** See PLAN.md §Completed work for the
ship summary; this section is preserved for the original scoping
discussion.

**Why:** Above ~200k DOFs the MUMPS LU factorization dominates wall time. 3D
FinFET-class problems will be in the millions of DOFs and CPU-LU is hopeless.
GPU-accelerated iterative solvers change the scaling law.

**What can actually run on GPU** (be realistic about this):

| Stage                          | GPU-suitable?                | Library                       |
|--------------------------------|------------------------------|-------------------------------|
| Mesh build, tagging            | No (serial graph operations) | n/a                           |
| UFL → assembly                 | Yes, with dolfinx-cuda/KOKKOS| dolfinx-cuda (experimental)   |
| Jacobian assembly              | Partial; the dominant O(N)   | dolfinx-cuda                  |
| Linear solve (Krylov)          | **Yes — biggest win**        | PETSc + HIP/CUDA, AMGX, hypre |
| Preconditioner setup (AMG)     | Yes                          | AMGX, hypre-BoomerAMG         |
| Nonlinear SNES loop overhead   | No (negligible cost)         | n/a                           |
| I/O (writing fields)           | No                           | n/a                           |

**Realistic plan:** the 80/20 is "PETSc built against CUDA/HIP, Jacobian
solved on GPU via AMGX or hypre on device." Do not try to port assembly to
GPU yet — dolfinx-cuda is experimental and moving fast.

**Deliverable:**

- `semi/solver.py` grows a `backend: str = "cpu-mumps" | "gpu-amgx" | "gpu-hypre"`
  parameter.
- CPU path untouched, bit-identical to current output.
- GPU path: Jacobian assembled on CPU, copied to GPU, solved with AMGX (or
  PETSc-GAMG-on-device); solution copied back.
- Benchmark: 3D FinFET-scale mesh (≥500k DOFs) showing ≥5× speedup over
  CPU-MUMPS on an A100 or MI300X.
- CI covers CPU path only; GPU path has a separate self-hosted runner or is
  left to nightly.

**Acceptance tests:**

1. On the existing benchmarks, GPU backend produces results within 1e-8
   relative L2 of the CPU-MUMPS reference.
2. On the new large-3D benchmark, wall-time speedup ≥5× for the linear-solve
   portion alone.
3. Fallback: GPU backend gracefully degrades to CPU if no device is found,
   with a warning in the manifest.

**Estimated scope:** 5–7 days, dominated by environment setup.

**Dependencies:** M9 (needs artifact writer for timing instrumentation).

---

### M16: Physics completeness pass (umbrella)

**Why.** To mimic COMSOL Semiconductor properly we need the models
engineers actually use daily. The umbrella M16 work is broken into
seven sub-milestones, each shipped as its own PR with an explicit
acceptance test and an analytical or external reference. Do them in
the order below; M16.4 (Fermi-Dirac) is a hard prerequisite for both
M16.6 (BBT tunneling, where the density of states matters) and M17
(heterojunctions, where the barrier breaks the nondegenerate
approximation).

**Deliverable.** Seven sub-milestones, each its own PR. See M16.1
through M16.7 below.

**Acceptance tests.** Each sub-milestone has its own gate; the
umbrella M16 is "done" when all seven are merged and every existing
benchmark with the default (constant mobility, Boltzmann statistics,
SRH-only recombination) is bit-identical to v0.15.0.

**Dependencies.** M9 (artifact writer), M11 (schema versioning),
M14.3 (strict-mode schema must be in place before any new schema
field is added; the v1-vs-v2 acceptance also exercises every
benchmark JSON).

---

### M16.1: Caughey-Thomas field-dependent mobility

**Why.** Velocity saturation is the entry-level field-dependent
mobility model and is required for any quantitative MOSFET I-V at
fields above ~10 kV/cm. Without it, the M14.3 mosfet_2d verifier
passes only in the deeply-linear regime; with it, we can extend the
verifier window into saturation and start running 3D MOSFET
benchmarks meaningfully.

**Deliverable.**

- New file `semi/physics/mobility.py` with `caughey_thomas_mu(mu0, F_par, ...)`
  UFL builder. Closed-form, no new unknowns. Schema entry
  `physics.mobility.model: "constant" | "caughey_thomas"` with parameters
  `vsat_n`, `vsat_p`, `beta_n`, `beta_p`. Defaults bake in the standard
  Si values (vsat ~ 1e7 cm/s, beta_n = 2, beta_p = 1).
- Wire the new mobility into
  [`semi/physics/drift_diffusion.py`](../semi/physics/drift_diffusion.py)
  and [`semi/runners/bias_sweep.py`](../semi/runners/bias_sweep.py)
  behind the schema dispatch. The `constant` branch is bit-identical
  to pre-M16.1.
- MMS verifier `tests/fem/test_mms_caughey_thomas.py`: extend the
  existing MMS-DD harness to include a manufactured solution where
  the mobility depends on the gradient. Acceptance L2 rate >= 1.99,
  H1 rate >= 0.99 at the finest pair.
- New benchmark `benchmarks/diode_velsat_1d/`: 1D pn diode at
  `V_F in [0.5, 0.9] V` comparing constant-mu and caughey-thomas
  forward I-V; verifier asserts the two diverge by >5% at 0.9 V and
  converge to within 1% at 0.5 V.

**Acceptance tests.**

1. `python scripts/run_verification.py mms_dd` includes the
   caughey_thomas variant and reports L2 rate >= 1.99 at the finest
   pair.
2. `python scripts/run_benchmark.py diode_velsat_1d` exits 0 with the
   divergence-vs-convergence verifier passing.
3. Every existing benchmark with `physics.mobility.model: "constant"`
   (which is the schema default) produces results bit-identical to
   v0.15.0.

**Dependencies.** M14.3 (need the strict-mode schema and the
tightened mosfet_2d verifier in place first; otherwise the new
mobility schema field collides with a v1 schema bump and the
mosfet_2d verifier has nothing analytical to compare velocity
saturation against).

---

### M16.2: Lombardi surface mobility

**Why.** Inversion-layer mobility in MOSFETs is dominated by surface
scattering, which Caughey-Thomas does not capture. Required for
quantitative MOSFET I-V in the inversion regime.

**Deliverable.** Lombardi composite (Coulomb + phonon + surface
roughness) added to `semi/physics/mobility.py`. Schema entry
`physics.mobility.model: "lombardi"`. Benchmark:
[`benchmarks/mosfet_2d`](../benchmarks/mosfet_2d) re-run with
lombardi mobility, verifier threshold tightened from 20% to 10% in
the inversion-strong-field region.

**Acceptance tests.**

1. MMS rate >= 1.99 L2 with a manufactured surface-distance field.
2. Re-run mosfet_2d in the [V_T + 0.4, V_T + 1.0] V window with
   lombardi mobility, get within 10% of the analytical Sah-Pao
   reference.

**Dependencies.** M16.1.

---

### M16.3: Auger recombination

**Why.** High-injection diode and BJT modeling are wrong without
Auger. Cheap (~100 LOC) and benchmarkable on a 1D diode.

**Deliverable.** `R_Auger = (C_n * n + C_p * p) * (np - n_i^2)` added
to [`semi/physics/recombination.py`](../semi/physics/recombination.py).
Schema: `physics.recombination.auger: bool` and `C_n`, `C_p`
parameters. Benchmark: 1D high-injection diode (N=1e15, V_F = 0.9 V)
where SRH alone underpredicts recombination current by >20% and
SRH+Auger matches an analytical high-injection long-diode reference.

**Acceptance tests.**

1. With `auger=false`, every existing benchmark produces results
   bit-identical to v0.15.0.
2. New benchmark `benchmarks/diode_auger_1d` shows the SRH-only-vs-
   SRH+Auger divergence at >20% and the latter matches analytical
   within 5%.

**Dependencies.** M14.3.

---

### M16.4: Fermi-Dirac statistics (gated)

**Why.** Boltzmann breaks above ~1e19 cm^-3, which is the source/drain
extension regime of every modern MOSFET. Required for quantitative
I-V at modern technology nodes and a hard prerequisite for M17
heterojunctions.

**Deliverable.** Blakemore approximation in
`semi/physics/statistics.py` for the production path; full Fermi-Dirac
integral via `scipy.special.fdk` for the verification reference.
Schema: `physics.statistics: "boltzmann" | "fermi_dirac"`, default
`boltzmann`. Replace `exp(+/- psi)` calls in
[`semi/physics/poisson.py`](../semi/physics/poisson.py) and the
Slotboom builders with dispatched calls.

**Acceptance tests.**

1. With `statistics: "boltzmann"`, every existing benchmark is
   bit-identical to v0.15.0.
2. New benchmark `benchmarks/diode_fermi_dirac_1d/` (1D pn,
   `N_D = 1e20 cm^-3` in n+ region) where boltzmann and FD diverge by
   >15% on V_bi and the FD result matches a stand-alone scipy-driven
   reference within 1e-3.
3. MMS rate >= 1.99 L2 on a manufactured solution that pushes the
   Boltzmann-validity boundary.

**Dependencies.** M14.3, M16.1.

---

### M16.5: Schottky contacts

**Why.** Diode-on-Si and any metal-semiconductor interface is
unmodellable without thermionic-emission boundary conditions.

**Deliverable.** New contact `type: "schottky"` with parameter
`barrier_height_eV`. Builder in [`semi/bcs.py`](../semi/bcs.py) adds a
Robin-style boundary form to the continuity rows; ohmic and gate
contacts unchanged. Benchmark: 1D Schottky diode with Pt-on-n-Si
contact vs thermionic-emission analytical I-V.

**Acceptance tests.**

1. New benchmark `benchmarks/schottky_1d` matches the thermionic-
   emission analytical I-V within 10% from V_F = 0.1 V to 0.5 V.
2. Existing ohmic-contact benchmarks are bit-identical.

**Dependencies.** M14.3.

---

### M16.6: Tunneling (BBT and TAT)

**Why.** Required for any non-toy diode (Zener, Esaki, GIDL) and
floating-gate flash modeling. The largest single physics addition in
M16; do this last in M16.

**Deliverable.** Kane band-to-band model and Hurkx trap-assisted
model, both as UFL generation/recombination kernels added to
[`semi/physics/recombination.py`](../semi/physics/recombination.py).
Schema flags `physics.tunneling: {bbt: bool, tat: bool}` plus model
parameters.

**Acceptance tests.**

1. New benchmark `benchmarks/zener_1d` shows reverse-bias breakdown
   current matching a Kane analytical reference within 20% from
   V_R = 4 V to 8 V on a heavily-doped (1e19) abrupt junction.
2. Existing benchmarks bit-identical with both flags off.

**Dependencies.** M14.3, M16.4 (BBT depends on the FD-corrected
density of states).

---

### M19: 3D MOSFET benchmark (capstone after M16.1)

This is a new milestone, not a rename of an existing one. Slotted
between M16 and M17.

**Why.** The single biggest visible gap relative to "mimics COMSOL
Semiconductor". Exercises the multi-region MOSFET infrastructure in
3D, the M15 GPU linear-solver path on a real device (not just on
Poisson), and the M16.1 Caughey-Thomas mobility under non-trivial
fields.

**Deliverable.**

- New benchmark `benchmarks/mosfet_3d/`: 3D n-channel MOSFET on a
  gmsh-sourced unstructured tetrahedral mesh, ~200k DOFs to start
  (scalable to ~1M for the GPU acceptance run). Channel length
  L = 250 nm, width W = 1 um, oxide t_ox = 5 nm. Gaussian n+
  source/drain implants, p-type body 1e16 cm^-3.
- Verifier compares I_D vs V_GS in linear (`V_DS = 0.05 V`) and
  saturation (`V_DS = 1.0 V`) regimes against the
  Pao-Sah-with-velocity-saturation analytical reference within 25%
  (looser than 2D because of the corner effects).
- Run on both `cpu-mumps` and `gpu-amgx` backends to demonstrate M15
  acceptance on a real device, not just on Poisson.

**Acceptance tests.**

1. `python scripts/run_benchmark.py mosfet_3d` exits 0 in both
   CPU-MUMPS and GPU-AMGX runs.
2. Linear-regime I_D within 25% of the Pao-Sah analytical reference
   at three V_GS values.
3. Saturation-regime I_DSAT within 30% of the velocity-saturation
   reference.
4. CPU/GPU wall-clock ratio for the linear solve >=5x at the
   ~500k-DOF mesh refinement, on the nightly GPU runner.

**Dependencies.** M16.1 (need Caughey-Thomas before saturation has
any meaning), M14.3 (need XDMF or gmsh ingest stable).

---

### M16.7: Time-varying transient contact voltage

**Why.** Closes audit case 06 (transient FFT vs AC sweep) which is
currently `pytest.skip`. Enables switching-transient and ringing
simulation, which is the second-most-asked-for transient feature
after turn-on.

**Deliverable.** Extend
[`semi/runners/transient.py`](../semi/runners/transient.py) to accept
a per-step contact voltage from a callable or a JSON-supplied table.
Schema:
`contacts[].voltage_t: {type: "table", times, values}` or
`{type: "step", t0, v0, v1}`. Update audit case 06 to active.

**Acceptance tests.**

1. Audit case 06 passes: transient FFT of I(t) at a small-signal
   V(t) sinusoid agrees with `run_ac_sweep` Y(omega) at the same
   frequency within 5%.
2. Existing transient benchmarks bit-identical.

**Dependencies.** M14.3.

---

### M19.1: MPI parallel benchmark

**Why.** dolfinx supports MPI natively; the runner orchestration
does not. Above ~1M DOFs (well within reach of the M15 GPU path and
the M19 3D MOSFET) MPI is the next bottleneck after the linear
solver.

**Deliverable.** Verify and where needed fix collective communication
in [`semi/runners/bias_sweep.py`](../semi/runners/bias_sweep.py) and
[`semi/postprocess.py`](../semi/postprocess.py) for IV recording. Add
a CI matrix entry that runs `benchmarks/mosfet_3d` under
`mpiexec -n 4`.

**Acceptance tests.**

1. mosfet_3d under `mpiexec -n {1,2,4}` produces the same I_D within
   1e-8 relative.
2. Wall-clock scaling: n=4 vs n=1 speedup >=2.5x on the ~500k-DOF
   mesh.

**Dependencies.** M19.

---

### M17 — Heterojunction / position-dependent band structure

**Why.** AlGaAs/GaAs, InGaAs/InP, SiGe/Si: none of this works without
position-varying electron affinity `chi(x)` and bandgap `Eg(x)`.
Required for HEMT and HBT modeling, both of which are core COMSOL
Semiconductor capabilities.

**Deliverable.** Extend the material model and the Poisson and
continuity kernels to read `chi` and `Eg` as cellwise DG0 fields.
Schema: per-region `material_overrides: {chi_eV, Eg_eV}` plus a
`heterojunction: true` switch on the region join. Benchmark: an
AlGaAs/GaAs HEMT or a SiGe HBT with a published reference solution.

**Acceptance tests.**

1. New benchmark `benchmarks/hemt_2d` (AlGaAs/GaAs) reproduces the
   2DEG sheet density at the heterojunction within 15% of a published
   self-consistent Poisson-Schrodinger reference.
2. With a single-material override (chi and Eg constant in space),
   every existing benchmark is bit-identical to v0.15.0.
3. MMS rate >= 1.99 L2 on a manufactured solution with a smooth
   chi(x) and Eg(x) variation.

**Dependencies.** M16.4 (Fermi-Dirac, because heterojunctions break
the nondegenerate approximation at the barrier).

---

### M18 — UI: first cut

**Why.** At this point the engine has everything; the UI is what
turns this into a product.

**Not in scope of this repo.** Mentioned here so the engine team
knows what invariants the UI relies on.

Recommended stack: React + TypeScript, three.js for 3D mesh
visualization, vtk.js or plotly for field rendering, JSONForms for
schema-driven device setup. The UI is a separate repo that consumes
this engine's JSON schema and HTTP API.

---

### M20: HTTP server hardening

**Why.** [`kronos_server/app.py`](../kronos_server/app.py) carries a
`# TODO(M10+): add auth, rate limiting, API keys before any public
deployment`. Required before this can be hosted multi-tenant.

**Deliverable.** API-key middleware, per-key rate limiter (in-memory
token bucket; Redis backend optional), basic admin endpoint to
issue/revoke keys. Update OpenAPI to reflect the Authorization
requirement.

**Acceptance tests.**

1. Unauthenticated `POST /solve` returns 401.
2. Authenticated `POST /solve` is rate-limited to a configurable RPS
   per key with a 429 response on overrun.
3. Existing `/health` and `/ready` endpoints remain auth-free.

**Dependencies.** None.

---

## 5. GPU section (expanded)

### What is worth accelerating

Profile first, then accelerate. But a general ordering of the biggest wins:

1. **Linear solve (Krylov + AMG preconditioner).** 60–85% of wall time on
   problems above ~100k DOFs. PETSc has first-class CUDA and HIP backends;
   AMGX (NVIDIA) and rocALUTION (AMD) are drop-in options. **Biggest single
   lever.**
2. **Jacobian assembly.** 10–25% of wall time. dolfinx-cuda (still
   experimental as of 2026) handles this via batched cellwise kernels. The
   UFL-to-GPU-kernel path is not yet production-grade; revisit in a year.
3. **Field interpolation + post-processing.** Minor (<5%) but trivially GPU
   with CuPy for things like computing `E = -grad psi` on a dense grid.
4. **Multi-job parallelism.** Less "GPU" and more "throughput": run 100
   parameter-sweep jobs, each on its own small GPU slice. MIG partitions on
   A100/H100 or MPS on older cards. This is actually the most impactful
   pattern for a parameter-exploration GUI.

### What is *not* worth GPU-ifying (yet)

- **Meshing.** Gmsh is not GPU-friendly; time spent here is negligible
  anyway.
- **SNES nonlinear outer loop.** Host-side Python; totally negligible.
- **I/O.** Writing XDMF/BP is CPU-bound and fine that way.
- **Schema validation, JSON parsing, job dispatch.** Obviously host.

### Concrete engineering path

Phase 1 (M15): PETSc built with `--with-cuda` or `--with-hip`, add
`mat_type: aijcusparse` and `vec_type: cuda` as solver options. Use AMGX
(nvidia/AMGX) as the preconditioner via `-pc_type amgx`. Engine exposes a
`solver.backend` field. All assembly stays CPU; matrix and vectors are
moved to device for the Krylov solve.

Phase 2 (post-M15, optional): experiment with dolfinx-cuda for assembly.
Only if Phase 1 profiling shows assembly is now the bottleneck.

Phase 3 (post-M18, throughput): MIG partitioning for parameter sweeps.
Relevant when the UI ships and users run design-of-experiments studies.

### Honest caveat

PETSc-on-GPU is mature for structured problems (Poisson, elliptic). For
coupled drift-diffusion with exponential nonlinearities, the Jacobian
conditioning is terrible and AMG can stall. Expect to spend real time tuning
preconditioner parameters per problem class. A 5× speedup is realistic; a
50× speedup is marketing.

---

## 6. UI integration checklist (what the UI team will ask for)

The engine is ready for a UI when all of these are green:

- [x] M9 complete: runs produce a stable on-disk artifact.
- [x] M10 complete: HTTP API exposes solve, status, stream, artifact fetch.
- [x] M11 complete: schema is versioned, richly annotated, published.
- [x] `GET /materials` returns the material DB.
- [x] `GET /schema` returns the input schema.
- [x] `GET /capabilities` returns which physics models this engine build
      supports (e.g., `{"transient": true, "ac": false, "gpu": true, ...}`).
      (Closed in M15: dynamic backend / device discovery via
      `semi.compute.available_backends` and `device_info`.)
- [ ] WebSocket stream emits at least one message per SNES iteration with
      `{"residual_norm": ..., "iteration": ..., "bias_step": ...}`.
- [ ] CORS configured on the HTTP server for the UI's dev origin.
- [ ] OpenAPI spec auto-generated (FastAPI does this for free).
- [ ] At least one end-to-end integration test where a browser-like client
      submits a JSON and visualizes the result manifest.

---

## 7. What coding agents should do when picking up work here

1. **Read PLAN.md and ROADMAP.md before touching code.** "Current state" and
   "Next task" are the source of truth for what is done.
2. **Pick exactly one milestone.** Do not mix M9 and M10 in a single PR. Do
   not start M11 before M9 is merged.
3. **Write the acceptance test first.** Every milestone above states its
   acceptance test explicitly. Make it fail, then make it pass.
4. **Respect the layer boundaries.** Layer 3 (pure-Python core) never imports
   dolfinx. The new `kronos_server/` package is Layer 6 and never imports
   PETSc or UFL types into its public API.
5. **Do not rewrite the physics kernels.** The UFL forms are correct and
   MMS-verified. If you think you see a bug, write a failing MMS test first;
   90% of the time the "bug" is a scaling-convention confusion that the
   existing tests already cover.
6. **Never skip `make_scaling_from_config`.** The raw equations have a
   Jacobian condition number >1e30. This is not negotiable.
7. **Use `snes_rtol: 1.0e-14` only in tests.** Production defaults are looser
   and documented in `DEFAULT_PETSC_OPTIONS`.

---

## 8. Anti-goals (things to actively *not* do)

- **Do not build a bespoke mesh format.** Use XDMF/ADIOS2-BP and gmsh. They
  work, they're standard, the VTK/ParaView/vtk.js ecosystem reads them for
  free.
- **Do not embed a physics DSL.** The JSON schema is the DSL. If it gets
  inadequate, extend the schema; do not invent a second configuration layer.
- **Do not pickle `SimulationResult`.** It contains live PETSc handles; pickles
  break across processes. Always go through `write_artifact`.
- **Do not add `requests`-based auth to the HTTP server before a real
  deployment need.** Rate limiting and API keys can wait until there is a
  second user.
- **Do not port the whole codebase to Rust or C++ for performance.** The
  bottleneck is the linear solve, not Python. M15 addresses it in the right
  place.
- **Do not claim COMSOL parity.** COMSOL has 30 years of model variations,
  convergence hacks, and user-reported-edge-cases. kronos-semi will have a
  useful, correct subset. Be honest about that in marketing.

---

## 9. Change log for this document

- **2026-04-23**, initial version, written post-M8.
- **2026-04-30**, refresh of §1, §4, §6 to reflect v0.14.x reality
  post-M14.2; introduce §10 shipped-milestone appendix.
- **2026-05-15**, mark §4 M15 Done (v0.15.0); the GPU linear-solver
  path landed with schema 1.4.0 (`solver.backend`, `solver.compute`)
  and manifest 1.1.0 (KSP iters and linear-solve wall time fields).
- **2026-05-22**, M14.3 housekeeping shipped (v0.16.0): §4 M14.3
  marked Done with `[0.16.0]` CHANGELOG anchor; the four production-
  hardening gaps (Pao-Sah mosfet_2d verifier, XDMF mesh ingest,
  strict schema v2.0.0 with `additionalProperties: false`, dead SG
  primitives removed) are closed; coverage gate restored to 95. §6
  UI integration checklist has the dynamic `additionalProperties:
  false` behavior available to UI form-builders so typos surface
  with clear error messages.
- **2026-05-23**, M14.4 residual cleanup (v0.16.1): §1 refreshed to
  v0.16.0 reality post-M14.3 (schema v2.0.0 strict mode added, the
  four engineering gaps marked closed, audit case 06 surfaced as the
  lone remaining production-hardening residual); README rewritten
  without milestone tags or frozen test counts;
  `docs/mos_derivation.md` §6 rewritten in the intrinsic-Fermi
  convention; `.github/workflows/publish-schemas.yml` shipped to make
  the post-M14.3 publish-URL claim true.
- **2026-05-01**, post-M15 roadmap refresh: §1 updated to v0.15.0,
  M14/M14.1/M14.2 status badges grew CHANGELOG anchors, M14.3
  housekeeping milestone added between M14.2 and M15, M16 umbrella
  rewritten and broken into seven sub-milestones M16.1 through M16.7
  each with explicit four-subsection Why / Deliverable / Acceptance /
  Dependencies blocks, M17 rewritten in the same shape, three new
  milestones M19 (3D MOSFET capstone), M19.1 (MPI parallel
  benchmark), and M20 (HTTP server hardening) added with full
  acceptance tests. Two new starter prompts shipped:
  [M14_3_STARTER_PROMPT.md](M14_3_STARTER_PROMPT.md) and
  [M16_1_STARTER_PROMPT.md](M16_1_STARTER_PROMPT.md).

---

## 10. Shipped milestone detail

This appendix preserves the original §4 deliverable, acceptance, and
scope blocks for milestones that have shipped. The §4 entries above
carry only a one-line status badge; full text lives here so that
acceptance criteria remain available as regression references.

### M9 — Result artifact writer + manifest

**Why:** Nothing downstream works without a stable, machine-readable output.
This is the single highest-value piece of work on the list.

**Deliverable:** New module `semi/io/artifact.py` exposing:

```python
def write_artifact(result: SimulationResult, out_dir: Path, run_id: str) -> Path:
    """Write the full result tree under out_dir/run_id/. Returns the run dir."""
```

Plus a new CLI entry point `semi-run <input.json> [--out runs/]` that wraps
`semi.run.run` and calls `write_artifact`.

**Acceptance tests (gate for merge):**

1. For each of the five shipped benchmarks, `semi-run` produces a run dir
   validated against a new JSON-schema file `schemas/manifest.v1.json`.
2. A pure-Python reader `semi.io.artifact.read_manifest(run_dir)` round-trips.
3. A Python-only (no dolfinx) consumer script can read `fields/psi.bp` via
   `adios2` and `iv/cathode.csv` via `numpy.loadtxt` and plot them.
4. New test file `tests/test_artifact.py` with at least 10 assertions.

**Estimated scope:** 2 days. ~400 LOC + schema + tests.

**Dependencies:** none.

---

### M10 — HTTP server: `POST /solve`, `GET /runs/{id}`

**Why:** This is what lets a browser UI talk to the engine.

**Deliverable:** New top-level package `kronos_server/` (kept out of `semi/` to
preserve the pure-engine boundary):

```
kronos_server/
├── __init__.py
├── app.py              # FastAPI app
├── jobs.py             # job queue + worker spawning
├── storage.py          # LocalFS + S3 backends for run dirs
├── models.py           # pydantic models mirroring schemas/
└── routes/
    ├── solve.py        # POST /solve  -> {run_id, status_url}
    ├── runs.py         # GET  /runs/{id}, GET /runs/{id}/manifest
    └── stream.py       # WebSocket /runs/{id}/stream for SNES progress
```

**Endpoints:**

| Method | Path                       | Purpose                                   |
|-------:|----------------------------|-------------------------------------------|
| POST   | `/solve`                   | Submit JSON, get back `{run_id, status}`  |
| GET    | `/runs/{id}`               | Status + manifest                         |
| GET    | `/runs/{id}/fields/{name}` | Stream a field file                       |
| GET    | `/runs/{id}/iv/{contact}`  | Stream CSV                                |
| WS     | `/runs/{id}/stream`        | Live SNES residual norms during solve     |
| GET    | `/materials`               | Material DB dump for UI autocomplete      |
| GET    | `/schema`                  | The JSON schema itself, for UI validation |

**Worker model:** start with a `ProcessPoolExecutor` of size `N_CPU / 4` (each
worker can use 4-way MPI). Redis + Celery is a later upgrade, not a
requirement at first ship.

**Acceptance tests:**

1. End-to-end: `curl -X POST /solve -d @pn_junction.json` then polling
   `/runs/{id}` yields `status: "completed"` in under 30 s.
2. WebSocket client sees at least `n_steps` progress messages during a bias
   sweep.
3. A second client hitting `/runs/{id}/manifest` while the job runs gets
   `status: "running"`, not a 500.
4. Integration test matrix covers all five benchmarks via the HTTP API.

**Estimated scope:** 3 days. ~700 LOC + tests.

**Dependencies:** M9.

---

### M11 — Schema versioning + UI-facing schema companion

**Why:** A UI form-builder needs introspectable, versioned schemas, not just
a validator.

**Deliverable:**

- Add `schema_version` as a required top-level JSON field; validator refuses
  mismatched majors.
- Split `semi/schema.py` into `schemas/input.v1.json` (Draft-07) plus a
  Python loader that imports it. The JSON-file schema is what the UI pulls
  from `GET /schema` and feeds to a form generator (JSONForms, rjsf, etc.).
- Add `title`, `description`, `default`, `examples`, and `enum` annotations
  to every schema node so form-builders render sensible labels and help text
  without a separate UI config.
- Publish the schema on every git tag to a stable URL (a static GitHub Pages
  site is sufficient).

**Acceptance tests:**

1. `jsonschema-cli validate schemas/input.v1.json` against every benchmark
   JSON passes.
2. All existing tests still pass; the schema refactor is a lift-and-shift.
3. New test asserts every node with `type: object` has a `description`.

**Estimated scope:** 1 day.

**Dependencies:** M9 (so the manifest schema and input schema can share a
layout).

---

### M12 — Mesh input beyond axis-aligned boxes

**Why:** Real devices are not boxes. UI will export gmsh `.geo` or `.msh`
files; current engine support is partial.

**Deliverable:**

- Extend `semi/mesh.py::_build_from_file` to cover XDMF (previously
  `NotImplementedError`).
- Add a `geometry` input alternative to `mesh` in the schema:

```json
"geometry": {
  "source": "gmsh_geo",
  "path": "device.geo",
  "characteristic_length": 5.0e-8,
  "physical_groups": {
    "silicon": {"dim": 2, "tag": 1},
    "oxide":   {"dim": 2, "tag": 2},
    "gate":    {"dim": 1, "tag": 10}
  }
}
```

The engine calls gmsh in a subprocess to produce the `.msh`, caches it by
content hash, then loads it.

- Add a 2D MOSFET benchmark (`benchmarks/mosfet_2d/`) that exercises the new
  geometry input: source/drain/gate/body contacts, non-axis-aligned doping.

**Acceptance tests:**

1. `.geo` to `.msh` to solve to IV curve matches SPICE-level analytical
   approximation within 20% at V_DS = 0.1 V.
2. Cache hit avoids re-meshing on identical `(geo_hash, char_length)`.
3. Mesh-convergence test on the MOSFET benchmark.

**Estimated scope:** 3 days.

**Dependencies:** M9, M11.

---

### M13 — Transient solver

**Why:** Every C-V, capacitance-transient-spectroscopy, and realistic device
characterization involves time. Missing transient is the single biggest
physics gap relative to COMSOL.

**Deliverable:**

- `semi/runners/transient.py` implementing backward-Euler and BDF2 time
  stepping on the coupled (psi, phi_n, phi_p) system.
- Schema extension: `"solver": {"type": "transient", "t_end": 1e-9, "dt": 1e-12}`
  plus adaptive time-stepping options mirroring the bias-continuation options.
- Benchmark `benchmarks/pn_1d_turnon/`: forward-bias step response, verify
  charge storage and RC time constant.

**Acceptance tests:**

1. Steady-state limit of the transient solver matches `run_bias_sweep` within
   numerical noise.
2. Turn-on benchmark: minority-carrier lifetime extracted from the transient
   matches the SRH `tau_n` used as input within 5%.
3. BDF2 convergence rate verified against MMS.

**Estimated scope:** 4 days.

**Dependencies:** M9.

**M13.1 follow-up (closed in v0.14.1).** Slotboom primary unknowns
(ADR 0014) replace the M13 (n, p) Galerkin discretisation; both
`test_transient_steady_state_limit` and the BDF rate tests are active
and passing as of v0.14.1; deep-steady-state runner matches
`bias_sweep` within 1e-4 relative error and `pn_1d_turnon` within 5%.

---

### M14 — AC small-signal analysis

**Why:** Capacitance-voltage, admittance-spectroscopy, and high-frequency
characterization all need AC. The math reuses the transient Jacobian.

**Deliverable:**

- `semi/runners/ac_sweep.py`: at each DC operating point, assemble
  `(J + jωM)` and solve the linearised system for the AC response. The
  PETSc-real build forces a real 2x2 block reformulation
  (`[[J, -ωM], [ωM, J]] [[Re δu], [Im δu]] = [[Re b], [Im b]]`); ADR
  0011 documents the decision and lists complex PETSc as deferred
  M16+ work.
- Terminal admittance includes the displacement current at the
  contact in addition to the linearised conduction current.
- MOS C-V benchmark upgraded to compute true C(V) via AC admittance
  (M14.1 follow-up: `mos_cap_ac` returns dQ/dV directly from
  `Im(Y) / (2πf)`).

**Acceptance tests:**

1. Low-frequency limit of AC capacitance matches `dQ/dV` from the existing
   MOS benchmark within 2%.
2. Frequency sweep produces the expected MOS C-V frequency dispersion for
   interface-trap models (flat until traps are added).
3. `rc_ac_sweep` benchmark matches analytical depletion C within 0.4%
   over [1 Hz, 1 MHz].

**Estimated scope:** 4 days.

**Dependencies:** M9, M13 (for the mass matrix infrastructure).

**M14 sign-convention errata (2026-04-28).** Resolved Phase 1 audit
Cases 02 and 05. `run_ac_sweep` now reports terminal current INTO the
device (matching `bias_sweep` and
`semi/postprocess.evaluate_current_at_contact`); `result.C =
+Im(Y) / (2πf)` is bit-identical to the pre-fix value, and ADR 0011
gained an Errata section formalising the convention. Audit Cases 02
and 05 assertions tightened from NaN-guards to sign-equality plus
1% / 5% relative-error gates.
