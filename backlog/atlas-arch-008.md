<a id="atlas-arch-008"></a>
## ATLAS-ARCH-008 — Replace pointer-scattered containers on traversal paths [patch] — in-progress

- Owner: current session; scope for this increment is the root classifier and
  its focused tests, not provider source or the hotness-ranked conversions.
  The scanner currently traverses `repos/consus/worktrees/*`, so a peer lane is
  counted as a second provider source and makes the live site set depend on
  lane topology.
- **Current increment evidence:** the focused classifier suite is 44/44 after
  adding a lane-exclusion regression. The live scan is now 242 production and
  98 test/bench sites with zero `worktrees/` paths. The committed oracle still
  reports 35 additions and 36 removals because peer provider edits and line
  shifts are present in the shared tree; it is not regenerated from that
  unstable state.
- Outcome: 318 `Vec<Vec<_>>` occurrences across package sources, led by
  `consus-compression/src/chunking/iterator.rs` (10),
  `gaia/src/domain/topology/adjacency.rs` (8), and
  `coeus-autograd/src/ops/nn/loss/ctc.rs` (6). Adjacency and chunk iteration are
  prefetch-sensitive; a jagged per-row allocation defeats it.
- Acceptance: the contiguous form is a flat buffer plus an offset table
  (CSR-shaped) or an arena span, with a criterion comparison on the traversal
  showing the change is a win. A site where the jagged shape is genuinely correct
  is recorded as such rather than converted.
- **Evidence re-measured 2026-08-03; two of the three named sites are wrong.**
  Verify before claiming — as written this item would send someone to rewrite
  test code.
  - `consus-compression/src/chunking/iterator.rs` (listed as the worst, 10
    occurrences): **all 10 are test-local.** `#[cfg(test)] mod tests` opens at
    line 156 of a 400-line file and every occurrence is at lines 167-383, each
    a `let coords: Vec<Vec<usize>> = ChunkIterator::new(..).collect()`
    collecting an iterator's output for an assertion. That is not a container
    on a traversal path; it is a test binding, and converting it would be
    rewriting tests to suit a metric.
  - `gaia/src/domain/topology/adjacency.rs` (listed at 8): now **zero**
    occurrences. The file is 679 lines and no longer contains the pattern.
  - The raw stack-wide count is ~370, up from the recorded 318, so the
    headline number is not shrinking even though its named exemplars have
    evaporated — which is the signal that the count is measuring the pattern,
    not the defect.
- What the item still needs before it is claimable: a classifier that
  separates production containers from `#[cfg(test)]`-local and
  `tests/`/`benches/` bindings. I wrote one and do not trust it — it
  mis-classified `kwavers-math/.../lsqr/tests.rs` as production, so its
  per-repo split is not recorded here rather than recorded wrongly. The
  two corrections above were each confirmed by reading the file.
- Re-scoped acceptance: the deliverable is first a *correct site list* —
  production-only, ranked by traversal hotness rather than raw count — and
  only then the CSR conversions with their criterion evidence. A raw
  `Vec<Vec<` count is not a defect list.
- **Site list delivered 2026-08-03.** A classifier now separates production
  containers from `#[cfg(test)]`-guarded and `tests/`/`benches/`/`examples/`
  bindings, and it carries two self-checks derived from files read by hand —
  it refuses to print numbers unless it reproduces both. That gate earned its
  keep: the first version failed, because it matched only the bare
  `#[cfg(test)]` and the consus module is gated
  `#[cfg(all(test, feature = "alloc"))]`. Any cfg predicate carrying a bare
  `test` token now counts, with string literals stripped first so a
  `feature = "test-utils"` value cannot pose as the predicate.
- Verified totals: **297 production, 73 test/bench-local** (370 raw). So ~20%
  of the recorded 318 was never a defect.
- **There is no hotspot, and that changes how this item should be worked.**
  Production counts per repo are ritk 81, kwavers 70, CFDrs 46, gaia 37,
  consus 24, coeus 12, apollo 6, moirai 5, leto 2 — but the top *file* has 10
  (in a private downstream consumer, out of stack scope), the next has 6, and
  everything after is a tail of 4s and 3s across unrelated subsystems
  (`coeus-autograd/.../ctc.rs` 6; `ritk-vtk/.../poly_data.rs`,
  `ritk-filter/.../anti_alias_binary/solver.rs`,
  `cfd-optim/.../search/genetic.rs`, `consus/src/sync/mod.rs` 4 each).
  There is no "fix the top three files" increment available.
