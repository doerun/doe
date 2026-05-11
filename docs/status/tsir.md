# Doe status: TSIR

This is a live topical status shard for the Tiled Spatial IR (TSIR) work
defined in [`docs/tsir-lowering-plan.md`](../tsir-lowering-plan.md) and
sequenced by [`docs/loop-protocol.md`](../loop-protocol.md). Follow the shared
shard policy in [`README.md`](README.md).

Parity receipts themselves land under `reports/parity/` and are bound into
Doppler manifests at `integrityExtensions.lowerings[]`; this shard is narrative
status, not the receipt surface.

This shard exists because `compiler-and-webgpu.md` outgrew its old shard
target once the TSIR Phase A landings started. The deep 2026-04-24
TSIR Step 7-12 block now lives under
[`archive/2026-04-24-tsir.md`](archive/2026-04-24-tsir.md); older TSIR history
(2026-04-23 TSIR Step 4 increments) lives in
[`archive/2026-04-02-to-2026-04-15.md`](archive/2026-04-02-to-2026-04-15.md)
(tail block). New TSIR entries go here going forward.

## 2026-04-27 — Qwen 3.6-27B audit: TSIR / CSL emit gap list

Audit of what Qwen 3.6-27B (or any current Qwen 3.5 architecture extended to
27B) needs from the TSIR + CSL spatial-lowering path that Gemma 4 31B currently
travels. Trigger: Doppler already runs Qwen 3.5 (0.8B and 2B) in production
through the same Program Bundle shape, so the next Cerebras-lane refresh-loop
target is queued to be Qwen 3.6-27B once the gaps below are typed-rejected or
lowered. Findings are against:

- `runtime/zig/src/tsir/schema.zig`
- `runtime/zig/src/tsir/emit_kernel_body.zig`
- `runtime/zig/src/tsir/emit_kernel_body_attention.zig`
- `runtime/zig/src/doe_wgsl/emit_csl_rope.zig`
- `runtime/zig/src/doe_wgsl/emit_csl_layout.zig`

### Already covered (no Doe-side change needed)

- **GQA shape (`num_q_heads != num_kv_heads`).** `AttentionScoresBody` is
  per-head; `head_dim` is the only head-level field
  (`schema.zig:451-474`). Q→KV head mapping is the host plan's job, not the
  body's. Qwen 3.5-2B's 8:2 GQA ratio already rides through Doppler's bundle
  shape without an attention-body change; Doe's host plan binds the right
  K/V slice per Q head.
- **Partial-rotary RoPE (`partialRotaryFactor < 1.0`).** `emit_csl_rope.zig`
  iterates `num_pairs` rotation pairs as a CSL `param`
  (`emit_csl_rope.zig:33,51`). The kernel never assumes `num_pairs ==
  head_dim/2`; the layout emitter just supplies a `head_dim=128, num_pairs=64`
  *default* (`emit_csl_layout.zig:313-314`) that the driver's `--params`
  invocation overrides. For Qwen 3.5 (`head_dim=128`,
  `partialRotaryFactor=0.25`) the host wires `num_pairs=16`. No CSL emit
  change required; the host plan just needs to source `num_pairs` from
  `manifest.attention.rotary.partialRotaryFactor` instead of `head_dim/2`.
- **Per-head Q/K RMSNorm (`queryKeyNorm: true`).** Doppler implements this as
  a separate rms_norm dispatch (`doppler/src/inference/pipelines/text/attention/run.js:419`,
  `applyAttentionQKNorm`). It rides through Doe's existing
  `SemanticBodyOp.rms_norm` for free as additional kernel invocations between
  QKV projection and attention.

### Typed-blocker gaps (would require a Doe-side body / emit change)

- **`SemanticBodyOp` has no `rope` variant.** The schema enum
  (`schema.zig:271-305`) covers `rms_norm`, `gather`, `kv_write`, `kv_read`,
  `attention_scores`, etc., but not `rope`. RoPE today is handled at the
  `doe_wgsl` layer (a separate WGSL-pattern → CSL transpiler) rather than as
  a TSIR semantic body. Promoting RoPE to a TSIR body op is required if RoPE
  needs to participate in TSIR cross-backend canaries the way attention does.
  Not a Qwen 3.6 blocker if RoPE keeps riding through `doe_wgsl` only.
