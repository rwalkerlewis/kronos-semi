# MOS Derivation: 2D MOS Capacitor (Day 6 Gate)

This document is the mathematical specification for the Day-6 2D MOS
capacitor benchmark, gate contact wiring, multi-region Poisson
assembly, and C-V verification. It is a gate artifact in the same
sense as `docs/mms_dd_derivation.md` for Day 4: no implementation code
is written until this document is reviewed and approved.

The scope is:

1. Device geometry and box-tagged regions for `regions_by_box`.
2. Per-region governing equations (full drift-diffusion in silicon,
   Poisson-only in SiO2, no continuity in the oxide).
3. The Si/SiO2 interface conditions and what is natural vs. imposed.
4. The submesh formulation: V_psi on the full mesh, V_phi_n and
   V_phi_p restricted to the semiconductor submesh via
   `dolfinx.mesh.create_submesh` and `entity_maps`.
5. Gate contact BC in scaled units, with and without a work-function
   mismatch.
6. MOS C-V theory in the depletion regime, with the derivation of
   V_FB, V_T, psi_s(V_gate), and C(V_gate), and the rationale for the
   10 percent verifier tolerance.
7. Multi-region Poisson MMS: an exact psi with eps-weighted flux
   continuity at the interface, per-region forcing derived from a
   cellwise eps_r, and the finest-pair rate targets.

Scaled symbols follow Day-2 and Day-4 conventions:

```
psi_hat   = psi   / V_t      (electrostatic potential)
phi_n_hat = phi_n / V_t      (electron quasi-Fermi potential)
phi_p_hat = phi_p / V_t      (hole quasi-Fermi potential)
N_hat     = N_net / C_0      (net doping)
n_hat     = n     / C_0
p_hat     = p     / C_0
ni_hat    = n_i   / C_0
```

with thermal voltage `V_t = k_B T / q`, reference density `C_0` (set
from peak doping, floored at 1e22 m^-3 per `semi/scaling.py`), and
reference length `L_0`. The scaled Debye length squared satisfies
`L_D^2 = eps_0 V_t / (q C_0) = lambda2 * L_0^2`. Mesh coordinates stay
in meters (Invariant 3 in `PLAN.md`). `eps_r(x)` becomes a cellwise
function on the full mesh; the scalar `eps_r` in the existing
`semi/physics/poisson.py` generalises to that function.

---

## 1. Device geometry and regions

The 2D MOS capacitor occupies the rectangle

```
Omega = [0, W] x [0, y_top]

W       = 500 nm          lateral extent
t_Si    = 500 nm          silicon substrate thickness
t_ox    =   5 nm          oxide thickness
y_int   = t_Si            interface height
y_top   = t_Si + t_ox     gate-side top
```

Two regions:

```
Omega_Si  = [0, W] x [0,     y_int]     tag 1, role "semiconductor"
Omega_ox  = [0, W] x [y_int, y_top]     tag 2, role "insulator"
```

Four facet boundaries:

```
body facet  = { (x, 0)          : 0 <= x <= W }   ohmic, grounded
gate facet  = { (x, y_top)      : 0 <= x <= W }   Dirichlet psi = (V_gate - phi_ms)/V_t
left side   = { (0, y)          : 0 <= y <= y_top } natural (Neumann)
right side  = { (W, y)          : 0 <= y <= y_top } natural (Neumann)
```

JSON structure for the mesh block (informative preview; the exact
schema-compliant shape lands in `benchmarks/mos_2d/mos_cap.json`):

```json
"mesh": {
  "source": "builtin",
  "kind": "rectangle",
  "extents": [[0.0, 500.0e-9], [0.0, 505.0e-9]],
  "resolution": [64, 72],
  "regions_by_box": [
    {"name": "silicon", "tag": 1, "bounds": [[0.0, 500.0e-9], [0.0,     500.0e-9]]},
    {"name": "oxide",   "tag": 2, "bounds": [[0.0, 500.0e-9], [500.0e-9, 505.0e-9]]}
  ],
  "facets_by_plane": [
    {"name": "body", "tag": 1, "axis": 1, "value": 0.0},
    {"name": "gate", "tag": 2, "axis": 1, "value": 505.0e-9}
  ]
}
```