- Consequence for the acceptance oracle: ranking by *count* is worthless here.
  A claimant should pick sites by traversal hotness — profile first, per the
  measurement-first rule — and convert the ones that a profile implicates,
  recording the rest as correct-as-jagged. The classifier lives in the session
  scratchpad; it should be committed under `scripts/` if this item is claimed,
  since re-deriving it is the expensive part (toil automation).
- **Delivered 2026-08-05 — classifier committed, site list refreshed.**
  `scripts/atlas_scattered_containers_classify.py` is the committed,
  reproducible form (underscore-named and importable, matching the
  testable-script convention), with pytest coverage in
  `scripts/tests/test_atlas_scattered_containers_classify.py` (24 tests:
  production vs test/bench/example split, `#[cfg(test)]`/`mod tests`
  brace-depth tracking, comment/string/char/raw-literal stripping with
  char-vs-lifetime disambiguation and multiline-string state, `cfg(not(test))`
  and `feature = "test-utils"` exclusions, filename heuristics, semicolon-line
  leak guard, determinism). It scans only the `.gitmodules`-registered members via
  `atlas_stack.registered_members()`, so the git-ignored private consumer
  never surfaces. Refreshed verification totals on the 2026-08-05 tree:
  **260 production / 65 test-bench / 325 total**, per member — CFDrs 42/11,
  apollo 6/2, coeus 12/0, consus 20/15, gaia 34/2, kwavers 63/5, leto 3/13,
  mnemosyne 0/1, moirai 6/9, ritk 74/7. The delta vs the 2026-08-03 recording
  (297/73/370) is tree drift plus method differences: this implementation
  strips comments, string/char/raw literals and block comments before any
  matching (so a `feature = "test-utils"` value or a `"mod tests {"` template
  string cannot arm a predicate and commented `Vec<Vec<` sites are not
  counted), narrows the test-filename heuristic to `tests.rs`/`*_test.rs`/
  `bench.rs`-style names (so `test_utils.rs` helpers stay production), and
  emits root-relative site paths; the committed script is the reproducible
  oracle going forward. The production-only site list is
  regenerated with
  `python scripts/atlas_scattered_containers_classify.py --site-list
  scripts/oracles/arch-008-production-sites.txt` (see the gate bullet
  below). Ranking by traversal hotness
  (profile-first) and the conversions themselves remain the open work — this
  item stays `todo`.
- **First conversion delivered 2026-08-05 — moirai collective family.**
  `repos/moirai` `moirai-core/src/communication/collective.rs`:
  `CollectiveOps::{scatter,gather,all_to_all}` now build and traverse a
  CSR-shaped `ChunkedVec<T>` (contiguous flat buffer + chunk-offset table)
  instead of jagged `Vec<Vec<T>>`. Semantics preserved exactly (chunk tiling,
  all-to-all column truncation at the chunk count); the empty-input / zero-
  participant edge returns an empty buffer rather than the historical
  `chunks(0)` panic. Consumers were verified tests-only, so the signature
  change is contained. Criterion
  (`benchmarks/benches/collective_ops_comparison.rs`, `harness = false`,
  jagged baselines kept inline, 32/128 participants × 4096/8192 items):
  gather **~10–13×** faster (O(1) hand-off), traverse **~1.6×**, scatter
  **~1.1–2.2×**, all_to_all **~1.3–3.2×** — a win on every measured path.
  moirai-core gate: check 0, collective nextest 4/4 (round-trip, empty/
  zero-participant, all-to-all parity), strict clippy 0.
  `channel_fusion` per-channel buffers are recorded as **correct-as-jagged**:
  each channel grows and flushes independently, so a shared flat buffer would
  add reallocation complexity without a traversal win. `owned_chunks`
  (hybrid.rs) stays owned-per-worker by contract (parallel ownership model);
  it is a candidate only if its consumers move to borrowed chunks. The next
  conversion should be picked from a different repo family per the
  one-family-per-claim rule.