- **Causal mask in `AttentionScoresBody`.**
  `emit_kernel_body_attention.zig:59` rejects
  `causal_mode != .none` with `error.InvalidBodyContract`. Qwen 3.6 prefill
  uses standard causal masking; the unified-emit path is decode-only until
  causal lowering lands. Manifest-shape simfabric proof of concept for Qwen
  prefill is gated on this. Decode-only / single-token receipts can avoid
  it. Same blocker the Gemma 4 31B prefill simfabric ladder still carries.
- **Sigmoid-gated activation (`attentionOutputGate: true`).** Qwen 3 applies
  `sigmoid(qGateProjection) * attnOutput` before the O projection
  (`doppler/.../attention/run.js:893-902`, `gateActivation: 'sigmoid'`).
  Doe's `SemanticBodyOp.gelu_gated` is GELU-shaped only
  (`schema.zig:285`). Either generalize to a `gated_activation` body with a
  `kind ∈ {gelu, sigmoid, silu}` field, or add a sibling `sigmoid_gated`
  variant. Same emit shape as `gelu_gated`, just a different scalar
  activation in the inner loop. Qwen 3 SwiGLU FFN
  (`silu(gate) * x`) needs the same generalization.
- **Softcap (`tanh(s/cap)·cap`).** Currently rejected
  (`emit_kernel_body_attention.zig:60`); affects Gemma-style attention not
  Qwen, called out here only because it lives in the same emit body and
  closing causal usually ships alongside softcap.

### Non-blockers for the existing receipt surface

The Doe-WebGPU end-to-end runner does not go through the unified
`attention_scores` emit; it runs Doppler's WGSL kernel closure directly
through Doe's WebGPU runtime, where causal/softcap/sigmoid-gate/SwiGLU all
ride through the kernel body verbatim. Qwen 3.6-27B going through the
*Doe-WebGPU vs Doppler reference parity* receipt is unblocked today
modulo bundle availability; only the *Cerebras-lane simfabric* receipt
needs the body-emit gaps closed.

## 2026-04-25 — CSL RMSNorm emitters use sqrt_nr wrapper

TSIR CSL RMSNorm emission no longer writes raw `math.sqrt(mean_sq + eps)` into
the production PE body. `runtime/zig/src/tsir/emit_kernel_body.zig` now emits a
`sqrt_nr` helper (`math.sqrt` seed plus one Newton refinement) and computes
`inv_rms` through that helper. The shared WGSL-to-CSL reduction walker also has
a configurable sqrt target; `emit_csl_reduction.zig` sets it to `sqrt_nr`, and
the distributed reduction emitter uses the same wrapper.

This keeps future generated RMSNorm CSL inside the C12 self-check contract that
WSE production kernels must not call raw `math.sqrt` except inside the
NR-refined wrapper.

## 2026-04-25 — KV cache CSL wrapper narrowed to TSIR body emission

`runtime/zig/src/doe_wgsl/emit_csl_kv_cache.zig` is now just the WGSL-name
adapter for TSIR `kv_write` / `kv_read` body ops. The unused hand-maintained
storage-pointer / compile-time export helpers were removed so the live body
path has a single source: `runtime/zig/src/tsir/emit_kernel_body.zig`.

Coverage added in `emit_csl_host_compile_source.zig` locks the HostPlan compile
source output for both KV patterns: `kv_write` must use the TSIR decode-position
loop and export `position`; `kv_read` must use the TSIR read window loop. Both
tests assert the legacy toy `gid.x` WGSL body does not leak into the CSL PE
program.

## 2026-04-24 — Move 4: first real-kernel fixture (`embed`) lands

First real-kernel TSIR fixture under `runtime/zig/tests/tsir/real/embed/`:

- `embed.wgsl` — pinned snapshot of Doppler's production embedding
  gather (`src/gpu/kernels/gather.wgsl`), independent of the
  bootstrap catalog's minimal gather.