And:

```json
"regions": {
  "silicon": {"material": "Si",   "tag": 1, "role": "semiconductor"},
  "oxide":   {"material": "SiO2", "tag": 2, "role": "insulator"}
}
```

Doping is uniform `N_A = 1e17 cm^-3 = 1e23 m^-3` in silicon; the oxide
carries no doping field. Contacts:

```json
"contacts": [
  {"name": "body", "facet": "body", "type": "ohmic", "voltage": 0.0},
  {"name": "gate", "facet": "gate", "type": "gate",  "voltage": 0.0, "workfunction": 0.0}
]
```

The `workfunction` JSON key already exists in the schema. Its semantic
content at a gate contact is `phi_ms` (Section 5). For ideal-gate
runs (Day 6 baseline) it is 0 V.

The resolution `[64, 72]` is illustrative. Vertical spacing must
resolve the 5 nm oxide with at least 5 cells; the practical choice is
a graded mesh (fine in the oxide, coarser in the bulk). The benchmark
config may use a non-uniform rectangle or a Gmsh-loaded geometry in
a later iteration; for Day 6 the builtin rectangle generator with a
dense vertical resolution is sufficient.

---

## 2. Equations by region

### 2.1 Semiconductor region (Omega_Si)

The full Poisson-coupled drift-diffusion system from
`docs/PHYSICS.md` Section 2.5, in scaled Slotboom form:

```
-div( L_D^2 eps_r_Si grad psi_hat )            - (p_hat - n_hat + N_hat) = 0
-div( L_0^2 mu_n_hat n_hat grad phi_n_hat )    - R_hat                   = 0
-div( L_0^2 mu_p_hat p_hat grad phi_p_hat )    + R_hat                   = 0
```

with Slotboom recovery

```
n_hat = ni_hat * exp( psi_hat   - phi_n_hat )
p_hat = ni_hat * exp( phi_p_hat - psi_hat   )
```

and SRH (used as a verification hook; Day-6 equilibrium and small-bias
C-V sweeps sit near equilibrium where R_hat is small). Materials: Si
with `eps_r_Si = 11.7` and `n_i(Si, 300K) = 1.0e10 cm^-3`.

### 2.2 Oxide region (Omega_ox)

The oxide is a perfect insulator. It carries only Poisson:

```
-div( L_D^2 eps_r_ox grad psi_hat ) = 0
```

with `eps_r_ox = 3.9` (SiO2). There is no free charge (no doping, no
mobile carriers), no continuity equation, no quasi-Fermi potential.

**Why continuity equations must not be assembled in the oxide.** The
Slotboom variables `phi_n` and `phi_p` are defined via
`n = n_i exp(psi - phi_n)/V_t` and the symmetric relation for p. In
the oxide, both n and p are (by definition of an ideal insulator)
identically zero or, more precisely, many orders of magnitude below
any physically meaningful scale. Forcing the Slotboom form in the
oxide would require n_i_ox -> 0 (an undefined logarithm under the
inversion), mu_n_ox -> 0 (collapsing the continuity diffusion
coefficient so the block becomes singular), and the current J_n/J_p
is identically zero so the residual carries no information. There is
also no transport parameter tau for SRH in the oxide. In short, the
continuity equations are ill-posed in Omega_ox: we simply do not
solve them there. This is why the submesh formulation in Section 4 is
the correct structural choice, not a convenience.

### 2.3 Scaled Poisson LHS coefficient as a cellwise function

On the full mesh, the Poisson LHS coefficient becomes

```
L_D^2 * eps_r(x) = lambda2 * L_0^2 * eps_r(x)
```

where `lambda2 = eps_0 V_t / (q C_0 L_0^2)` is scalar (it depends only
on scaling reference values, not on position), and `eps_r(x)` is a
DG0 cellwise function with values

```
eps_r(x) = eps_r_Si   if cell lies in Omega_Si
           eps_r_ox   if cell lies in Omega_ox
```