- **Oracle gate wired 2026-08-05 — the split can no longer drift silently.**
  `scripts/atlas_scattered_containers_classify.py --verify-oracle
  scripts/oracles/arch-008-production-sites.txt` re-verifies the current
  production split against the committed oracle (read-only; exit 0 = match,
  1 = drift, 2 = unreadable oracle), wired as `make verify-scattered-oracle`
  following the `fmt-check`/`board-lint` convention. `outputs/` is gitignored
  by design (derived state), so the oracle now lives at the tracked path
  `scripts/oracles/arch-008-production-sites.txt` and is regenerated
  deliberately with `--site-list` and committed in the same change that
  caused the drift. Oracle refresh after the moirai conversion:
  **256 production / 71 test-bench / 327 total** (per member — CFDrs 42/11,
  apollo 6/2, coeus 12/0, consus 20/15, gaia 34/2, kwavers 63/5, leto 3/13,
  mnemosyne 0/1, moirai 2/15, ritk 74/7). The sole delta vs the recorded
  260/65/325 is the moirai conversion: −4 production sites (the
  `collective.rs` family left the scattered set) and +6 test-local sites
  (the new parity tests build jagged vectors). The 2 remaining moirai
  production sites are `channel_fusion` and `owned_chunks`, both recorded
  correct-as-jagged / owned-by-contract above. Verify-mode coverage:
  `scripts/tests/test_atlas_scattered_containers_classify.py` gained
  oracle-parse, added/removed drift, blank/member-suffix tolerance, and CLI
  exit-code (0/1/2) tests (classifier suite now 32; full scripts suite 92 +
  20 subtests).
- **Spot-check 2026-08-05 — classifier matches a manual read.** Hand-verified
  the top per-member production files and the complete discrepancy set for
  ritk (74), kwavers (63), CFDrs (42): all 33 production sites in the top 3
  files per member match the oracle exactly (raw `Vec<Vec<` lines == oracle
  claims, same lines), and all 39 occurrences the classifier excluded from
  production were confirmed by hand to be comment/doc text (16 — stripped,
  never counted) or test/bench/example code (23 — counted test-local, e.g.
  the `#[cfg(test)]`-guarded `clahe_2d` in interpolate.rs:168 and the
  `#[cfg(test)] mod tests` VOF reconstruction.rs cases exercise the
  brace-depth path; `tests.rs`/`tests/`/`examples/` paths exercise the
  heuristics). Zero production code misclassified as test and zero test code
  counted as production. Read-only; no tree edits.
- **Spot-check 2026-08-05 — mid-count members + claimed-sites sweep; classifier
  extended; oracle corrected 256/71 → 250/77.** Hand-verified the six remaining
  members (gaia 34, consus 20, coeus 12, apollo 6, leto 3, mnemosyne 0) with
  the same discrepancy-set method: every top-file raw `Vec<Vec<` line matches
  the oracle claims (all 34 gaia, 20 consus, 12 coeus, 6 apollo, 3 leto
  claims), every excluded occurrence (doc comments, in-file `#[cfg(test)]` /
  `mod tests` regions, `tests/`/`examples/` paths) confirmed non-production,
  and a reverse stale-check confirmed all 75 mid-count claims point at live
  `Vec<Vec<` lines. The claimed-sites direction then surfaced a genuine
  classifier blind spot: it could not see **include-site gates**
  (`#[cfg(test)] mod <name>;` declared in a parent module) or bare
  `#[test]`/`proptest!` regions, so whole test-only files were misreported as
  production. The earlier top-member spot-check verified the excluded-direction
  only; the claimed-sites sweep here is what caught the remaining sites.