- `embed.tsir-semantic.json` — hand-sketched TSIR semantic with
  `familyHint=embed`, body op `gather`, pinned frontend version.
  Validates against `config/doe-tsir-semantic.schema.json`.
- `embed.tsir-realization.wse3.json` — hand-sketched realization
  for WSE-3 at Gemma 4 E2B scale (num_tokens=32, hidden_size=1536,
  vocab_size=262144). Output pe_sliced on token axis (shards=8, 4
  tokens/PE × 1536 × 4 = 24 KiB per PE) avoids the 192 KiB per-PE
  output overflow WS4 characterized. Table fabric_streamed on color
  0 (1.5 GiB total cannot pe_replicate or pe_slice). Validates
  against `config/doe-tsir-realization.schema.json`.
- `embed.tsir-realization.webgpu-generic.json` — webgpu-generic
  realization is pe_replicated (adapter memory hosts table).
  Under Move 2, Doppler's browser WebGPU is authoritative for this
  lane; Doe does not emit WGSL bodies for real kernels.
- `embed.notes.md` — per-PE budget math, decision rules, and a
  validation plan naming the `frontend.zig` / `planner.zig` /
  `emit_kernel_body.zig` extensions the follow-on engineer must
  land to produce this realization from the WGSL.

`bench/tools/doe_tsir_convert_lowering.py` gains a
`REAL_KERNEL_FIXTURES` registry and routing. Registered real-kernel
refs (currently just `embed`) produce a fixture-specific rejection
detail that cites the notes.md and names the exact compiler-extension
surfaces. Unregistered real-kernel refs (e.g.
`doe.tsir.real.lm_head_gemv`) produce a blanket rejection
pointing at Move 4. 22 tests total in
`bench/tests/test_doe_tsir_convert_lowering.py`; 56 across that and
`test_doe_parity.py`.

**What Move 4 does NOT yet land**: the Zig compiler extensions
themselves. The fixture is the target shape and the validation plan;
producing that shape from the WGSL is still open compiler work. The
orchestrator now routes `doe.tsir.real.embed` to a rejection that
names the work instead of a generic "not yet covered" message, so the
remaining gap is audit-visible from receipts alone.

Next real-kernel fixture to sketch: `lm_head_gemv` (reuses
`fused_gemv` body, adds `out_dim`-sharding residency at Gemma 4 E2B
vocab scale). Then `attn_head256` / `attn_head512` (Move 5 — adds
`attn_head` body op with `stream_kv_tiles` residency).

## 2026-04-24 — TSIR plan re-scoped to Gemma-on-Cerebras, reference inverted

`docs/tsir-lowering-plan.md` has been re-scoped. The five moves are
documented in the updated "Scope and phasing" section of the plan and
drive the remaining mechanical-emit and per-kernel-family parity work:

1. **Reference inversion.** For real kernels, `doppler.reference-transcript/v1`
   from Doppler's browser WebGPU run is the parity reference, not the
   Zig scalar interpreter. The Zig oracle stays authoritative for the
   bootstrap catalog (`fused_gemv`, `rms_norm`, `gather`). The parity
   CLI will carry a `referenceSource` field naming which regime gated
   each receipt.
2. **CSL is the sole critical-path backend.** `emit_csl.zig` must
   reach body parity for real kernels. `emit_webgpu.zig`,
   `emit_msl.zig`, `emit_dxil.zig`, `emit_spir_v.zig` stay at their
   current semantic-aware-where-bootstrap / skeleton-elsewhere level;
   real-kernel body parity for those is post-WS3.
3. **AOT convert-time lowering (step 11) promoted ahead of kernel
   rewrites (step 9).** Doppler's convert stage will invoke TSIR
   lowering for each declared kernel and emit parity receipts +
   manifest bindings as convert outputs. This drives frontend coverage
   off real models instead of off a family-sequencing decision.
4. **WS4's per-PE blockers drive first real-kernel selection.**
   `embed`, `lm_head_gemv`, `attn_head256`, `attn_head512`
   become the first non-bootstrap families through TSIR. The planner
   gains residency classes for `hidden_per_pe`, `out_dim` sharding,
   and `stream_kv_tiles`.