This is the minimum structural change to `semi/physics/poisson.py`:
today `eps_r` is a `fem.Constant` (see line 63 of `poisson.py`); Day-6
replaces it with a Function interpolated from the region tag map. The
single-region path (all cells have the same role) is preserved as a
scalar fast path so the 1D benchmarks do not regress.

---

## 3. Interface conditions at the Si/SiO2 boundary

Let `Gamma = { (x, y_int) : 0 <= x <= W }` denote the Si/SiO2
interface with unit normal `n` pointing from Omega_Si into Omega_ox.

### 3.1 Conditions on psi (both natural in the weak form)

1. **Continuity of psi.** `psi_hat` is a single scalar in H^1(Omega).
   Continuity is enforced simply by using a single V_psi space over
   the full mesh: conforming P1 elements are in H^1, so continuity
   across the interface is structural, not imposed.

2. **Continuity of normal D = eps_0 eps_r grad psi.** Writing the
   weak form of Poisson over the full Omega with a piecewise
   eps_r(x),

   ```
   sum_{k in {Si, ox}} integral_{Omega_k} L_D^2 eps_r_k grad psi . grad v dx
       = integral_{Omega} f v dx     (plus Dirichlet lifting)
   ```

   integration by parts in each region yields boundary terms on
   Gamma that combine to `[eps_r grad psi . n] * v ds`. The weak
   form gives a valid solution iff this jump is zero (when there is
   no interface charge), i.e. eps_r_Si grad psi_Si . n =
   eps_r_ox grad psi_ox . n. This is a natural condition: the
   discrete system enforces it automatically when eps_r is supplied
   as a cellwise function in the bilinear form. No surface integral
   needs to be added by hand.

### 3.2 Condition on the Slotboom variables

phi_n and phi_p exist only on the semiconductor submesh. There is no
oxide-side counterpart, so "continuity across Gamma" is not a
meaningful statement. The relevant condition is

```
J_n . n = 0   and   J_p . n = 0   on Gamma
```

that is, no carrier flux crosses into the oxide. In the scaled
continuity equation

```
-div( L_0^2 mu_n_hat n_hat grad phi_n_hat ) - R_hat = 0
```

the natural (Neumann) boundary condition in the weak form is
`L_0^2 mu_n_hat n_hat grad phi_n_hat . n = 0`, which is exactly
`J_n . n = 0` up to sign. Because phi_n lives on the submesh and the
submesh's exterior boundary consists of body facets (where Dirichlet
is applied) plus the Si/SiO2 interface (where no Dirichlet is
applied), the discretization gives J_n . n = 0 on Gamma for free.
This is the second reason the submesh formulation is the right
structural choice: the interface condition is a do-nothing on the
submesh exterior.

### 3.3 Contact and interface charge

Day 6 assumes zero fixed oxide charge Q_ox and zero interface trap
density D_it. The flatband voltage derivation in Section 6 reflects
this (V_FB = phi_ms, no Q_ox / C_ox term). Adding Q_ox or D_it is a
future extension that requires an interface facet integral in the
Poisson weak form. It is out of scope here.

---

## 4. Submesh formulation

### 4.1 Function spaces

Let `msh` be the full 2D mesh with cell tags `cell_tags` from
`regions_by_box`. Let `msh_Si` be the semiconductor submesh,
constructed via

```python
from dolfinx.mesh import create_submesh
semi_cells = cell_tags.find(semi_tag)        # indices of cells with role "semiconductor"
msh_Si, entity_map, vertex_map, geom_map = create_submesh(msh, tdim, semi_cells)
```

Function spaces:

```
V_psi   = FunctionSpace(msh,    ("Lagrange", 1))     # full mesh, one DOF per node
V_phi_n = FunctionSpace(msh_Si, ("Lagrange", 1))     # semi submesh only
V_phi_p = FunctionSpace(msh_Si, ("Lagrange", 1))     # semi submesh only
```

The block residual `(F_psi, F_phi_n, F_phi_p)` has:

- `F_psi` defined over the full mesh, using `eps_r(x)` cellwise and
  reading `n_hat`, `p_hat` from phi_n, phi_p on the submesh (see
  Section 4.3 for the coupling).
- `F_phi_n`, `F_phi_p` defined only over the submesh.