- **Classifier fix.** `compute_test_regions` now also treats `#[test]`
  attributes and `proptest! {` blocks as test regions, and `classify_file`
  gains `_is_include_gated`: it locates the file's `mod <name>;` declaration
  (`dir/mod.rs`, sibling `dir.rs`, `src/lib.rs`/`src/main.rs`, or crate-root
  `mod <dir>;` for `dir/mod.rs`) and checks the stacked attributes directly
  above it, stopping at the first non-attribute line so a cfg attribute of a
  *previous* declaration never leaks (the `boolean_csg` regression: its
  `#[cfg(test)]` belongs to the neighbouring `adversarial_tests_2`, and its
  claims are genuinely production). Files loaded under an arbitrary module
  name via `#[path = "..."]` (e.g. `#[cfg(test)] #[path = "tests_ply.rs"]
  mod tests;`) are covered by a per-member `#[path]`-declaration map keyed by
  the *resolved* target path (`#[path]` is relative to the declaring file's
  directory) — a basename key would collide on the many `mod.rs` modules and
  wrongly gate unrelated production files (caught live: the MGH reader, DICOM
  directory scanner and DICOM Association SCU `mod.rs` files are production
  and stay claimed). 11 new unit tests (classifier suite now 43) cover
  include-gated module, plain include, previous-declaration leak, dir module,
  `#[test]` fn, `#[test]` non-leak, `proptest!` block, and the `#[path]` map
  + stacked-attribute gate. Residual, deliberately-conservative blind spots
  (test code kept as production, never the reverse): a `mod foo;` nested
  inside an in-file `#[cfg(test)]` block of the parent, a `//` comment between
  the attribute and the `mod` declaration, `#[cfg_attr(test, ...)]`, and
  parenthesized `proptest!(...)`.
- **Corrected oracle: 250 production / 77 test-bench / 327 total** (was
  256/71 — total unchanged, pure reclassification). Six sites moved
  production → test-local, all hand-verified genuine test code: consus
  `reader_proptest.rs:151` and `tests_extra.rs:101` (include-gated), and ritk
  `tests_staple.rs:142,243` (include-gated) and `tests_ply.rs:89,123`
  (include-gated via stacked `#[path]` attribute, plus `#[test]` regions).
  Corrected per-member split: CFDrs 42/11, apollo 6/2, coeus 12/0, consus
  18/17, gaia 34/2, kwavers 63/5, leto 3/13, mnemosyne 0/1, moirai 2/15,
  ritk 70/11. Final independent verification: all 250 committed claims are
  live `Vec<Vec<` lines and none classify as test under the committed logic;
  `make verify-scattered-oracle` passes on the corrected oracle.
- **Second conversion 2026-08-05 — ritk-vtk Laplacian adjacency family.**
  `repos/ritk` `ritk-vtk/src/domain/filters/smooth.rs`: the smoothing
  filter's `build_adjacency`/`laplacian_step` now use a CSR-shaped
  `Adjacency` (contiguous `neighbors` buffer + per-vertex `offsets` table —
  the VTK `VtkCellArray` layout) instead of jagged `Vec<Vec<u32>>`. The
  build is jagged-free (degree count → prefix-sum offsets → direct flat fill
  → in-place sort+dedup per run), so the oracle site `smooth.rs:133`
  disappears rather than moves; the sorted/deduped layout is fully
  deterministic where the old `HashSet` build left neighbor order
  implementation-defined. Neighbor *sets* are unchanged, so filter results
  are preserved to within the existing 1e-5 test tolerance; a parity test
  pins the CSR runs against the sorted jagged reference (polygon + line
  edges, an isolated vertex, and a quad-grid interior vertex with its four
  edge-sharing neighbors sorted/deduped). `Adjacency` and `Adjacency::build`
  become documented public API (the only API change; `laplacian_step` stays
  private) so the criterion bench measures the production path. Criterion
  (`crates/ritk-vtk/benches/smooth_adjacency_comparison.rs`, `harness =
  false`, jagged baseline kept inline, 4096/16384-vertex quad grids): build
  **~7.8× at 4096 / ~8.5× at 16384** faster (857.7→110.5 µs / 3.523→0.415
  ms) — the CSR build replaces one `HashSet` allocation per vertex with a
  single flat buffer; traversal **~1.07× at 16384** (78.5→73.2 µs) and
  statistically flat at 4096, the short degree-4 runs amortizing the layout
  win — the honest headline is the build, which runs once per filter
  invocation while traversal runs once per iteration. Oracle regenerated to
  **249/78/327** (ritk 69/12): the smooth.rs production claim moved to the
  bench baseline, where the pre-conversion formulation lives by design
  (mirroring the moirai bench precedent). Gate: `ritk-vtk` nextest 258/258,
  warning-denied Clippy, fmt clean, `make verify-scattered-oracle` exit 0.
  The other named ritk families were assessed and deliberately left
  unclaimed this slice: `ritk-filter/.../anti_alias_binary/solver.rs`
  layers are a push-front/pop-front work-queue — CSR would turn every front
  insert into an O(n) memmove across all layers (**correct-as-jagged**),
  and `ritk-vtk poly_data.rs` cell arrays are the native CSR end state but a
  ~225-reference data-model migration that warrants its own dedicated claim.