5. **Phase B narrows to the Gemma 4 E2B attention variant.** Sollya
   polynomials, flash-style streaming attention, sliding-window, and
   paged KV drop out of Phase B and become post-WS3.

WS3 closure condition is now explicitly defined in the plan's
"WS3 closure condition" section: `doppler bundle` for
`gemma-4-e2b-it-q4k-ehf16-af32` produces passing `reports/parity/*`
against Doppler reference transcripts for the four WS4 blockers, plus
rope/rmsnorm/elementwise/dequant/sample as they are touched, with
lowering entries bound into the Gemma 4 E2B manifest.

Current bootstrap state (below) is unchanged; the re-scope is a
forward-looking plan change, not a retroactive relabeling of the
bootstrap receipts already landed.

## 2026-04-24 — reference lane green end-to-end; reports/parity/ populated; first Doppler manifest bound

- Added input-tensor fixtures under
  `bench/fixtures/tsir-bootstrap-inputs/{fused_gemv,rms_norm,gather}.json`.
  The Zig bootstrap oracle executes against these and emits real
  reference hashes for all three bootstrap kernels.
- `bench/gates/nightly_tsir_parity_canary.py` now pairs each
  `tsir-manifest-entries/*.json` fixture with its matching input-tensor
  fixture by kernel name. Previously the canary passed the manifest
  fixture itself as `--inputs`, which the oracle could not parse, so
  every receipt fell to `reference=not_implemented`.
- All six receipts under
  `bench/out/nightly-tsir-parity-canary/receipts/*/` now report
  `reference=pass` with backend-agnostic reference hashes bound to each
  fixture's `loweringIdentity`. Backend lanes (`webgpu`,
  `csl-simfabric`) honestly report `deferred` with
  `reason=reference=pass, backend=not_implemented` — backend-execution
  wiring remains unlanded. No lane is claimed to pass that has not
  actually executed.
- Populated `reports/parity/{kernel}.{backend}/` with the same six
  receipts under this session's oracle. This is the first time the
  Step 9 receipt directory exists with non-stub content.
- Bound all six bootstrap lowering entries into two live Doppler
  manifests — `gemma-3-270m-it-q4k-ehf16-af32` and
  `gemma-3-1b-it-q4k-ehf16-af32` — via
  `bench/tools/bind_bootstrap_lowerings_to_manifest.mjs`. Doppler's
  `validateManifest` is clean on both; `listSupportedBackends` returns
  both `webgpu-generic` and `wse3` for the three bootstrap kernels;
  `findLoweringOrThrow` returns normalized entries with
  `sha256:`-prefixed digests and the Doppler-hyphenated exactness
  class. The binder is safe to re-run on additional manifests in the
  family without regenerating receipts because the identity digests
  come from the shared Doe fixtures.
- Placeholders / follow-ups still tracked:
  - WebGPU and CSL-simfabric execution lanes in `doe_parity.py`
    remain `not_implemented` by design. Wiring each lane requires a
    per-kernel runner that can produce the same `referenceHash` shape
    for comparison; neither has landed.
  - Bootstrap-kernel lowerings are the first real entries in a live
    manifest, but they do not yet cover real Gemma kernels. Real
    Gemma-kernel TSIR semantics + realizations + target-correctness
    hashes are needed before a real-Doppler-family parity lane is
    more than a bootstrap-shape proof.
  - `targetDescriptorCorrectnessHash` in the Doe fixtures is
    normalized to `targetDescriptorHash` on the Doppler side; both
    names resolve to the same value via
    `normalizeManifestLoweringEntry`.

## Phase A status at a glance

Compiler surface by plan step (see
[`docs/tsir-lowering-plan.md`](../tsir-lowering-plan.md) for the full
plan). This is a shape summary — file paths name what exists, not
how much. For iteration cadence see
[`docs/loop-protocol.md`](../loop-protocol.md).