### 4.2 Boundary conditions on the submesh

Dirichlet conditions for phi_n, phi_p are applied only on ohmic
contact facets that lie on the submesh boundary. In the Day-6 device
this is exclusively the body facet at y = 0. The Si/SiO2 interface
`Gamma` is on the submesh exterior but carries no Dirichlet, so the
natural `J . n = 0` condition applies (Section 3.2).

### 4.3 Cross-region coupling in the Poisson residual

The Poisson residual over Omega is

```
F_psi(v) = integral_Omega L_D^2 eps_r(x) grad psi_hat . grad v dx
         - integral_{Omega_Si} (p_hat - n_hat + N_hat) v dx
```

where the space-charge integrand lives only in Omega_Si. The n_hat
and p_hat terms are functions of (psi_hat, phi_n_hat, phi_p_hat) via
the Slotboom relations. Because psi lives on the full mesh but phi_n,
phi_p live on the submesh, the UFL form for this integrand requires
dolfinx 0.10's `entity_maps` parameter:

```python
form = fem.form(F_psi_ufl, entity_maps={msh_Si: entity_map})
```

For the continuity blocks, everything lives on the submesh, so no
entity_map is needed except for reading psi_hat onto the submesh.
There too, `entity_maps` is needed because `psi_hat` is a Function on
the full mesh and the continuity residual evaluates it at submesh
cells.

The required dolfinx 0.10 plumbing is:

```python
F_phi_n_form = fem.form(F_phi_n_ufl, entity_maps={msh: inv_entity_map})
F_phi_p_form = fem.form(F_phi_p_ufl, entity_maps={msh: inv_entity_map})
```

where `inv_entity_map` is the submesh-to-parent lookup derived from
`entity_map` (submesh cell i <-> parent cell `entity_map[i]`).

### 4.4 Single-region fast path

When every cell in the full mesh carries `role = "semiconductor"`
(the 1D `pn_1d`, `pn_1d_bias`, `pn_1d_bias_reverse` benchmarks), the
submesh equals the full mesh modulo index maps. The Poisson LHS
coefficient reduces to a scalar Constant, entity_maps are trivial
identity, and the assembly is identical to the Day 2-5 single-region
path. `semi/physics/poisson.py` detects this condition and uses the
scalar path. This is what keeps the 1D benchmarks byte-identical
through Day 6, which is the top stop-and-report trigger.

---

## 5. Gate boundary condition

### 5.1 Physical statement

The gate is an ideal metal electrode on the oxide side of the
interface. Its potential is clamped to the applied V_gate, modulated
by the metal-semiconductor work function difference phi_ms:

```
psi(gate) = V_gate - phi_ms
```

where

```
phi_ms = phi_m - ( chi_s + E_g/2 - phi_F_bulk )
```

and `phi_F_bulk = V_t * ln(N_A / n_i)` for a p-type substrate (sign
flipped for n-type). For an "ideal gate" (phi_m set equal to the
silicon mid-gap plus phi_F correction, giving zero flatband offset),
`phi_ms = 0` and `V_FB = 0`. This is the Day-6 baseline. A non-zero
phi_ms is read from the `workfunction` JSON key on the contact;
ContactBC already has the `work_function` field (see
`semi/bcs.py:37-48`), so no schema extension is needed.

### 5.2 Scaled form

In scaled units the Dirichlet condition is

```
psi_hat(gate) = ( V_gate - phi_ms ) / V_t = V_applied_hat - phi_ms_hat
```

where `V_applied = V_gate` comes from the contact config (or a bias
sweep override via `voltages=` in `resolve_contacts`) and
`phi_ms_hat = phi_ms / V_t`.

### 5.3 What changes in semi/bcs.py

`_VALID_DIRICHLET_KINDS` already contains `"gate"` (see
`semi/bcs.py:34`). Both build functions today skip every contact with
`c.kind != "ohmic"` (`semi/bcs.py:173` and `:216`). Day 6 adds a gate
branch in `build_psi_dirichlet_bcs`:

```
for c in contacts:
    if c.kind == "ohmic":
        # existing path, unchanged
        ...
    elif c.kind == "gate":
        phi_ms = c.work_function or 0.0
        psi_bc_hat = (c.V_applied - phi_ms) / sc.V0
        dofs = fem.locate_dofs_topological(V_psi, fdim, facets)
        bcs.append(fem.dirichletbc(PETSc.ScalarType(psi_bc_hat), dofs, V_psi))
    # schottky handled later
```

`build_dd_dirichlet_bcs` keeps skipping gate contacts explicitly:
the gate facet sits outside the semiconductor submesh, so even if
we asked, `fem.locate_dofs_topological` would find no submesh DOFs
there. An explicit comment documents why (gate is on the oxide side
of the interface; no Slotboom variable exists there).

### 5.4 No phi_n / phi_p at the gate

There is no quasi-Fermi variable on the oxide side. The gate facet
contributes only a psi Dirichlet BC; phi_n and phi_p at the Si/SiO2
interface are determined by the interior PDE plus the
`J_n . n = J_p . n = 0` natural conditions from Section 3.2.

---

## 6. MOS theory for the C-V verifier

The verifier compares the simulated capacitance, extracted as
dQ_gate/dV_gate by finite-differencing the integrated space charge
across a gate-voltage sweep, against the depletion-approximation
analytical C-V curve. Only the depletion regime is checked; the
tolerance is 10 percent.

### 6.1 Flatband voltage

With zero oxide charge and zero interface trap density, the flatband
voltage is

```
V_FB = phi_ms
```

For the Day-6 ideal-gate baseline, V_FB = 0.

### 6.2 Surface potential and Fermi potential

Let psi_s = psi(x, y_int) - psi(x, y_bulk) be the surface potential
relative to the bulk (defined for the 1D cross-section; in 2D the
MOS capacitor is translation-invariant away from x = 0 and x = W, so
psi is effectively a function of y alone in the interior). The bulk
Fermi potential for p-type substrate is

```
phi_F = V_t * ln( N_A / n_i )
```

At N_A = 1e17 cm^-3, T = 300 K, n_i(Si) = 1e10 cm^-3:

```
phi_F = 0.02585 * ln(1e7) = 0.02585 * 16.118 = 0.417 V
```

### 6.3 Depletion width and charge

Under the depletion approximation (mobile carriers fully depleted in
a layer of width W_dep beneath the oxide; fixed acceptor charge
-q N_A uniformly),

```
W_dep(psi_s) = sqrt( 2 eps_s psi_s / (q N_A) )
Q_dep(psi_s) = -q N_A W_dep(psi_s) = -sqrt( 2 eps_s q N_A psi_s )
```

valid for `0 < psi_s < 2 phi_F` (onset of strong inversion).

### 6.4 Oxide capacitance

```
C_ox = eps_0 eps_r_ox / t_ox
```

At eps_r_ox = 3.9, t_ox = 5 nm:

```
C_ox = 8.854e-12 * 3.9 / 5e-9 = 6.906e-3 F/m^2 = 0.691 uF/cm^2
```

### 6.5 Depletion capacitance

```
C_dep(psi_s) = eps_s / W_dep(psi_s) = sqrt( eps_s q N_A / (2 psi_s) )
```

with eps_s = eps_0 eps_r_Si.

### 6.6 Total capacitance

The oxide and depletion capacitances are in series:

```
C(V_gate) = C_ox C_dep(psi_s) / ( C_ox + C_dep(psi_s) )
```

with psi_s determined from the gate voltage via the control equation

```
V_gate - V_FB = psi_s + sqrt( 2 eps_s q N_A psi_s ) / C_ox
```

which is solved numerically for psi_s at each V_gate (monotonic in
psi_s, so one-dimensional root-finding converges quickly).

### 6.7 Threshold voltage

Strong inversion begins at psi_s = 2 phi_F:

```
V_T = V_FB + 2 phi_F + sqrt( 4 eps_s q N_A phi_F ) / C_ox
```

Numerical check for the Day-6 device (V_FB = 0, phi_F = 0.417 V,
eps_s = 11.7 eps_0, N_A = 1e23 m^-3, C_ox = 6.906e-3 F/m^2):