- **Third conversion 2026-08-05 — Apollo CWT output buffer.**
  `repos/apollo/crates/apollo-wavelet/src/application/execution/plan/cwt.rs`
  now collects the row-major `(scales, signal_len)` coefficient matrix through
  `moirai::map_collect_index_with::<moirai::Adaptive>` into one flat buffer,
  then reshapes it into the existing `leto::Array2`. This removes the
  per-scale `Vec<Vec<f64>>` intermediate and its row allocations while
  preserving indexed output order, adaptive parallel execution, and the public
  `CwtCoefficients` API. The flattened dimension is checked with `checked_mul`
  and returns `CoefficientShapeMismatch` on overflow. The selected production
  site is gone rather than moved; no DWT coefficient API was changed because
  those vectors represent intentionally level-shaped detail bands and remain
  correct-as-jagged for this slice. Evidence: Apollo `cargo check -p
  apollo-wavelet`, rustfmt, strict Clippy, doctests, and `cargo nextest run -p
  apollo-wavelet --lib` **21/21** pass; `git diff --check` and the targeted
  no-`Vec<Vec<` residue scan are clean. The separate oracle gate reports the
  expected single stale claim at `cwt.rs:72` (current split **248 production /
  78 test-bench / 326 total**); oracle refresh is intentionally deferred because
  `scripts/atlas_scattered_containers_classify.py` and
  `scripts/oracles/arch-008-production-sites.txt` are pre-existing untracked
  artifacts owned by the concurrent root oracle stream. Re-run
  `--site-list` and `make verify-scattered-oracle` when that stream lands the
  derived artifacts.
- **Fourth conversion 2026-08-05 — Apollo prime-pair macro tables.**
  `repos/apollo/crates/apollo-fft-macros/src/prime_pair_tables.rs` now keeps
  expansion-time cosine/sine values in flat `Vec<f64>` buffers and chunks them
  only while emitting the unchanged fixed-size `[[T; H]; H]` token arrays. This
  removes the nested `Vec<Vec<f64>>` allocation and preserves row-major token
  order and the `PrimePairTable<N, H>` API. Zero-height inputs avoid
  `chunks_exact(0)`; zero `N` and `H × H` overflow return deliberate procedural
  macro compile errors. Evidence: macro/FFT checks, rustfmt, strict Clippy,
  doctests, and `cargo nextest run -p apollo-fft --lib` **394/394** pass;
  targeted diff and nested-vector residue checks are clean. The ARCH-008 oracle
  remains deferred exactly as recorded above because its classifier/oracle files
  are owned untracked artifacts in the concurrent root stream.
- **Site investigated and recorded correct-as-jagged 2026-08-07 — CFDrs
  spectral-element global assembly.** Converted
  `repos/CFDrs/crates/cfd-math/src/high_order/spectral/assembly.rs`
  (`GlobalAssembly.element_dofs` + `SpectralMesh.element_connectivity`,
  oracle sites `assembly.rs:14,25,140`) to CSR-shaped flat offset+index
  storage with the input shape preserved, then measured it. The criterion
  comparison (DOF-traversal read, 2 000×8 / 2 000×32 / 500×128 elements×DOFs)
  showed the flat buffer is consistently **~1.2–1.6× slower** than the jagged
  rows for the isolated read (CSR 3.5/7.2/6.2 µs vs jagged 2.1/6.0/5.5 µs):
  the fixed-size spectral rows are small and cache-resident either way, and
  the flat slice window pays two bounds checks the direct `Vec` row does not.
  The whole-`add_element_matrix` variant was dominated by unbounded COO
  accumulation (bench-design noise), not DOF access. The conversion was
  **reverted** and the site is recorded as correct-as-jagged: no traversal
  hotness, no criterion win — converting it would trade memory for a
  measurable slowdown. No oracle change needed (the sites remain live
  `Vec<Vec<` occurrences, correctly classified as production).