| Step | Artifact | State |
| --- | --- | --- |
| Step 1 oracle | `runtime/zig/src/tsir/reference_interpreter.zig` | Recognizes fused_gemv / gather / rms_norm across {f32, f16, bf16} with strict_ordered + associative_allowed reductions + literal/uniform epsilon. Unsupported shapes fail closed with `NotImplemented`. |
| Step 1.5 bootstrap | `runtime/zig/tests/tsir/bootstrap/` | Pinned WGSL + hand-sketched `.tsir-semantic.json` + per-target realization sketches for fused_gemv, rms_norm, gather. |
| Step 2 descriptors | `runtime/zig/src/targets/{webgpu_generic,wse3,mod}.zig` | Correctness/planner field split; `RuntimeSizedBindingPolicy`; pairwise-distinct descriptor hashes. |
| Step 3 schema | `runtime/zig/src/tsir/schema.zig` + `config/doe-tsir-*.schema.json` | Semantic/realization split with canonical digests; RMSNorm body contract + uniform-field epsilon with binding/offset plumbing. |
| Step 4 frontend | `runtime/zig/src/tsir/frontend.zig` | Lowers all three bootstrap families to their declared body ops; axis recovery + reduction recovery + body inference (per family) + epsilon resolution. |
| Step 5 planner | `runtime/zig/src/tsir/planner.zig` | `planRealization` produces deterministic `RealizationFunction` records for both descriptors; residency / tile factors / PE grid / reduction tree / typed rejection. |
| Step 6 collectives | `runtime/zig/src/tsir/collective_synthesis.zig` (planner calls in); frontend walker still owns semantic collection | Dedicated pass file isolates descriptor-backed native-capability / exactness / fabric-color-budget logic with typed rejections. Bootstrap families still have no collectives to exercise it; attention (Phase B) consumes this pass. |
| Step 7 emitter | `runtime/zig/src/tsir/emit_{kernel_body,csl,webgpu,msl,dxil,spir_v,text_skeleton}.zig` | Realization-only skeleton entry points remain for contract inspection; semantic-aware entry points emit executable fused_gemv / rms_norm / gather bodies across WebGPU, CSL, MSL, DXIL/HLSL, and SPIR-V/GLSL surfaces. Source-backed `emitterCodeDigest()` includes shared body source and remains pairwise-distinct by test. |
| Step 8 parity CLI | `bench/tools/doe_parity.py` + `runtime/zig/src/tsir_bootstrap_oracle.zig` + `bench/gates/nightly_tsir_parity_canary.py` + `bench/fixtures/tsir-bootstrap-inputs/*.json` | Narrow bootstrap oracle executes fused_gemv / rms_norm / gather input JSONs through the built Zig reference subprocess and writes real reference hashes. Canary pairs each manifest-entry fixture with its input-tensor fixture by kernel name; all six receipts now carry `reference=pass`. Backend execution lanes still return `not_implemented` / `deferred`; WebGPU/CSL execution wiring remains unlanded. |
| Step 9 family rewrites | `reports/parity/{fused_gemv,rms_norm,gather}.{webgpu-generic,wse3}/` | **3/3 bootstrap kernels have reference-lane-green receipts at both targets.** Backend-lane `pass` still gated on Step 8 execution wiring. Real Gemma-kernel receipts still unlanded (bootstrap proves plumbing, not family coverage). |
| Step 10 manifest binding | `bench/tools/tsir_manifest_lowering.py` + `bench/fixtures/tsir-manifest-entries/*.json` + `bench/tools/bind_bootstrap_lowerings_to_manifest.mjs` | Schema, builder, six bootstrap fixtures; receipt ↔ fixture identity lockstep + fixture version + descriptor uniformity locked by test. Live binding shipped to two Doppler manifests — `gemma-3-270m-it-q4k-ehf16-af32` and `gemma-3-1b-it-q4k-ehf16-af32` — each carrying all six bootstrap lowering entries in `integrityExtensions.lowerings[]`; Doppler `validateManifest` and `listSupportedBackends` accept both. |
| Step 11 AOT convert | — | Unlanded; cache-key design pending. |
| Step 12 rollout | — | Unlanded. |

Gates protecting Phase A artifacts:

*Repo-wide hygiene:*