```
sqrt_arg = 4 * 11.7 * 8.854e-12 * 1.602e-19 * 1e23 * 0.417
        ~= 2.77e-6   [C^2 / m^4]
sqrt(sqrt_arg) = 1.66e-3 C/m^2
/ C_ox = 1.66e-3 / 6.906e-3 = 0.241 V
V_T = 0 + 0.835 + 0.241 = 1.08 V
```

The bias sweep covers `V_gate in [V_FB - 0.5, V_T + 0.5] = [-0.5, 1.58] V`.
The verifier window is `V_gate in [V_FB + 0.1, V_T - 0.1] = [0.1, 0.98] V`;
endpoints nudged in by 0.1 V to keep a clean depletion-regime
comparison (the flatband neighbourhood sees mobile-carrier
contributions to C that the depletion approximation misses, and the
threshold neighbourhood sees inversion-layer formation).

### 6.8 Simulated capacitance extraction

For each bias point `V_gate_i` in the sweep the simulator produces
scaled fields (psi_hat, phi_n_hat, phi_p_hat) on their respective
spaces. The gate charge is extracted by integrating the semiconductor
space charge beneath the gate:

```
Q_gate(V_gate_i) = -integral_{Omega_Si} q * ( p - n + N_D - N_A ) dx
                 = -q C_0 integral_{Omega_Si} ( p_hat - n_hat + N_hat ) dx_scaled
```

(sign convention: positive Q_gate corresponds to positive gate
charge, balanced by negative semiconductor charge.) The simulated
capacitance per unit area is

```
C_sim(V_gate_i) = ( Q_gate(V_gate_{i+1}) - Q_gate(V_gate_{i-1}) )
                  / ( ( V_gate_{i+1} - V_gate_{i-1} ) * W )
```

centered finite difference, divided by the lateral extent W to reduce
to per-area units that match C_theory.

### 6.9 Error metric and tolerance

```
err(V_gate_i) = | C_sim(V_gate_i) - C_theory(V_gate_i) | / C_theory(V_gate_i)
verifier passes iff max_{V in [V_FB+0.1, V_T-0.1]} err(V) < 0.10
```

**Why 10 percent and not tighter.**

1. **Depletion approximation error.** The exact Poisson solution in
   the silicon has a carrier tail that extends past the sharp
   depletion edge assumed by W_dep. At psi_s comparable to phi_F
   this adds ~3-5 percent to the total charge for N_A = 1e17.
2. **Slotboom-form tail near the depletion edge.** The Slotboom
   variables resolve n and p smoothly across the depletion edge,
   which differs from the depletion approximation's step-function
   charge profile by a few percent integrated over W_dep.
3. **Finite-difference extraction.** dQ/dV computed on a discrete
   bias sweep is a first-order approximation unless step sizes are
   made very small (which then amplifies solver noise).

10 percent is generous enough that a correctly-implemented simulator
passes on the first try and tight enough to catch a wrong flatband,
wrong C_ox, or wrong eps_r assignment per region. If the simulator
overshoots the tolerance, the debugging action is to shrink the
verifier window (push farther from accumulation and inversion) or to
examine dQ/dV noise, not to loosen the tolerance (anti-pattern).

### 6.10 Regimes explicitly excluded

**Accumulation** (V_gate < V_FB): holes pile up at the interface,
forming a surface charge layer that the depletion approximation does
not model. C -> C_ox, but the approach to that limit requires
solving the full Slotboom system near the interface with a
well-resolved carrier profile. The verifier's window starts above
V_FB by 0.1 V.

**Strong inversion** (V_gate > V_T): minority carrier (electron)
inversion layer forms at the oxide-silicon interface. The small-
signal low-frequency C-V curve approaches C_ox again, but this
requires minority-carrier generation at the steady-state equilibrium
rate, and the quasi-static assumption behind the depletion-
approximation C-V breaks down without a transient solver. The
verifier's window ends below V_T by 0.1 V.

The C-V verifier code includes a top-of-file comment citing this
subsection and the two excluded regimes.

---

## 7. MMS for multi-region Poisson