- **Fifth conversion 2026-08-07 — Leto L-BFGS ring buffer.**
  `repos/leto/crates/leto-ops/src/application/optimization/lbfgs.rs`
  `LbfgsMemory` now keeps correction pairs in two CSR-shaped flat ring
  buffers `s_buf`/`y_buf` (capacity `memory * n`) plus a scalar
  `rho_buf` (capacity `memory`) addressed by a single `head` index
  modulo `memory`, replacing the previous `Vec<Vec<f64>>` history
  with `Vec::remove(0)` eviction. The public API
  (`new`/`len`/`is_empty`/`direction`/`push`) is preserved; downstream
  `kwavers-solver` FWI callers (`elastic_fwi/inversion.rs`,
  `time_domain/quasi_newton.rs`) recompile against the new API without
  changes. The two-loop recursion in `direction` was re-derived against
  Nocedal & Wright Alg. 7.5: under the ring's logical-index convention
  (`pair_slot(0)` = newest, `pair_slot(k-1)` = oldest), the first pass
  walks `0..k` (newest→oldest) and the second pass `(0..k).rev()`
  (oldest→newest); a self-authored regression test
  (`direction_preserves_two_loop_after_wrap`) verifies value-semantic
  agreement with an independent jagged-reference implementation after a
  full ring wrap, and a saturation test verifies oldest-pair eviction.
  Criterion baseline comparison over the acceptance-oracle grid
  `{8,32}×{100,1000}` (median [lo hi], µs):

  | config | ring (new) | jagged (baseline) |
  |---|---|---|
  | m8_n100   | 1.71 [1.65 1.79]  | 1.78 [1.71 1.88] |
  | m32_n100  | 6.68 [6.31 7.04]  | 7.48 [7.14 7.79] |
  | m8_n1000  | 15.42 [14.61 16.24] | 16.36 [15.79 16.87] |
  | m32_n1000 | 75.00 [71.45 79.08] | 66.19 [63.35 70.11] |

  The flat ring wins at small dim (≤+13% over jagged, fewer allocations),
  is parity at `m8_n1000` (memory traffic dominates over allocation
  savings), and is **~13% slower** at `m32_n1000`: the large memory plus
  large dim regime has the ring doing `% memory` slot resolution per
  two-loop step against two big contiguous buffers while jagged has
  `memory` individual `Vec` allocations with one prefetcher-tight inner
  scan per row. The conversion's primary win is allocation/eviction
  elimination (no `Vec::remove(0)`, one allocation at construction
  instead of per-`push`), not raw throughput at high `m × n` — that is
  the honest baseline and is recorded here per the performance gate.
  Evidence: `cargo nextest run -p leto-ops --lib` **178/178** (176
  baseline + 2 new regression tests), `cargo test --doc -p leto-ops`
  20/20 + 1 ignored, `cargo clippy -p leto-ops --lib -- -D warnings`
  clean, `cargo fmt -p leto-ops -- --check` clean,
  `cargo check -p kwavers-solver --no-default-features` clean. The
  criterion bench `crates/leto-ops/benches/lbfgs.rs` is registered with
  `harness = false` and smoke-runs in single-iteration mode (`-- --test`)
  within the test budget; full timing runs fit the 300s/binary budget.
