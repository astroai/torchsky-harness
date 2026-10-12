# Torchsky Execution Roadmap

## SMACS evidence-first reconstruction plan — 2026-09-24

**End goal:** beat the frozen classical/Drizzle reference in depth at matched
false-positive density while preserving the same or better independently
measured effective resolution. “Prettier” is accepted only with faithful flux,
color, morphology, diffuse-light and uncertainty recovery. No new science result
is accepted merely because software tests pass. Current evidence and exact run
identities are in
[active.md](active.md#evidence-first-implementation-update--2026-09-24).

### 1. Recover evidence and establish the reference before further tuning

- [ ] Recover reports, logs, configurations, checkpoints and products for both
  precision experiments. The patch run completed; the full-image run timed out.
  Inspect its last completed step and saved state before restarting anything.
- [x] Inventory local recovered products and create a fixed-scale contact sheet.
  The July 29 six-band product is the strongest visual candidate, but its metadata
  aliases baseline and method to the same FITS file and provides no metrics.
- [x] Identify the archived candidate as
  `20260729-smacs-torchsky-drizzle-aa0aa21`; local provenance records ARC URIs
  and SHA-256 checksums for every SCI/WHT band.
- [ ] Confirm this is the user's intended earlier good reconstruction. Compare it
  with current outputs on the same sky
  footprint, masks, WCS, units and fixed stretch. If it cannot be identified,
  ask which product the user means; do not substitute an arbitrary weak run.
- [ ] Freeze independent F150W/F277W grids and the strongest existing classical
  reconstruction as current references. Recover existing official comparator
  products; do not rebuild SWarp/Montage/Drizzle. Verify input/code identities.
- [ ] Create one compact results table with per-band/per-exposure likelihood,
  reference-image contrast, injection-based flux/color errors, effective PSF,
  diffuse recovery, runtime and memory. Missing measurements stay missing.
  Preserve failed/time-limited runs and configuration differences in the table.

**Acceptance:** replay of a saved model reproduces its recorded predictions
and metrics within a declared numerical tolerance; every comparison identifies
whether it shares data, response, initialization, parameter budget and compute.
The precision correction is retained for correctness, but its current real-data
result is classified as no demonstrated improvement.

### 2. Establish a trustworthy observation model independently of architecture

- [ ] Run matched point, extended, blended and diffuse synthetic scenes through
  an independently generated forward model. Include known exposure-dependent
  offsets/planes, PSF widths/wings/centroids, photometric scales and small WCS
  shifts. Test exact calibration, deliberately wrong calibration, and recovered
  calibration separately; do not fit all nuisance terms freely with the scene.
- [ ] Check calibrated MJy/sr, variance scaling, pixel areas, flux conservation,
  measured passband integration with the reference-spectrum convention, and
  exactly-once pixel response. Check forward/adjoint and tiled/full predictions
  and gradients. Re-run the new fine-coordinate tests on CUDA; archive results.
- [ ] Validate PSFs on independent stars across detector position and exposures;
  report centroid, width, wings and encircled energy. Audit whether registered
  inputs already include resampling/pixel response. Distinguish nominal Gaussian
  controls from calibrated effective PSFs in plots and metadata.
- [ ] Validate background planes in full detector coordinates with independent
  calibration samples, including transfer into multiple cutouts. Keep relative
  offsets at weighted zero mean. Test extended-light attenuation explicitly;
  retain celestial diffuse emission in the scene and state the unresolved
  absolute foreground. Optical foregrounds and detector backgrounds retain
  their distinct response paths.
- [ ] Estimate relative throughput corrections only with independent evidence
  and a fixed reference exposure. Do not change measured passbands or inflate
  variance to compensate for model residuals. Report residual correlations and
  whether diagonal ERR adequately describes the registered data.

**Acceptance:** noiseless known-scene predictions agree to numerical accuracy;
noisy recovery has calibrated uncertainty and the flux/color limits in step 7.
Perturbations produce their expected residual signatures, and calibrated
corrections recover them without erasing injected diffuse light. Held-out
science residuals never determine their own PSF/background/photometric model.

### 3. Repair useful spatial resolution and establish the grid ceiling

- [x] Add measurement of actual angular cell spacing across each target and PSF
  halo; report it alongside nominal tensor dimensions. The current tanh/domain
  mapping wastes grid capacity: nominal 256 gives roughly 118 intervals over
  the footprint, and 48 gives roughly 22.
- [x] Add an explicit target-footprint spatial mapping to the existing grid,
  including a configurable PSF margin. Omitted bounds preserve the old mapping,
  so existing checkpoints are not silently reinterpreted.
- [x] Measure the new diagnostics on the frozen real-data target: a 256 grid
  changes from 47.13 target intervals (0.17113 arcsec/cell) to 245.13 intervals
  (0.03290 arcsec/cell) with the four-sigma fitted-PSF halo. The completed
  control corrected the earlier legacy estimate.
- [x] Compare legacy versus target-footprint reconstruction with every other
  factor fixed. The footprint mapping improves source/reference fidelity in
  both bands and detector validation in F277W, but F150W validation is 0.7–1.4%
  worse; classify the first screen as promising but mixed.
- [x] Compare physical sampling at one and two cells per output pixel. The 512²
  footprint grid ties legacy `m50` but worsens F150W effective FWHM; the 1024²
  grid is shallower and also worsens F150W effective FWHM. Both increase
  negative-lobe fractions. A four-cell treatment is not justified by this
  stopping rule; denser sampling is not recovered resolution.
- [x] With fixed calibration, establish a strong independent-band solution of
  the weighted inverse problem. Use existing matrix-free response/adjoint and
  an appropriate solver where available; any positivity/regularization choice
  is explicit. Compare objective convergence with Adam instead of assuming
  a fixed update count is enough. Keep noise amplification visible.

**Acceptance:** coordinate/node round trips pass at SMACS angular scales;
independent known-source recovery meets fidelity limits; increasing resolution
has a measured benefit or reaches a documented plateau. If the grid cannot
recover the synthetic scene, diagnose the operator/solver before neural tuning.

**Single-variable experiment card:** use the saved joint-grid command and source
identity, F150W/F277W, module B, aligned inputs, PATT `{1,2,3,4,5,7,8}`, 128-pixel
best-overlap target, seed 101, 256×256×4 grid, common-product initialization,
stationary frozen calibration, fitted Gaussian PSFs, learned background,
training-mean background reference, center sampling, Adam/cosine at LR 0.003,
and the existing train/validation split. Change only
`GRID_FIT_TARGET_FOOTPRINT=1` with `GRID_PSF_MARGIN_SIGMA=4.0`.

The earlier 600-step control already established a roughly nine-minute fit, so
the redundant ≤20-step timing pilot was skipped. A fresh matched pair was
launched on production CANFAR on 2026-09-24: control session `lclv179y` and
target-footprint session `nzs78f4r`, both from packaged source commit
`b2cc91a58fd553ad9b9deb5f1554457116003c38`. Compare their completed reports
with:

```bash
pixi run -e test -- python benchmarks/compare_smacs_grid_mapping.py \
  --control benchmarks_results/smacs-grid-control-20260924-r1/b/shared-foam.json \
  --treatment benchmarks_results/smacs-grid-footprint-20260924-r1/b/shared-foam.json \
  --json-out benchmarks_results/smacs-grid-mapping-20260924-r1/comparison.json \
  --markdown-out benchmarks_results/smacs-grid-mapping-20260924-r1/comparison.md
```

Advance the mapping only if held-out detector likelihood and source
flux/contrast do not materially regress and fixed-stretch blank-sky structure
does not increase. Effective PSF and matched-resolution injection metrics remain
required before any deeper-than-Drizzle claim.

The first exploratory injection launch (`kjopcswe`, `m0tktfks`) failed before
fitting because the wrapper selected only held-out PATT `{3,8}` and therefore
had no training exposures under the frozen calibration split. That stale
default is fixed. The next pair (`qsmlqs3c`, `f3ux7nq1`) exposed a second
independent failure: `log(expm1(x))` overflowed while initializing an explicit
grid from bright MJy/sr values, producing a NaN warm-start cube before the main
fit. The inverse softplus is now evaluated stably and covered by bright-data
regressions.

Sessions `brhmilwt` (legacy) and `lc6sn09r` (footprint) then completed at exact
commit `5d7978ead61edbb853b611ce6c022870f5157ae6`. The 1024-square footprint grid
fails the exploratory selection gate: at at least 95% purity its `m50` is 28.25
AB versus 28.50 AB for legacy, pooled completeness is 0.3929 versus 0.4405, and
F150W effective FWHM is 5.085 versus 4.790 pixels. F277W FWHM improves to 4.466
from 4.875 pixels, but one-band improvement does not satisfy the same-or-better
resolution requirement. Do not expand this candidate.

- [x] Run the staged 512×512×4 footprint treatment against the completed legacy
  control. Production session `xjb93a1r` completed all four frozen batches from
  package `95a11d8454986d58f212a56d5a312d650dcced17`; scoring session `mlv5wipx`
  completed the 95%-purity and effective-FWHM gates. Pooled completeness rose
  from 0.4405 to 0.4643 and `m50` tied at 28.50 AB, but F150W FWHM worsened from
  4.790 to 5.042 pixels despite F277W improving from 4.875 to 4.529 pixels. The
  treatment fails the two-band resolution gate and is rejected. Advance to the
  independent-band weighted inverse problem rather than another density sweep.

#### Handoff: first bounded inverse-solver slice

- [x] Add a one-band direct-linear grid state and native-detector operator
  adapter in `torchsky.map.field.inverse`. It uses
  `BoundObservationOperator`, not the nonlinear softplus-transformed
  `ExplicitSpectralGridField.grid`.
- [x] Establish the local operator invariants in
  `tests/test_explicit_grid_solver.py`: linearity, float32/float64 and
  asymmetric-PSF adjoint identities, zero-weight exclusion, empty-support and
  footprint guards, fixed effective-PSF response, fixed-background subtraction,
  and damped CG parity with a dense weighted oracle.
- [x] Declare the first inverse contract: a direct signed band-integrated
  surface-brightness state, fixed effective `kernel2d` PSF with detector pixel
  response included, explicit diagonal inverse-variance weights, no implicit
  clipping, and positive damping for the bounded CG comparison. Spectral,
  radiometric and additive-background terms are prepared before binding rather
  than silently advertised in the custom operator bundle.
- [x] Extend the binder to `BoundObservationOperatorSet` for same-band
  exposures and verify exposure-order/chunk-size invariance. Mixed-band inputs
  fail closed.
- [x] Add full-versus-tiled and CUDA parity. Add an LSQR/LSMR path instead of CG
  if the selected production system cannot be made demonstrably positive
  definite with the declared damping.
- [x] Convert the frozen stationary SMACS calibration artifacts into the exact
  band-integrated data and fixed effective-kernel contract required by the
  binder. Verify units, background gauge, pixel-response provenance and input
  hashes before any real-data solve.
- [x] After local identities pass, wire one bounded independent-band benchmark
  path with frozen calibration. Compare solver residual and objective convergence
  against Adam, and persist iteration count, normal-operator applications,
  timing, memory and noise-amplification diagnostics. Completed in production
  sessions `tt6un1ml` (Stage 1 128² pilot) and `dj76x1p2` / `bace9w8z` /
  `x6mkfqja` / `pggb711n` (Stage 2 512² 4-batch validation screen and model
  selection, commit `f8f437aa20fcc1c275b6d4f4e50af5e06ee5035d`):
  `fitted_gaussian__linear_band_grid_field` wins validation model selection with
  `m50 = 29.750 AB` `[29.667, 29.833]` (+1.25 mag over Adam grids, +0.25 mag
  over `coadd_bilinear`) and >2× lower held-out detector χ²/pixel (`3.063 /
  8.075`).
- [ ] Run a bounded cold-start (`scene_initialization="none"`,
  `prior_reference="zero"`) linear-solver comparison to eliminate the 432 s
  `common_product` initializer overhead on 512×512 and test whether effective
  FWHM (`3.799 / 4.854 px` when damped toward the ~5 px warm start) closes the
  remaining gap to `coadd_bilinear` (`1.429 / 2.107 px`) before any six-band or
  20-batch expansion.
- [x] Run the focused grid/joint/solver/chunking/new-solver tests, then
  `pixi run preflight-push` and `pixi run typecheck`. Do not auto-run
  `pixi run ci-local`.

**Stop before production:** any failed linearity/adjoint/finite/tiled test;
unknown PSF pixel-response or bandpass normalization; undeclared rank deficiency
or positivity semantics; unstable tighter-tolerance/chunk-size behavior; a
timing or memory budget overrun; or failed paired flux, color or effective-FWHM
gates. Do not repeat the 512/1024 footprint sweep, add a four-cell density arm,
or expand the rejected mapping to six bands or 20 batches.

### 4. Correct training coverage without making fits impractically slow

- [ ] Profile the timed-out full-image run: separate WCS, scene evaluation,
  spectral integration, PSF, backward, I/O and diagnostic costs, plus memory.
  Compare measured full-observation objective and gradients with the reference.
- [ ] Prefer exact accumulation over PSF-aware tiles with one optimizer update
  after the complete selected-observation objective. Cache only invariant
  coordinates/response products, respecting device memory and autograd.
- [ ] If stochastic tiles are needed, use known nonzero inclusion probabilities
  and the full-observation normalization. Verify the expected sampled gradient
  against the full gradient on masked/unequal-weight/unequal-footprint cases.
  Uniform patch origins alone do not make pixel inclusion uniform; patch-local
  weight normalization is not automatically an unbiased objective.
- [ ] Record full training and validation objectives at saved checkpoints,
  not just the last sampled patch loss. Preserve optimizer/RNG/scheduler state
  and export partial results before a wall-time limit.

**Acceptance:** tiled/full predictions and gradients agree; any sampled method
matches the full gradient within Monte Carlo uncertainty. A measured short GPU
pilot predicts a feasible run budget before a long fit is authorized by the
existing plan. A timeout supplies a recoverable checkpoint and failure report.

### 5. Make initialization and representation comparisons fair

- [ ] Quantify each model's error immediately after initialization. Grids and
  splats currently inherit structure; SIREN is only adjusted near mean brightness.
  Report this inequality rather than calling all starts equivalent.
- [ ] Test image-informed INR initialization using only the common training
  product, alongside a cold-start control. Count initialization parameters,
  training work and time in the total budget. Verify it preserves information
  rather than merely improving the initial scalar loss.
- [ ] Require each candidate to fit a small known scene with the calibrated
  operator before a real-data run. For SIREN, verify spatial frequency coverage,
  parameter gradients, conditioning and optimization; width alone already failed.
- [ ] Screen independent/joint grids, SIREN, FLAIR, SASNet, Foam, Gaussian splats
  and diffuse/Foam hybrid with fixed data and response. Check implementations
  against the actual intended architecture; record adaptations explicitly.
  Keep hybrid components diagnostic, not physical decompositions.
- [ ] For splats, measure spatial-evaluation cost and background texture/blank
  sky false positives. Consider spatial indexing or bounded-tail support only
  with quantified flux/gradient error. Test component density/width conditioning;
  do not hide mottling with a different PNG stretch.

**Acceptance:** candidates recover the known scene and beat their own initial
prediction without violating fidelity. Compare both matched total parameter/
optimization budgets and quality versus elapsed time. Predeclare one bounded
screen and at most one evidence-based repair per failed configuration before
parking it; record why it failed and advance the other candidates.

### 6. Use controlled real-data experiments and explicit decisions

- [ ] Change one factor at a time: spatial mapping, training coverage,
  initialization, representation, then independently supported calibration.
  Use paired seeds/inputs and the same independently frozen operator.
- [ ] Keep train PATT `{1,2,4,5,7}`, validation `{3,8}`, final test `{6,9}`.
  Split before normalization or calibration statistics. Two validation exposures
  per band are insufficient for broad uncertainty claims; do not bootstrap
  correlated pixels as independent evidence. Use paired injection batches and
  exposure/region-aware uncertainty, stating the small-sample limitation.
- [ ] Classify each change as improved, worse or uncertain. Selection requires
  validation detector likelihood plus scientific fidelity; sharper images,
  lower training loss or fewer residuals alone are insufficient.

**Decision:** advance only candidates whose fidelity passes and whose validation
improvement is supported by paired uncertainty. An interval overlapping no
change is uncertain. A fidelity failure rejects the claimed improvement even
when detector likelihood is lower. Do not use the final test to tune choices.

### 7. Demonstrate quality before six-band/full-cluster claims

- [ ] Start small injections during steps 2–5; for final evidence run at least
  20 paired batches and 800 continuum injections across at least seven flux
  levels and the four fixed science regions. Include independent injection
  PSFs, blends, dropouts, extended and diffuse sources, blank sky, negative
  injections and shuffled-band controls.
- [ ] Require bright-source flux bias ≤2% and adjacent-band color bias ≤0.02 mag
  for the declared continuum population, with paired confidence intervals.
  Predeclare diffuse-light recovery and uncertainty-coverage tolerances before
  evaluating them. Measure depth at matched effective resolution and false
  positive density; report completeness/purity and noise correlations.
- [ ] Expand passing candidates to all bands and full detector footprints.
  Resolve missing independent F090W validation calibration rather than dropping
  those exposures. Verify seams, edges, spatially varying response and memory.
- [ ] Produce brightness/support/coverage/uncertainty/residual/background/PSF
  FITS through Torchfits; common-scale linear/asinh and signed-residual PNGs;
  fixed-region comparisons and learning curves at 0%, 10%, 25%, 50%, 75%, 100%.
  Legends include units, orientation, angular scale, error, PSF, flux/color,
  runtime/memory; unknown values say “not measured.”
- [ ] Produce fixed-stretch false-color RGB with Torchfits: blue F090W/F150W,
  green F200W/F277W, red F356W/F444W averages, with native and independently
  resolution-matched versions. Keep the classical-reference display scales.
- [ ] Compare published UPDC as a secondary photometric/morphological reference,
  not truth. Injected-depth competition requires UPDC on identical injected
  inputs. Select on validation, evaluate the untouched test once, then refit
  the selected configuration on all exposures. Broader claims need another field.

### Handoff and resource discipline

- Continue on `sfabbro/torchsky` main; preserve unrelated working-tree changes.
  Read current ownership before editing. No force pushes or upstream publication.
- Use `AI-Zone-GPT-6-Sol-US` on high for difficult numerical/scientific work and
  `AI-Zone-GPT-6-Luna-US` on high for bounded routine work. Both deployments
  returned 404 in this session, so continue locally rather than retrying them in
  a loop; resume delegation when the deployments exist.
- Production CANFAR only, `images.canfar.net/astroai/webterm:latest`, one GPU for
  initial validation; up to six independent single-GPU runs when justified.
  If GPUs are unavailable, stop and ask the user. No staging/CPU fallback.
- Invoke CANFAR and VOS tools from the repository environment: `pixi run canfar`,
  `pixi run vcp`, and `pixi run vls`. Keep these dependencies unpinned in
  `pixi.toml`; the lockfile records the resolved environment. ARC paths are
  available through slower VOS commands such as `vls arc:projects/...` and
  `vcp arc:projects/...`; use mounted `/arc/projects/...` inside sessions for
  large or compute-adjacent access.
- Local execution is limited to code checks, synthetic tests and lightweight
  evidence inspection. All real-data, CUDA and heavy reconstruction work runs in
  production CANFAR headless sessions with `PYTHONNOUSERSITE=1` and no `PYTHONPATH`.
- Before each long run, state its question, fixed factors, predicted cost,
  checkpoint schedule, stopping rule and next decision. Start with a ≤20-step
  timing pilot; do not launch a run whose estimate exceeds its declared budget.
  Stop at the budget or a predeclared validation plateau, preserve results,
  and move to another independent task rather than repeatedly extending it.
- Keep immutable run reports and update `active.md` after reading actual outputs.
  Do not describe submitted jobs as scientific progress. Use focused tests,
  preflight and changed-signature type checks; no automatic full suite.
- **Remaining first-session deliverables:** recover the full-run failure,
  confirm the July 29 reference with the user, and measure the CANFAR timing
  breakdown. The local evidence inventory, grid-spacing measurement and
  single-variable experiment card are complete. No architecture sweep first.

## Historical bounded reconstruction comparison — 2026-09-22

Add **Gaussian splatting** to the independent-band grid, joint grid, SIREN,
FLAIR/SASNet and Foam comparisons. Astronomical splats are additive positive
elliptical surface-brightness components with learned positions, shapes and
spectral amplitudes. They pass through the same frozen detector operator as
every other representation; they do not use opaque alpha compositing or
replace the measured PSF. Preserve the previous Gaussian-basis model for
checkpoint replay.

Advance two tracks concurrently rather than waiting indefinitely for a
perfect baseline:

1. Fit independent F150W and F277W grids with explicit spatial resolution and
   learning rate, using the established exposure split and calibration. Bound
   this first comparison to 600 steps per band and one GPU per run. Diagnose
   a failed run, but do not repeatedly tune it before testing other models.
2. Screen joint grid, Gaussian splats and a larger SIREN on the same region,
   with recorded parameter counts, effective optimizer settings and elapsed
   time. Start with 600 steps. Keep measured passbands, masks, background
   reference and PSFs fixed. FLAIR/SASNet and Foam remain subsequent comparison
   arms rather than being silently dropped.

These initial screens compare accuracy versus compute, not equal parameter
budgets. Follow promising candidates with matched budgets and injection-based
flux/color recovery. Report failed or flat solutions alongside successful
ones. Stop increasing training budgets when validation has stopped improving;
do not infer convergence from the last random patch loss. The final test stays
untouched. Keep the common sky level explicit, and treat splat components as a
representation rather than a physical source catalogue without recovery tests.

The next decision is which representation warrants six-band and finer-grid
work, using held-out detector prediction and source recovery together. A
sharper-looking image alone is insufficient.

## Accepted execution plan — 2026-09-05

This section supersedes earlier scheduling, branch, calibration-default, and
model-selection instructions below. Historical results retain their original
code identities; a new science run records a new exact pushed commit.

### Consolidate the fork first

- Preserve the three pending roadmap/sprint edits before switching branches.
- Reconcile all local and remote branches on `main` in `sfabbro/torchsky`:
  current and remote SMACS, WCS integration, SVO caching, field research, and
  the stale UPDC history. Preserve relevant unique work without restoring
  obsolete parallel implementations or FITS ownership in Torchsky.
- Track and push `origin/main`; do not force-push, push upstream, or delete
  branch references as part of consolidation. Record starting commits and
  conflict decisions in `active.md`.
- Repair the inconsistent lint job and spectral zero-weight test failures.
  Confirm WCS, sphere, and matching behavior after integration. Document the
  limits of finite-resolution native exact-region operations, matching epoch
  and validity handling, and device coverage.

### Shared scientific assumptions

All methods predict the same calibrated native detector observations through
the same independently calibrated response. Learn a static celestial
`I_nu(position, wavelength)` scene, including persistent intracluster light.
Flag moving or variable sources. A joint INR couples position and spectrum;
Foam combines localized spatial components with spectral coefficients. Hybrid
component images remain diagnostic until component-specific injections support
physical interpretation. Six measured band integrals do not establish a unique
fine spectrum.

| Component | Initial treatment | Controlled extensions |
| --- | --- | --- |
| Passbands | Measured tabulated photon throughput with the actual calibration reference spectrum; fixed across methods. | Throughput corrections need independent calibration. |
| PSF and pixels | Independently calibrated effective PSFs, frozen during scene comparison; explicitly record whether pixel response is included and integrate pixels exactly once. | Spatial, chromatic, and temporal response variation require calibration support. |
| Brightness | Predict calibrated SCI, normally MJy/sr; preserve zero points and pixel-area conventions. | Independently fitted relative exposure scaling with an explicit reference. |
| Background | Persistent celestial light stays in the scene. Detector offsets act in detector coordinates; optical foregrounds pass through the optical response. | Independently calibrated plane/neural backgrounds, frozen across scene representations. |
| Noise | Gaussian likelihood using valid calibrated error/variance planes and identical masks; covariance only where independently supported. | Separate calibration-uncertainty propagation; no free variance inflation to hide residuals. |

For a flat-`I_nu` calibration and dimensionless photon throughput `T(lambda)`,
the normalized band weights are proportional to `T(lambda)/lambda`. Verify
against the input product convention and otherwise use its reference-spectrum
normalization. Keep throughput shape, absolute calibration, and numerical
scaling separate. Do not multiply calibrated MJy/sr by gain and call it counts.

Fit numerical normalization on training data only, scale SCI/ERR/VAR
consistently, and reverse it on export without subtracting an unexplained
diffuse pedestal. Relative background offsets have weighted zero mean; this
does not determine absolute sky brightness. Use an independent foreground
reference or explicitly report brightness relative to the adopted mean
foreground. Calibration for held-out observations comes from independent
evidence or training-based predictions, never unrestricted fits to their
science residuals.

Replace misleading nominal defaults: Gaussian PSFs are approximation controls,
summary-shaped passbands are not measured curves, and a plane option must
actually apply a plane. Each run identifies fixed, independently fitted, and
scene-learned quantities. Temporal dependence belongs to instrument/background
terms initially, not an unrestricted astronomical position/wavelength/time field.

### Ordered implementation

1. Recover actual ARC log contents and products; verify all 135 aligned detector
   inputs, UPDC references, calibration identities, and code versions before
   restarting jobs.
2. Preserve WCS, units, passbands, PSF convention, masks, variance, and background
   metadata through fitting, rendering, normalization, save/resume, replay, and
   export. Fix sampling inconsistencies and invalid spectral integration.
3. Finish PSF-aware patches with sufficient margins, streamed backward
   evaluation, and recomputation for full-observation noise treatment. Verify
   tiled/full predictions and gradients. FITS subset/streaming writing belongs
   in Torchfits; core computation remains tensor-native.
4. Produce independent official Drizzle, SWarp, and Montage products alongside
   Torchsky on identical inputs and WCS. Check flux, support, weights, counts,
   provenance, time, and memory. Missing comparators remain incomplete.
5. Screen existing field architectures and compare explicit grids, independent
   and joint INRs, independent and joint Foam, and diffuse/Foam hybrid against
   strong classical multiband and native detector-space detection. Resolve
   Foam flux recovery before expensive runs. Compare equal total parameter and
   optimization budgets, and separately accuracy versus elapsed time.
6. Select on validation, evaluate the final test once, then refit on all
   exposures and produce six-band reconstructions and UPDC comparisons.
7. Finish general AstroDrizzle registration/background/outlier/combination,
   SWarp background/clipping/weights, and Montage overlap-background/curved
   footprint workflows. Validate beyond SMACS before claiming general parity.

Keep public interfaces thin: retain `field` and deprecated `inr`, extend
existing observation/product records, provide bounded tile iteration and the
documented AstroDrizzle workflow preset.

### Delegation and CANFAR scheduling

Use Astra-medium for most implementation and coordination, Astra-high/max for
difficult numerical work, merge conflicts and substantive review, and
Luna-xhigh for bounded routine implementation, checks, logs, documentation and
verified commits. Assign disjoint file ownership; serialize integration and
commits on the shared `main`.

Use CANFAR within available allocations: one GPU validation run, then up to six
independent single-GPU jobs by default, adapting to measured capacity and needs.
Continue independent coding/debugging/testing/reporting while jobs run. Wait
only for results that actually determine the next decision. Multi-GPU training
requires measured single-device limitations first.

### Products and continuous measurements

Every completed method produces FITS reconstruction, valid support/coverage,
available labelled uncertainty, and applicable residual/background/PSF products.
Produce matched full-field and fixed-region PNGs with common per-band scales,
linear/asinh views, signed residuals and distinct missing coverage. Legends
show method, band, units, orientation, angular scale, measured prediction error,
PSF width, flux/color bias, runtime and memory; missing values say "not measured".

Use Torchfits for FITS and RGB. Freeze stretch and channel mapping across
methods: blue averages F090W/F150W, green F200W/F277W, red F356W/F444W. Label false
color and provide native and resolution-matched comparisons. Extend the existing
visualizer; freeze display scales from the classical reference.

Track validation prediction error, flux/color recovery, PSF width/encircled
energy, diffuse recovery, noise correlations, completeness/purity, uncertainty
coverage, time and memory. Save diagnostics at 0%, 10%, 25%, 50%, 75% and completion.
Keep immutable run reports and compact history; report improved/worse/uncertain
with uncertainty intervals. Sharpness alone is not improvement; the test set
is not a development dashboard. Use plain-language reports.

### Verification and selection

Keep whole PATT groups together: training `{1,2,4,5,7}`, validation `{3,8}`,
test `{6,9}`. Split before fitting preprocessing statistics. Verify units,
surface brightness, flux, passband integration, PSF centroid/wings/normalization,
single pixel integration, applicable adjoints, tiled/full behavior and replay.
Use real data and independent point, extended, blended, dropout and diffuse
injections: at least 20 paired batches and 800 continuum sources, seven or more
flux levels, four fixed science regions, and independent truth PSFs.

Select by validation detector likelihood after scientific-fidelity checks.
Bright-source flux bias must be at most 2% and adjacent-band color bias at most
0.02 mag for the claimed continuum population. Measure depth at matched
effective resolution and false-positive density with paired intervals and
blank, negative-injection and shuffled-band controls. Published UPDC products
are secondary image/photometry/morphology references, not truth or an injected
depth competitor without rerunning the same injected inputs.

Run targeted tests, preflight and changed-signature type checks. Verify CUDA on
CANFAR; unavailable devices remain unverified. Broad superiority claims need an
independent field. Completion requires reconciled fork `main`, passing relevant
checks, reproducible six-band products/comparisons, validated general workflows,
and clear separation of measured, experimental and incomplete capabilities.

> Ordered engineering and science tasks after the 2026-07-22 map/INR milestone.
> This is the authoritative remaining-work roadmap, not a public API promise.
> The execution/evidence log lives in [`active.md`](active.md), and the
> scientific contract lives in [`../formulation_map.tex`](../formulation_map.tex).
> [`status.md`](status.md) is a historical status snapshot and must be
> re-baselined when a release is cut.
> The user-authored FOSSIL/BISOU science and primitive work is incorporated as
> a separate mission-neutral track in
> [`../projects/fossil.md`](../projects/fossil.md); its immediate ordering is
> interleaved with the active exact/bounded map-operator gates.

## Live SMACS parity recovery checkpoint — 2026-09-04

This is the durable restart point for the current work. The classical map code
under test is commit `ff2afba21efa5126978d647990ce60b6d943307f` on
`sfabbro/smacs-map-parity`; it is committed and pushed. Keep every band in this
comparison pinned to that science-code commit even if documentation-only commits
advance the branch.

The job is testing Torchsky equivalents against the actual official comparator
implementations, not comparing Torchsky modes with one another:

- Drizzle: STScI `drizzle==2.2.0` through its compiled Python API, compared with
  Torchsky exact square drops at `pixfrac=0.8`.
- SWarp: the source-built executable at
  `bf4f496f18c04a8d32022b45449ef8675ab9b3da`, using `LANCZOS3`, compared with
  Torchsky Lanczos3.
- Montage: source-built `mProject`/`mProjectPP` at
  `0fc9e5ff55ece4ee0b5d731157cf07cc31325724`, compared with Torchsky's
  conservative polygon remapper.

Each side writes independent `SCI`/`WHT` products on the same supplied target
WCS. The strict harness then compares their pixels, support, flux, exposure
count, provenance, and acceptance bounds. This is workflow parity on calibrated
aligned exposures; it is not raw JWST calibration and it is not the full
AstroDrizzle orchestration surface.

Last observed CANFAR state before this checkpoint:

| Band | Session | Persistent run | Last observed state |
| --- | --- | --- | --- |
| F277W | `lwm8klfq` | `depth-20260904-213335` | H100 proved; installing the single locked `map-compat-cuda` environment. |
| F090W | `b02dnl1p` | `depth-20260904-213526` | Session created; science stage not yet inspected. |
| F150W | `mrfyfau0` | `depth-20260904-213553` | Session created; science stage not yet inspected. |
| F200W | unresolved | launch begun after 21:35 UTC | Local client was interrupted; resolve from `canfar ps --all --json` before retrying. |
| F356W | not submitted | — | Submit only after the F277W canary clears environment and comparator setup. |
| F444W | not submitted | — | Submit only after the F277W canary clears environment and comparator setup. |

Artifacts are expected under
`/arc/projects/ots/torchsky-runs/<run-id>/mosaic-parity/b-<band>/`, including
separate official/Torchsky products plus `parity.json` and `parity.md`. None of
the active sessions had produced accepted science evidence at the time of this
checkpoint. Earlier failed attempts stopped before science execution and are not
parity results.

The classical SMACS gate is complete only when all six band rows report the
expected exposure counts (36 for F090W/F150W/F200W and 9 for
F277W/F356W/F444W), every required official comparator has status `ok`, every
acceptance row passes, every Torchsky row records `compute_device=cuda`, and the
persisted products can be reopened through Torchfits. A skipped comparator is a
failure. Until that evidence exists, Drizzle/SWarp/Montage are implemented and
locally gated but are not claimed ready for the full SMACS mosaic.

Neural-field and Foam contracts are usable for bounded experiments, but the
full-size SMACS field product, equal-budget bakeoff, calibrated uncertainty,
and scientific depth gate remain open. Do not call the system SOTA or deeper
from the classical parity run.

## Reconciliation register — 2026-08-30

This register reconciles the unchecked work in the active, project, formulation,
and archived planning documents. A row names a contiguous checklist group; all
unchecked bullets in that group have the same disposition. `implement` means
Torchsky work remains; `absorbed` means the current implementation or another
roadmap item covers it; `downstream` belongs in `torchfits`, FOSSIL, USPM, or
cosmodist; `conditional` waits for a declared profile/consumer/benchmark gate;
and `rejected` is intentionally out of scope or conflicts with the ownership
contract. No row is a scientific claim without its evidence gate.

| Source and unchecked group | Disposition | Evidence gate / next proof |
| --- | --- | --- |
| `active.md`: staged-calibration identifiability, learned-PSF covariance, CUDA conditioning profile, and public tile sink | implement / downstream | Held-out calibration score; covariance test; CUDA profile; `torchfits` subset-writer contract. |
| `active.md`: MPS/spherical/delay-axis variants and the remaining Foam blank, contracted-grid, exact-refinement, and blind-test gates | implement / conditional | Device parity where available; frozen real-exposure artifacts; activate new axes only with a FOSSIL consumer. |
| `active.md`: Checkpoint 6 `TensorSpec`, response, protected subspace, cross-fit, full-sky, and cosmology rows | implement / conditional / downstream | Shared Torchsky consumer plus adjoint/chunk/replay gates; cosmology certification remains downstream. |
| `adass_updec_depth_week.md`: independent/shared real Foam, common photometer, frozen configs, injection batches, claim gates, and submission rows | implement / conditional | Exact frozen exposure/split artifacts; official comparators; 20 paired batches and the preregistered 95% purity/depth/coverage gates. |
| `fossil.md`: typed operators, `TensorSpec`, `SpectralResponse`, protected subspaces, cross-fit/injections, full-sky/open residuals, and FOSSIL benchmark phases | implement / conditional / downstream | Implement only shared mission-neutral primitives; require adjoint, held-out, injection, memory, and consumer evidence before promotion. |
| `torchsky-uspm-cosmodist-roadmap.md`: TS-02 | implement | Cross-project adapter fixtures, units/time/provenance, device movement, and query/splat adjoint gates. |
| `torchsky-uspm-cosmodist-roadmap.md`: USPM-06–12 | downstream | USPM-owned real manifests, physical state, nuisance/calibration, predictive uncertainty, and science-case certification. |
| `torchsky-uspm-cosmodist-roadmap.md`: COSMO-01–09 and INT-01 | downstream / conditional | cosmodist-owned representation/mode/certification artifacts; Torchsky contributes only accepted shared primitives and evidence schemas. |
| `formulation_map.tex`: normative equations and 52-assumption contract | absorbed | Treat the formulation as the contract; every implementation claim must pass its operator, information, uncertainty, and held-out gates. No unchecked task list exists in the TeX source. |
| `docs/archive/*` roadmap/whitepaper plans | absorbed / conditional / rejected | Preserve as rationale/history; promote an item only when it appears in `next.md` with a current owner and gate. Legacy duplicate abstractions and FITS ownership are rejected. |

The current working-tree implementation has already absorbed the P0 map fixes
for adaptive curved footprints, exact square-drop edge support and diagonal
variance, honest optional map uncertainty/context/provenance products, MEF
writing through Torchfits, workflow/background presets, and plan-v2 identity
replay. Field plan replay now requires and content-verifies its tensor-only
artifact and renders without adding optimizer steps; changed artifacts are
rejected. These are still subject to the targeted gates recorded in `active.md`;
the large-output subset writer remains a downstream `torchfits` prerequisite.
The field trainer also has an opt-in CUDA `--field-amp` path with local
autocast/GradScaler, FP32 diagnostics, unscale-before-clipping, overflow
accounting, and resumable scaler state. Actual CUDA parity and overflow evidence
remain open because this host has no CUDA device.

## Status guardrails — 2026-09-01

The current working tree is an implementation checkpoint, not a scientific
promotion. The immediate aim is one tensor-native, bounded observation path that
can be compared fairly across classical coadds, continuous fields, and Foam
under the same WCS, passband, PSF, mask, weight, background, and uncertainty
contracts.

What is complete enough to execute:

- the map substrate has adaptive curved-footprint planning, finite-kernel
  squared-coefficient variance propagation, optional `NCORR` diagnostics,
  capacity-checked reducer scratch, plan-v2 identity/artifact replay, and
  non-skippable Drizzle/SWarp/SWarp-`CLIPPED`/Montage smoke gates;
- the field surface has tensor-only artifacts, default joint multiband fitting,
  a common constructor/device/gradient contract for every registered candidate,
  and a fast benchmark that reserves a complete exposure and removes PSF-guarded
  NE/SW sky regions before product, domain, initializer, or fit construction;
- Foam lifecycle, the combined diffuse/Foam renderer, and opt-in AMP have
  executable contracts, but their scientific promotion gates remain open.

The remaining work that can change a scientific conclusion is: FFT/spectral
uncertainty, medium/large memory scorecards, the
distorted/dithered/cylindrical/all-sky
comparator matrix, equal-parameter/step/time field bakeoffs, blank and
detector-space controls, component-specific injections, at least three scene
seeds with two noise realizations, and replication on an independent real field.
Multi-GPU DDP is conditional work after the single-device streaming and
deterministic-reduction contracts are stable; no DDP result exists yet. Large
FITS output remains downstream of a `torchfits` subset-writer/tile-export
contract.

No SOTA, depth, or production-preset claim is allowed from the current smoke
artifacts, a one-seed result, a one-field result, visual sharpness, or image
RMSE. A parent checklist stays unchecked until its complete evidence gate passes:
matched input information and budgets, held-out exposures and sky regions,
negative controls, calibrated uncertainty, deterministic repeats, and the
required CPU/CUDA/device and memory evidence. Test or blind identifiers may not
be used for selection; a null or negative result is a valid outcome.

## North Star

Torchsky should provide one tensor-native observation model for classical
coaddition, continuous neural fields, and adaptive bounded power-cell fields.
The same WCS, bandpass, PSF, calibration, mask, weight, and background operators
must be used by every representation. A new method earns promotion by improving
truth recovery or operational scale under those shared operators, not by making
a visually sharper image.

## P0 — Exact And Scalable Map Substrate

These tasks protect every later INR/Foam result from operator or memory errors.

- [x] Remove the stale module-global image cache and make weighted/mean tiled
  mosaics exposure-major: each input image and its calibration/weight preparation
  are held for one exposure, reused across tiles, then released.
- [x] Decide caller-cache policy from repeated real MEF evidence: warmed
  `SCI`/`ERR`/`DQ` reads are already 0.060–0.068 ms, so do not add a second
  caller cache.
- [x] Spill exact median and iterative sigma-clipped weighted stacks to a
  tile-local scratch store. Capacity is checked before projected contributions
  are consumed; values are reduced in bounded pixel slabs and scratch is removed
  after success or failure. Evidence: masked/even-median parity, outlier/context,
  tiled parity, scratch exhaustion, and cleanup tests.
- [x] Spill cross-exposure background correction so overlap rectification does
  not trade bounded memory for repeated input reads. The implementation now
  projects every exposure once into a capacity-checked linear-size scratch
  store, accumulates pairwise models directly into one anchored graph RHS, and
  solves/applies corrections by output tile without retaining an edge-model
  stack. Global chain-graph parity, explicit-IVAR parity, single-read behavior,
  scratch exhaustion, and cleanup tests pass. Robust polynomial and default
  mesh estimators now retain only coefficients/the filtered mesh and render
  correction windows on demand; unsupported custom estimators fail closed in
  the tiled path. The updated three-run-median four-exposure 1024-square
  scorecard records 2.565 s, 1.635 projected Mpix/s, 83,886,080 exact scratch
  bytes, and a 243,777,536-byte peak-RSS delta, with unchanged propagated-IVAR
  error.
- [x] Adaptively sample curved SIP/TPV footprint boundaries when planning union
  products; gate containment across the RA=0 seam and rotated/sheared grids.
  Evidence: recursive quarter-pixel chord-bound sampling, seam-safe buffering,
  invalid-WCS fail-closed behavior, and focused curved-edge/seam/rotation tests.
- [ ] Complete diagonal variance propagation for interpolation, conservative,
  and forward-splat kernels. Direct copy, exact square/point drizzle,
  nearest/bilinear/bicubic, Lanczos/cubic, conservative polygon, and point/box
  splat paths now propagate squared coefficients only when an explicit scalar
  or map noise weight is supplied. Evidence includes basis-coefficient oracles,
  half-pixel surface-brightness/flux cases, tiled parity, and seeded bilinear
  Monte Carlo. Distorted-WCS flux quadrature sums repeated source-pixel
  coefficients before squaring and passes real-SIP tiled parity. The gate
  remains open for FFT/spectral remappers; those paths return `None` rather than
  a proxy.
- [x] Report correlated-noise/effective-noise products where interpolation makes
  diagonal variance incomplete. Gate: local/aperture correlation diagnostics
  and a variance Monte Carlo parity fixture.
  - [x] Emit optional `NCORR` as the local first-coefficient/squared-coefficient
    ratio whenever exact propagated detector variance exists. Identity,
    half-pixel Drizzle/interpolation/polygon/splat, tile/cube, FITS metadata, and
    seeded large-aperture Monte Carlo gates pass. It remains explicitly labelled
    as a local diagnostic; exact requested apertures use the evaluator below.
  - [x] Add an exact finite-aperture evaluator for every finite-support map
    kernel. It applies the shared differentiable observation operator's adjoint,
    accumulates reused source-pixel coefficients across output tiles before
    squaring, and never materializes a map covariance matrix. Evidence covers
    all twelve finite kernels, signed apertures, flux and surface-brightness
    units, spatial inverse-variance maps, a distorted SIP source-basis oracle,
    tile-boundary covariance, and a seeded 10,000-draw Monte Carlo. Mismatched
    provenance, unsupported coverage, data-dependent backgrounds, and global
    FFT/spectral kernels fail closed.
- [x] Emit science-ready data, weight/inverse-variance, overlap/context, and
  mask planes from `torchsky map`; large outputs still require the downstream
  Torchfits subset writer.
  Evidence: MEF writer and context-overflow/provenance tests.
- [ ] Emit optional coverage-MOC products. Gate: a sparse all-sky consumer and
  RING/NEST/MOC parity fixture.
- [x] Make saved execution plans replayable and reject changed/missing inputs by
  recorded identity rather than silently running a different job.
  Evidence: plan-v2 schema and trust-boundary validation, checksum/SHA-256
  identity, auxiliary-map identity pairing, artifact-bound field replay without
  extra optimizer steps, malformed-plan rejection, and input/artifact tampering
  tests.
- [x] Keep weighted-mean execution observation-streaming and tile-bounded.
  Evidence: exposure-major execution and tiled parity tests.
- [x] Make exact median and sigma-clipped scratch requirements explicit in plan
  v2 (`5` and `12` bytes per observation-pixel respectively) and fail before
  consuming projections when free capacity is insufficient.
- [ ] Record medium/large reducer runtime, peak RSS, and scratch-usage scorecards.
  Provisional 1024/2048-square CPU artifacts now record all three measurements
  and exact scratch cleanup, but retain `git_dirty=true`; rerun from the clean
  implementation commit before closing this evidence gate.

## P1 — Full Bounded Power-Foam Representation

The shipped `foam` primitives are the exact geometry foundation, not yet a full
renderer. `ResidualTileBasisField` remains a Gaussian residual baseline and must
not be presented as Foam.

### Geometry and sparse execution

- [x] Tensor-native power distance, exact bounded-cell ownership, Čech overlap
  edges, radical-plane equations, and an explicitly labelled soft optimization
  surrogate.
- [x] Build a survey-scale overlap index before pair testing. Validate it against
  the exact chunked Čech reference and report candidate reduction and peak memory.
- [x] Construct per-cell neighbor CSR and tile-to-cell candidate lists without a
  mandatory graphics or CUDA-only runtime dependency.
- [x] Implement exact clipped power-cell/pixel intersection in the local tangent
  plane, including flux-conserving area integration and an adjoint/dot-product
  gate. Use quadrature only as a documented fallback for curved WCS footprints.
- [x] Add exact hard-cell inference and a well-defined differentiable training
  path; never conflate a soft partition with the exact renderer.

### Astronomy-native appearance model

- [x] Share spatial sites, radii, and adjacency across wavelength while keeping
  spectral appearance parameters separate from geometry.
- [x] Add per-cell spectral bases or compact spectral decoders evaluated through
  the existing deterministic bandpass operator; support broadband images, narrow
  bands, IFU channels, and energy bins through the same contract.
- [ ] Add within-cell detail sites with normalized soft-Voronoi interpolation for
  high-frequency spatial/spectral appearance, following the Power Foam separation
  of coarse geometry from texture without importing its view-dependent RGB model.
- [ ] Compose Foam with a diffuse INR branch so cells model compact/residual
  structure and the INR models smooth emission; add identifiability and sparsity
  constraints so the branches cannot exchange arbitrary flux.
  - [x] Implement the experimental combined-sky model, explicit
    diffuse/Foam/joint stages, low-capacity diffuse default, non-negative
    localized Foam, declared sparsity/correlation penalties, exact hard-cell
    inference, and tensor-only artifacts. The parent gate remains open until
    component-specific injections show that the decomposition is identifiable.

### Optimization and uncertainty

- [ ] Initialize sites from persistent sky evidence across multiple exposures,
  not a residual from one detector image.
  - [x] Add the exposure-balanced, order-invariant core initializer over
    normalized sky coordinates and whitened residuals. The remaining gate is
    wiring it into a frozen production recipe and held-out injection benchmark.
- [x] Track per-cell held-out residual error, contribution, and residual-position
  EMAs; implement deterministic densification/pruning with survivor optimizer
  state preserved and new-child moments zeroed. Evidence: focused model tests,
  tensor-only artifact round-trip after topology change, and resumed Adam step.
- [ ] Add overlap/connectivity, contribution sparsity, radius, and component
  separation losses with ablations; document every heuristic and its upgrade path.
- [ ] Produce posterior/ensemble uncertainty and coverage diagnostics for cell
  fluxes, colors, positions, radii, and diffuse-field predictions.
  - [x] Add bounded-memory seeded ensemble rendering with separate detector,
    epistemic, and independently seeded calibration-draw variance components.
    Per-cell posterior coverage and real held-out coverage remain open.

## P1 — State-Of-The-Art Continuous Fields

- [x] Replace the INR-only product surface with the `field` method (retain
  `inr` as a deprecated alias), field presets, and tensor-only resumable field
  artifacts. Evidence: CLI/API, JSON-manifest, weights-only load, input
  identity, and split/resume-equivalence tests.
- [x] Make joint multiband fitting the default while retaining per-band fitting
  as an explicit control (`--per-band`/`--per-filter`). Evidence: the field CLI
  derives and preserves each exposure's passband by default, and two-band
  operator/CLI tests pass without collapsing exposure-specific metadata.
- [ ] Benchmark the existing SIREN, WIRE, Fourier, hash-grid, sky-encoder,
  sky-lambda plane/K-plane, feature-atlas, and operator-constrained families on
  equal parameter, optimizer-step, and wall-time budgets. Promote presets only
  from held-out exposure performance.
  - [x] Give all registered models one API/device/gradient/tensor-state contract;
    keep corrected BACON and support-capped SASNet candidates experimental until
    the equal-budget bakeoff is complete.
  - [x] Add deterministic complete-exposure holdouts to the common benchmark,
    split before product/domain/initializer construction, and record parameter,
    trainable-parameter, wall-time, split identity, and held-out detector RMSE.
    The fast contract covers SIREN, spectral Foam, the diffuse/Foam hybrid, and
    the equal-information coadd product; the full equal-budget model zoo remains
    open and opt-in because its slow candidates are not a smoke gate.
- [ ] Add footprint-aware/integrated encodings beyond fixed 2x2 pixel quadrature
  when compact-source phase tests show a measured gain.
- [ ] Make training observation-streaming and patch/tile-bounded, with mixed
  precision and `torch.compile`/CUDA paths enabled only after numerical parity.
  - [x] Add opt-in CUDA `--field-amp none|float16|bfloat16` with local
    autocast/GradScaler, FP32 diagnostics, unscale-before-clipping, skipped-step
    overflow accounting, and scaler-state artifact persistence/resume. CPU and
    MPS fail closed.
  - [ ] Run CUDA FP32-parity and overflow scorecards before enabling AMP in a
    production preset. Gate: exact loss/gradient tolerance, finite artifacts,
    and matched held-out results.
- [ ] Strengthen heteroscedastic and robust likelihoods, calibration nuisance
  parameters, and posterior predictive checks; distinguish epistemic model error
  from detector noise.
- [ ] Add physically optional spectral structure—smooth continua, emission-line
  components, redshift/kinematic transforms, and non-negative mixtures—without
  forcing physical approximations when data support a more expressive decoder.
- [ ] Train and score hybrid diffuse-INR plus Power-Foam models against each branch
  alone, classical stacks, and explicit-grid inverse solutions.
  - [x] Implement the combined-only hybrid and its staged-fit/exact-render path.
    Equal-budget held-out scoring and component-identifiability injections remain.

## P1 — Multi-Wavelength Depth Demonstration

The central claim is improved inference at fixed input information, not merely a
higher-S/N detection image.

- [ ] Build a seeded injection suite with sub-threshold point sources, compact
  galaxies, diffuse color gradients, line emitters, band dropouts, PSF variation,
  dithers, masks, calibration offsets, and realistic correlated noise.
  - [x] Add deterministic paired manifest plumbing for positive, blank,
    explicitly sign-flipped, and per-band source-permutation controls. The same
    detector injection and classical/field adapters consume every mode, and the
    shuffled control records exact permutations while preserving per-band flux
    marginals. Real frozen-batch execution and pass/fail thresholds remain open.
- [ ] Compare matched single-band stacks, classical multi-band detection with
  forced photometry, independent per-band INRs, a shared multiband INR, a shared
  spectral Foam, and the hybrid model under equal train/validation information.
- [ ] Reserve complete exposures and sky regions for held-out prediction; use
  blank-sky negative controls and never tune on the final test field.
  - [x] Implement seeded complete-exposure reservation and PSF/resampling-guarded
    sky-coordinate quadrant holdouts in the common synthetic field benchmark.
    The fast contract removes NE and SW before every initializer/operator and
    verifies zero training support in the evaluation cores. Blank controls,
    frozen final-test identities, arbitrary-region splits, and a detector-space
    classical prediction baseline remain open.
- [ ] Report completeness versus intrinsic flux, purity/false detections, flux and
  color bias/scatter, morphology error, limiting depth at fixed purity, interval
  coverage, calibration residuals, runtime, and peak memory.
- [ ] Require the joint model to improve limiting depth at fixed purity while
  preserving calibrated flux/color uncertainty; publish negative results and
  source-class-specific failures.
- [ ] Reproduce the winning protocol on a real multi-band field using raw
  exposures plus independent external catalogs, not a deeper coadd as truth.
  This field-to-field replication is required before any SOTA or depth language,
  even if the first real field has a positive interval.

## P2 — SWarp, Drizzle, And Montage Workflow Closure

Torchsky already covers the central reprojection/coaddition algorithms. Remaining
work should target operational semantics and measurable parity, not clone every
legacy option.

- [x] Expose `native|drizzle|swarp|montage` workflow presets and
  `none|per-exposure|overlap` background modes while retaining `--sky` as an
  alias. Evidence: resolved-configuration CLI tests.
- [ ] Maintain source-built official-tool comparison rows for representative
  TAN/TPV, dithered undersampling, cylindrical, and all-sky cases; keep unsupported
  comparisons as explicit skips.
  - [x] Add non-skippable, version-locked acceptance rows for upstream-derived
    Drizzle point/square translation, SWarp bilinear/Lanczos3 shifted TAN, and
    Montage conservative SIN projection. Evidence: `bench-map-drizzle-required`,
    `bench-map-swarp-required`, and `bench-map-montage-required` pass their
    committed absolute bounds; the weekly job source-builds pinned SWarp and
    Montage revisions before running them.
  - [ ] Extend the required matrix to distorted TPV/dithered, cylindrical, and
    spherical/RA-seam workloads rather than treating the three smoke fixtures as
    workflow-wide closure.
- [ ] Close SWarp-style background matching, photometric scaling, clipping/combine
  behavior, weight/mask interpretation, and large-mosaic streaming where those
  workflows are scientifically useful.
  Current evidence: `sigma_clipped` is a bounded scratch-backed iterative
  MAD/inverse-weight-noise clipped weighted mean with retained-observation
  `WHT`/`NEXP`/`CTX`. On the locked shifted-TAN fixture, complete-footprint
  bilinear and Lanczos3 data differences are at most `1.50e-5` and `6.74e-6`,
  respectively, and weight differences are below `1.84e-4`; explicit support
  IoU/full-grid diagnostics retain SWarp's border-policy disagreement. A locked
  five-exposure cosmic-ray fixture also passes official SWarp `CLIPPED` with
  `8.59e-5` maximum data difference and `1.44e-3` maximum median-normalized
  weight difference on complete support. Dithered clipping and the broader
  gain/noise/`CLIP_AMPFRAC` matrix remain open.
- [ ] Close Drizzle context maps, pixfrac/kernel semantics, units, fill/support,
  and correlated-noise accounting on upstream-derived translated/dithered cases.
  Current official translated-fixture evidence is exact for point drops and
  `1.68e-12` maximum data difference for square drops, with zero weight
  difference. Dithered context overflow, units, and correlation acceptance remain
  open.
- [ ] Close Montage-style footprint planning, background rectification, plate
  aggregation, and spherical large-mosaic execution, while retaining Torchsky's
  tensor-native internals.
  Current official SIN projection evidence is exact on data and support against
  pinned `mProjectPP`; overlap rectification and spherical/plate scale gates remain
  open.
- [ ] Promote a parity item only when analytic truth, the external comparator,
  edge/interior diagnostics, flux conservation, and deterministic repeats agree.

## P2 — WCS, Sphere, And All-Sky Scale

- [ ] Finish named Paper III/IV and frame-precision gaps with concrete upstream
  fixtures and device-parity tests.
- [ ] Generalize map products across tangent patches, HEALPix/MOC partitions, and
  sparse all-sky outputs without densifying the sky.
- [ ] Route Foam/INR queries through patch-local tangent coordinates with explicit
  seam/overlap blending and prove equivalence on shared patch boundaries.
- [ ] Benchmark CPU, CUDA, and MPS only where the numerical contract is supported;
  fail closed elsewhere.

## Release And Infrastructure Gates

- [ ] Keep `main` releasable: targeted test during development, then
  `pixi run ci-local` before every push.
- [ ] Add small/medium/large benchmark baselines for map streaming, sparse Foam
  candidates, Foam rendering, INR fitting, and the multi-band depth experiment.
- [ ] Record environment, commit, device, dtype, seeds, input identities, config,
  wall time, and peak memory in every benchmark artifact.
- [ ] Exercise `torchfits` at every FITS boundary and keep all FITS ownership and
  throughput work in the sibling repository.
- [ ] Validate Linux headless CPU and CUDA wheels on CANFAR before declaring a
  release candidate; retain CPU/MPS correctness on local CI.
- [ ] Add a conditional multi-GPU DDP runner and deterministic reduction/parity
  scorecard only after the single-device field path is streaming and bounded;
  DDP is an execution/scaling gate, not evidence of scientific improvement.
- [ ] Promote experimental field APIs only after their truth, held-out, uncertainty,
  memory, and device gates are green.

## Immediate Task Order

The detailed scientific protocol remains
[`../projects/adass_updec_depth_week.md`](../projects/adass_updec_depth_week.md).
Resume from the live checkpoint above in this order:

1. inspect the three known sessions and resolve whether the interrupted F200W
   launch created a fourth session; never submit a duplicate blindly;
2. require F277W to prove the H100/CUDA device, finish the locked environment,
   source-build the pinned comparators, and enter the real mosaic stage;
3. submit or resume the other five bands at exact science commit `ff2afba2`,
   using one GPU per band and no more than the available CANFAR quota;
4. collect `parity.json`, `parity.md`, logs, manifests, and both official and
   Torchsky products for all bands; reject missing, skipped, CPU, changed-input,
   wrong-count, or incomplete rows;
5. diagnose numerical failures by workflow and rerun only after committing and
   pushing a tested fix, with every replacement run pinned to one new exact
   science SHA;
6. after all classical rows pass, record runtime/peak-memory scorecards and cut
   the first usable single-node map checkpoint;
7. then run the frozen independent-field, joint-field, Foam, and hybrid matrix
   under equal information and compute budgets; full-size execution alone is
   not a promotion gate;
8. run paired detector injections, blank/negative/shuffled controls, calibrated
   uncertainty, and independent-field replication before any SOTA/depth claim;
9. keep DDP conditional until the single-device streaming path and artifacts
   are stable, then add deterministic one-rank/eight-GPU equivalence evidence;
10. resume FOSSIL typed spectral/component-separation primitives and broader
    survey scaling after the SMACS map checkpoint is closed.