This is the unit-level guard on the multi-region assembly. Without
it, a silent degradation to O(h) at the interface (from a
coefficient-jump assembly bug) would surface only as a 5-15 percent
C-V error, easy to misattribute. The MMS rate cannot be fooled: it
is either 2.0 in L^2 or it is not.

### 7.1 Geometry

Same two-region rectangle as Section 1, with eps_r_Si = 11.7 and
eps_r_ox = 3.9. The implementation builds this from a minimal box-
tagged mesh (not the full Day-6 device), with parameters:

```
W     = 1.0e-7 m        square-ish domain
t_Si  = 0.7e-7 m
t_ox  = 0.3e-7 m        thicker-than-device oxide to keep the
                        convergence study on a reasonable aspect ratio
y_int = t_Si
y_top = t_Si + t_ox
```

The oxide is inflated to 30 nm so a uniform mesh on a 1e-7 m x 1e-7 m
square resolves both regions without needing a graded mesh; MMS just
needs the coefficient jump, not device-realistic thickness.

### 7.2 Exact psi with eps-weighted flux continuity

Let `psi_exact(x, y) = sin(pi x / W) * h(y)` where `h(y)` is piecewise
polynomial, chosen so that

```
psi_exact is C^0 across y = y_int
eps_r_Si * d psi_exact/d y |_{y_int^-} = eps_r_ox * d psi_exact/d y |_{y_int^+}
```

Concretely:

```
h_Si(y) = A * (y / t_Si)^2                                              for y in [0, y_int]
h_ox(y) = A + A * B_ox * (y - y_int) + gamma_ox * (y - y_int)^2         for y in [y_int, y_top]
```

where

```
A        = 1                                                            (amplitude)
B_ox     = 2 * eps_r_Si / (eps_r_ox * t_Si)                             (flux-continuity)
gamma_ox = ( h_top - A * ( 1 + B_ox * t_ox ) ) / t_ox^2                 (hits chosen h(y_top) = h_top)
h_top    = 0.5                                                          (gate-side Dirichlet)
```

Verifications at the interface:

```
h_Si(y_int)  = A                                                         = 1
h_ox(y_int)  = A + 0 + 0                                                 = 1                [continuity]
h_Si'(y_int) = 2 A / t_Si
h_ox'(y_int) = A * B_ox = 2 A eps_r_Si / (eps_r_ox * t_Si)
eps_r_Si * h_Si'(y_int) = 2 A eps_r_Si / t_Si                            [eps-weighted, Si side]
eps_r_ox * h_ox'(y_int) = eps_r_ox * 2 A eps_r_Si / (eps_r_ox * t_Si)
                        = 2 A eps_r_Si / t_Si                            [eps-weighted, ox side; matches]
```

So `eps_r grad psi . n` is continuous across the interface, and the
exact psi is a valid weak solution of the multi-region Poisson
problem with no interface delta source.

Boundary values (all Dirichlet, lifted from psi_exact directly):

```
psi_exact(0, y)     = 0                                                 (left edge; sin(0) = 0)
psi_exact(W, y)     = 0                                                 (right edge; sin(pi) = 0)
psi_exact(x, 0)     = 0                                                 (body; h_Si(0) = 0)
psi_exact(x, y_top) = h_top * sin(pi x / W)                             (gate-side)
```

### 7.3 Per-region forcing

The forcing in each region is derived from

```
f_k(x, y) = -div( eps_r_k grad psi_exact(x, y) )    for k in {Si, ox}
```

Because psi_exact has the tensor form `sin(pi x / W) * h(y)`,

```
d^2 psi_exact / d x^2 = -(pi/W)^2 * sin(pi x/W) * h(y)
d^2 psi_exact / d y^2 = sin(pi x/W) * h''(y)
```

and therefore

```
f_Si(x, y) = -eps_r_Si * sin(pi x/W) * ( -(pi/W)^2 * h_Si(y) + h_Si''(y) )
          = eps_r_Si * sin(pi x/W) * ( (pi/W)^2 * h_Si(y) - h_Si''(y) )
          = eps_r_Si * sin(pi x/W) * ( (pi/W)^2 * A (y/t_Si)^2 - 2 A / t_Si^2 )

f_ox(x, y) = eps_r_ox * sin(pi x/W) * ( (pi/W)^2 * h_ox(y) - h_ox''(y) )
          = eps_r_ox * sin(pi x/W) * ( (pi/W)^2 * (A + A B_ox (y - y_int) + gamma_ox (y - y_int)^2)
                                       - 2 gamma_ox )
```