- **Delivery**: leto PR #96 (`fix/leto-ops-lbfgs-ring-buffer`), commit
  `1ed166a`, branch pushed to origin. **Not merged — blocked on a leto CI
  infrastructure defect at `db9a63c` (origin/main HEAD)**: Codex's Aug-7
  commit replaced the `git = "..."` workspace declarations for `mnemosyne`/
  `moirai`/`hermes-simd`/`eunomia`/`aequitas`/`themis` with `path =
  "../..."` for local meta-repo convenience, which resolves locally (meta-
  repo `.cargo/config.toml` `[patch]` overlay redirects the URL sources to
  local paths either way) but is unresolvable in leto's standalone CI
  checkout (`cargo metadata` fails to read `../aequitas/Cargo.toml`).
  Pre-existing in main, unrelated to this PR — leto's prior main CI run was
  already red for the same reason. Codex's `LETO-INTO-ITERATOR-1` dirty
  state is present in the leto working tree iterating on `leto/array.rs`,
  `leto/src/application/iter/*`, `leto/src/lib.rs`, `leto/tests/core/
  iteration.rs`, plus unrelated `leto-ops/{lu_symbolic.rs, sparse/mod.rs,
  parallel.rs, lib.rs}` files — the workspace `Cargo.toml` is theirs by
  precedent and outside the file-disjoint scope of this lbfgs slice.
  Per `concurrent_agents: Contention response order`, PR #96 stays open
  with the peer's landing as its re-open trigger. **Re-open trigger**:
  leto CI on main turns green (Codex lands the CI fix forward), OR a
  future disjoint slice puts me in a position where
  `repos/leto/Cargo.toml` workspace section falls under my scope.
- **Out-of-scope finding recorded** (kwavers-math `optimization/lbfgs.rs`
  is a full duplicate `LbfgsMemory` implementation, not the re-export the
  ATLAS-MATH-SSOT-CONSOLIDATION-1 Lane B residual table records; see Lane
  B residual (5)). Not converted in this slice: out of the leto-local
  file-disjoint scope, peer-active territory.
- **Sixth conversion 2026-08-08 — consus-zarr chunk selection indices.**
  `repos/consus` `consus-zarr/src/chunk/ops.rs` `selection_indices`
  (`Vec<Vec<u64>>`, one allocation per selection dimension) is replaced by a
  CSR-shaped `SelectionIndices` (`flat: Vec<u64>` contiguous buffer +
  `offsets: Vec<usize>` offset table) built once per read/write call; both
  copy helpers (`copy_chunk_selection_to_output`, `copy_selection_input_to_chunk`)
  hoist `dims: Vec<&[u64]>` per call so the traversal hot loop does one
  indirection (`dims[dim][selection_position[dim]]`) instead of two, and all
  three call sites (`read_array`, `write_array_selection`, `read_array_sharded`)
  use the same `SelectionIndices::build`. Criterion
  (`crates/consus-zarr/benches/zarr_selection_copy.rs`, `harness = false`,
  faithful jagged replica of the non-sharded `read_array` kept inline as a
  baseline; byte-parity assertion pins the replica to production output
  before timing; 2d 256×256 / 2d 512×512 / 3d 64³ strided×2 selections on a
  populated `InMemoryStore`): CSR is a win on every case — **−4.7% /
  −6.5% / −10.9% time vs jagged** (criterion `change`, p < 0.05; within-run
  medians 6.50/25.75/33.8 ms vs 6.96/26.40/36.6 ms). Gate: `cargo clippy -p
  consus-zarr --all-features --all-targets -- -D warnings` clean, nextest
  `303/303`, doctests clean, fmt clean; CI `--all-features` clippy+check
  green on PR #13. **Oracle refreshed to 243 production / 80 test-bench /
  323 total**: the consus-zarr `ops.rs` production site is gone; coeus
  `ctc.rs` 408-410 → 353-355 (line shift from a peer PR, same sites); leto
  `lbfgs.rs:79,80` added (genuine `Vec<Vec<f64>>` in `LbfgsMemory`,
  hand-verified; the conversion's ring buffers are flat so the site moved,
  it did not stay). `--verify-oracle` exit 0 on the refreshed oracle.
  Delivery: consus PR #13, branch `refactor/consus-zarr-csr-selection-indices`
  (commits `3ce79b0` conversion + `d3d5b19` mechanical rustfmt of two
  pre-existing-dirty consus-core book examples that had kept the
  workspace-wide Format CI job red at HEAD, blocking the Check job for every
  PR). Residual: pre-existing untracked meta-repo scratch (`.commandcode/`,
  `libtest_*.rlib`) and peer-held `version-guard`/`gitlink-coherence` changes
  are untouched.