- `bench/gates/doe_private_strategy_leak_gate.py` — private-strategy
  leak guard (Doe docs must not contain upstream-repo path or
  competitive-framing patterns).
- `runtime/zig/tools/check_line_limits.py` — 999-line Zig source cap;
  three TSIR modules allowlisted with tracked sharding follow-ups.
- `bench/tests/test_doc_link_coverage.py` — in-repo markdown link
  integrity across `docs/**` + root-level markdown.

*Rejection / exactness taxonomy:*

- `test_rejection_taxonomy_is_consistent_across_schemas` — rejection
  taxonomy lockstep across the four JSON schemas + Python CLI.
- Zig `test "rejection taxonomy is exhaustive and enumerable"` —
  Zig canonical enum.

*Bootstrap catalog ↔ manifest fixture chain:*

- `test_every_wgsl_has_semantic_sketch` + `test_every_wgsl_has_realization_per_target` —
  catalog forward invariant (every WGSL has semantic/notes + both
  target realizations).
- `test_no_orphan_artifacts_without_wgsl_pair` — catalog reverse
  invariant (no orphan semantic/realization/notes files without a
  matching WGSL).
- `test_every_bootstrap_wgsl_has_manifest_fixture` — catalog →
  fixture cross-layer (every bootstrap WGSL has fixtures for both
  targets).
- `test_manifest_fixture_kernelrefs_map_to_bootstrap_wgsl` — fixture
  → catalog cross-layer (every fixture's kernelRef names a real WGSL).
- `test_bootstrap_fixtures_validate_and_bind_distinct_targets` —
  fixture schema + pairwise uniqueness + per-kernel semantic-digest
  coherence + per-kernel realization distinctness across backends.
- `test_bootstrap_fixtures_share_version_and_descriptor_identity` —
  fixture set agreement on `frontendVersion` + `compilerVersion` +
  per-backend `targetDescriptorCorrectnessHash`.

*Receipt ↔ fixture identity:*

- `test_canary_receipts_carry_fixture_lowering_identity` — every
  nightly canary receipt's `loweringIdentity` matches the source
  fixture's digests byte-for-byte.
- `test_loads_exact_bootstrap_fixture_set` — canary enumerates the
  expected six (kernel, backend) pairs.

*Emitter identity:*

- Zig `test "tsir emitter code digests are pairwise distinct across
  all five backends"` — manifest-binding disambiguation.
- `test_canary_runs_fixture_receipts_without_claiming_pass` — backend
  lanes return `not_implemented` / `deferred` and do not silently
  promote before execution harnesses exist.

The missing path to proof 1 — in priority order: WebGPU/CSL backend
execution wiring for the parity CLI (Step 8), first per-kernel-family
parity receipt for fused_gemv against both `webgpu-generic` and `wse3`
(Step 9 iter 1), manifest binding of that receipt into a Doppler manifest
(Step 10), and AOT convert-time lowering (Step 11). Each is a substantial
landing; the mechanical-emit hygiene work through today has made every
one of them safer to attempt.

## Archived sub-blocks

Older TSIR entries that no longer need to be in the live shard:

- [`archive/2026-04-24-tsir.md`](archive/2026-04-24-tsir.md) — TSIR Step 7-12
  bring-up entry block (initial-iteration close, Step 8 oracle subprocess,
  Step 9 first parity receipts, Step 11/12 AOT and bench surfaces).

## Scope

Use this shard for:

- TSIR schema + digest contract changes
- TSIR reference interpreter (oracle) coverage
- TSIR frontend lowering (WGSL IR → TSIR semantic)
- TSIR planner (residency, tile factors, PE grid, realization)
- TSIR mechanical backend emitters (CSL, WebGPU, MSL, HLSL/DXIL, SPIR-V)
- TSIR manifest-lowering identity contract + fixtures
- Mechanical-emit iteration status (hold-until-green discipline)
- Per-kernel-family parity closure status

Use `compiler-and-webgpu.md` for:

- Doe WGSL shader compiler (non-TSIR paths: Metal, Vulkan, D3D12)
- WebGPU runtime behavior outside TSIR lowering
- Robustness / validator / conformance work