These are smooth within each region; the only discontinuity is in f
itself, at y = y_int, which is the expected behaviour for a problem
with a coefficient jump. UFL handles this natively: the cellwise
forcing is supplied via a DG0 or piecewise-defined expression keyed
off the region tag, evaluated at quadrature points.

Scaled vs. raw: the MMS runs in pure scalar Poisson form (no
Slotboom, no doping term, no psi -> density coupling) to isolate the
coefficient-jump assembly. The scaling factor `L_D^2` is just a
positive scalar that multiplies both sides and drops out of the
residual construction.

### 7.4 Grid sweep

Uniform structured mesh on the square, four levels:

```
N in [16, 32, 64, 128]    # cells per direction
h = 1/N * max(W, y_top)
```

All four levels respect the interface (y_int is a grid line) by
choosing N with a factor such that `y_int` falls on a mesh node.
For the dimensions in Section 7.1 with t_Si = 0.7e-7, y_top = 1.0e-7,
we need N divisible by 10 in the y direction, or we use a rectangle
generator that explicitly inserts y_int as a grid node. The Day-6
implementation uses the existing `regions_by_box` path, which produces
a structured rectangle with box-aligned tag boundaries.

### 7.5 Thresholds

Expected rates (finest-pair):

```
rate_L2 = 2.00
rate_H1 = 1.00
```

Gate thresholds (same style as `semi/verification/mms_poisson.py`
single-region case):

```
rate_L2 >= 1.75
rate_H1 >= 0.80
```

The stricter 1.99 self-convergence threshold is reserved for the Day-6
acceptance criterion (item 10 in the Day-6 spec); the code-gate
threshold is the looser 1.75 so small amplitude or rounding
variations do not block CI unnecessarily.

### 7.6 CLI wiring

A new study name `mms_poisson_2d_multiregion` is added to
`scripts/run_verification.py`, exposed under `mms_poisson` and under
`all`. The pytest harness adds one test:

```
tests/fem/test_mms_poisson.py::test_mms_poisson_2d_multiregion
```

It asserts `rate_L2 >= 1.75` and `rate_H1 >= 0.80`, matching the
existing Poisson MMS pattern (see
`tests/fem/test_mms_poisson.py::test_mms_poisson_2d_convergence`).

---

## 8. Summary of deliverables implied by this derivation

For reference against the Day-6 prompt spec:

1. `docs/mos_derivation.md` (this file).
2. `semi/mesh.py`: `build_submesh_by_role` via
   `dolfinx.mesh.create_submesh`; DG0 cellwise `eps_r` Function.
3. `semi/bcs.py`: gate branch in `build_psi_dirichlet_bcs` using
   `c.work_function or 0.0` as `phi_ms`; `build_dd_dirichlet_bcs`
   keeps skipping gate contacts.
4. `semi/physics/poisson.py`: cellwise `eps_r` with a scalar fast
   path for single-region meshes.
5. `semi/physics/drift_diffusion.py`: submesh-scoped V_phi_n,
   V_phi_p with `entity_maps` plumbing.
6. `benchmarks/mos_2d/mos_cap.json`: device spec matching Section 1.
7. `scripts/run_benchmark.py`: 2D contour plotting path.
8. C-V verifier matching Section 6 with the 10 percent tolerance and
   the accumulation / inversion exclusions documented in code.
9. `semi/verification/mms_poisson.py`:
   `mms_poisson_2d_multiregion` per Section 7.
10. `docs/PHYSICS.md` Section 6: condensed MOS physics reference
    (cross-linked to this derivation).
11. `CHANGELOG.md`, `docs/ROADMAP.md`, `PLAN.md` updated on Day-6
    completion.
12. Optional ADR 0008 if the submesh approach warrants a design
    record beyond the dolfinx-mechanical `create_submesh` call.
