//! End-to-end DSL → CgProgram lowering driver.
//!
//! Wires every per-construct lowering pass (mask, view, physics,
//! scoring, spatial, plumbing) behind a single entry point —
//! [`lower_compilation_to_cg`] — that consumes a resolved
//! [`dsl_ast::ir::Compilation`] and returns a fully-built
//! [`CgProgram`]. See `docs/spec/dsl.md` §9 for the canonical
//! specification.
//!
//! # Phases
//!
//! 1. **Registry population.** Walk the [`Compilation`] and allocate
//!    typed ids for every event kind, sum-type variant, action name,
//!    view, and one event ring per event kind. The id allocations are
//!    deterministic (source order), so two runs over the same
//!    Compilation produce byte-identical CgProgram outputs.
//! 2. **Per-construct lowering.** For each user-construct kind
//!    (masks → views → physics → scoring), call the matching
//!    `lower_*` pass with its driver-supplied parameters
//!    (per-handler [`HandlerResolution`]s, [`SpatialQueryKind`] for
//!    masks with a `from` clause, [`ReplayabilityFlag`] from the
//!    rule's `@phase(...)` annotation). Per-construct failures are
//!    accumulated as diagnostics; the driver does NOT short-circuit
//!    on first defect.
//! 3. **Spatial-query synthesis.** Collect every distinct
//!    [`SpatialQueryKind`] referenced by the user ops' dispatch
//!    shapes and, when present, push a [`SpatialQueryKind::BuildHash`]
//!    entry first. Then call [`lower_spatial_queries`] to push one
//!    op per kind.
//! 4. **Ring-edge wiring (pre-gate).** For every user op whose
//!    dispatch shape is [`DispatchShape::PerEvent { source_ring }`],
//!    record an [`EventRingAccess::Read`] read on `source_ring`. For
//!    every [`crate::cg::stmt::CgStmt::Emit`] reachable from any
//!    op's body (descending through `If` / `Match` arms), record an
//!    [`EventRingAccess::Append`] write on the destination ring.
//!    Both wirings mutate the in-progress builder via
//!    [`CgProgramBuilder::ops_mut`] so the cycle gate (step 5) sees
//!    the symmetric ring graph.
//! 5. **Cycle gate.** Snapshot the program after step 4 (the
//!    user-op-only program with ring edges wired) and run
//!    [`check_well_formed`]. Errors surface as
//!    [`LoweringError::WellFormed`] entries on the accumulator. The
//!    plan reserves post-plumbing well-formedness for Phase 3.
//! 6. **Plumbing synthesis.** Call [`synthesize_plumbing_ops`] on
//!    the user-op-only program, then [`lower_plumbing`] to push one
//!    op per kind.
//!
//! # Diagnostic model
//!
//! Many real `.sim` constructs intentionally fail to lower today —
//! masks like `MoveToward(target)` whose predicates reference the
//! per-pair `target` binding, physics rules whose bodies use `Let` /
//! `For` / namespace setter calls, scoring rows that read
//! `target.<field>`, and so on. Each such failure surfaces as a
//! [`LoweringError`] of a deferral variant
//! ([`LoweringError::UnsupportedAstNode`],
//! [`LoweringError::UnsupportedPhysicsStmt`],
//! [`LoweringError::UnsupportedLocalBinding`], …). The driver
//! collects every such diagnostic and returns them alongside the
//! best-effort program.
//!
//! Non-deferral failures (registry conflicts, builder rejections,
//! type-check failures on lowered nodes) surface the same way; the
//! caller decides whether to treat any error as fatal or only treat
//! a non-deferral error as fatal. The integration test exercises
//! the second policy.
//!
//! # Limitations
//!
//! - **Per-mask spatial query selection.** The driver routes
//!   from-bearing masks to [`SpatialQueryKind::EngagementQuery`]
//!   when their predicate references engagement-flavoured access
//!   patterns (`agents.is_hostile_to`, `agents.engaged_with`, or
//!   any `IrExpr::ViewCall` — conservative widening; see
//!   `predicate_uses_engagement_relationship`). All other
//!   from-bearing masks route to [`SpatialQueryKind::KinQuery`].
//!   Refining the ViewCall test to gate on the called view's name
//!   is a follow-up — punted because no current counterexample
//!   exists in `assets/sim/masks.sim`.
//! - **No replayability annotation parsing.** Every physics rule
//!   lowers with [`ReplayabilityFlag::Replayable`] today. The plan
//!   defers `@phase(post)` parsing — a separate pass over the
//!   rule's annotation list — to a follow-up; today the engine
//!   side has only one phase.
//! - **Lazy view inlining.** Lazy view bodies are captured into
//!   [`super::expr::LoweringCtx::lazy_view_bodies`] during Phase 1
//!   (see `populate_view_bodies_and_signatures`); call sites
//!   inline the body via
//!   [`super::expr::lower_expr`]'s `IrExpr::ViewCall` arm.
//!   Materialized view signatures are populated in the same Phase
//!   1 walk; downstream `BuiltinId::ViewCall { view }` lowerings
//!   resolve through `ctx.view_signatures`.

use std::collections::{BTreeMap, BTreeSet};

use dsl_ast::ir::{
    Compilation, EventRef, FoldHandlerIR, IrCallArg, IrExpr, IrExprNode, IrStmt, IrType, MaskIR,
    NamespaceId, PhysicsIR, ViewBodyIR, ViewIR, ViewKind,
};

use crate::cg::data_handle::{
    AgentFieldId, AgentRef, ConfigConstId, CgExprId, DataHandle, EventRingAccess, EventRingId,
    MaskId, ViewId,
};
use crate::cg::dispatch::{DispatchShape, PerPairSource};
use crate::cg::expr::CgTy;
use crate::cg::op::{
    ActionId, ComputeOp, ComputeOpKind, EventKindId, PhysicsRuleId, ReplayabilityFlag, ScoringId,
    SpatialQueryKind,
};
use crate::cg::program::{
    CgProgram, CgProgramBuilder, ConfigConstValue, EventLayout, FieldDef, FieldLayout, MethodDef,
    NamespaceDef, NamespaceRegistry, WgslAccessForm,
};
use crate::cg::stmt::{CgStmt, CgStmtList, CgStmtListId, VariantId};
use crate::cg::well_formed::check_well_formed;

use super::error::LoweringError;
use super::expr::{lower_expr, LoweringCtx};
use super::mask::lower_mask;
use super::physics::lower_physics;
use super::plumbing::{lower_plumbing, synthesize_plumbing_ops};
use super::scoring::lower_scoring;
use super::spatial::lower_spatial_queries;
use super::view::{lower_view, HandlerResolution};

// ---------------------------------------------------------------------------
// Public entry point
// ---------------------------------------------------------------------------

/// Lower a fully resolved [`Compilation`] to a [`CgProgram`].
///
/// On success returns the constructed program; on failure returns
/// `(best_effort_program, diagnostics)`. Many real `.sim` constructs
/// fail to lower today because of staged AST coverage — see the
/// module-level "Diagnostic model" section. Callers that want a
/// strict policy ("any error is fatal") should match on the result;
/// callers that tolerate deferrals (the integration test policy)
/// can inspect the diagnostic list and accept programs whose only
/// failures are deferral variants.
///
/// # Side effects
///
/// None — the driver constructs a fresh [`CgProgramBuilder`] and
/// returns its `finish()` output. `comp` is consumed by reference;
/// the AST is not mutated.
///
/// # Determinism
///
/// Id allocation is deterministic in source order: the i-th event
/// kind in `comp.events` becomes [`EventKindId(i as u32)`], and a
/// matching [`EventRingId(i as u32)`] is allocated alongside it.
/// Variants and actions follow the same shape (one id per source
/// occurrence, allocated in walk order). Two runs over the same
/// `Compilation` produce identical [`CgProgram`] outputs.
///
/// # Limitations
///
/// See the module-level "Limitations" section for the deferred
/// pieces — per-mask spatial query selection, replayability
/// annotation parsing, and view-call signature registration.
/// Per-fixture lowering options. Today only [`Self::aoe_dispatch`] is
/// surfaced; future flags can stack here without breaking the public
/// `lower_compilation_to_cg(comp)` shorthand.
///
/// 2026-05-07 (#121 BGL opt-in): the AOE Path B dispatcher requires
/// spatial bindings (`agent_pos` + `spatial_grid_*`) on the chronicle
/// dispatcher kernel. Surfacing those bindings unconditionally would
/// auto-fire the five build-hash phases in EVERY `apply_ability`-using
/// fixture (see `collect_required_spatial_kinds`), forcing 3 production
/// runtimes (`duel_abilities_runtime`, `tactical_squad_5v5_runtime`,
/// `boss_fight_runtime`) to allocate ≈ 1.4 MB of spatial buffers they
/// don't currently use. The opt-in flag lets per-fixture build.rs
/// scripts choose between the AOE shape (smoke runtime — wants the
/// walk for parity testing) and the existing single-target chain
/// (production runtimes — keep their zero-spatial-overhead BGL).
#[derive(Debug, Clone, Default)]
pub struct LowerOpts {
    /// When `true`, every `apply_ability` lowered under this
    /// `Compilation` carries `with_aoe_dispatch: true` on its
    /// [`crate::cg::stmt::CgStmt::ApplyAbility`] node. The WGSL emit
    /// gates the spatial walk + multi-target chronicle write on the
    /// flag; the BGL composer surfaces the spatial reads via
    /// `wire_apply_ability_aoe_reads` only when at least one
    /// flag-on dispatcher exists in a kernel's body.
    ///
    /// Default `false` preserves the existing single-target shape
    /// for every non-opt-in fixture (the entire production-runtime
    /// set today).
    pub aoe_dispatch: bool,
    /// 2026-05-07 (Wave 3 ToM Phase 3.7): when `true`, every
    /// `agents.set_beliefs_<field>(observer, subject, value)` call in
    /// the program records a write on the matching
    /// [`crate::cg::data_handle::DataHandle::BeliefStateColumn`]
    /// handle, surfaces the column as a real BGL binding on the
    /// hosting kernel (`beliefs_pos` / `beliefs_type` / `beliefs_tick`
    /// / `beliefs_confidence` / `beliefs_suspicion` / `beliefs_flags`),
    /// and emits real WGSL store bodies instead of the `return true`
    /// no-op stubs. The fixture-side runtime allocates the 6 paired
    /// (primary, staging) buffers and supplies them via the kernel's
    /// `Bindings` struct.
    ///
    /// Default `false` keeps every other fixture binding-clean — the
    /// stubs stay no-ops and the BGL composer surfaces zero
    /// belief-state bindings. Today only `tom_probe_runtime` opts in.
    pub belief_state: bool,
    /// 2026-05-09 (compiler debug mode Phase 1): graduated GPU /
    /// memory-traffic / DSL-source-map instrumentation level. See
    /// [`DebugDepth`] for the per-level semantics.
    ///
    /// `DebugDepth::Off` (the default) emits zero instrumentation —
    /// every `dispatch_<kernel>` helper records a plain
    /// `kernel.record(...)` call against the caller's encoder, with
    /// no `write_timestamp` / `QuerySet` / readback overhead. Higher
    /// levels surface compiler-emitted helpers (`DebugTimings`,
    /// `dispatch::record_<name>_timing`, `KERNEL_DSL_SOURCE_MAP`)
    /// that per-fixture runtimes opt into for per-kernel attribution.
    ///
    /// **P2 (schema hash) compatibility**: `LowerOpts` is compile-time
    /// configuration consumed only by the lowering driver + emit
    /// passes; it does NOT participate in the SoA / event / mask
    /// schema-hash inputs. Toggling `debug` between runs leaves the
    /// schema hash unchanged.
    pub debug: DebugDepth,
    /// 2026-05-09 (Compiler debug mode Phase 2): WGSL-side atomic
    /// counter instrumentation. Independently selectable per axis
    /// (event-kind histograms, mask hit-rate, scoring kernel visits).
    /// When the bitset is `NONE`, the WGSL emit + BGL composer behave
    /// exactly as before; when any flag is set, the affected emit
    /// sites add parallel `atomicAdd` calls onto per-flag counter
    /// buffers.
    ///
    /// Orthogonal to [`Self::debug`]: Phase 1 owns host-side
    /// timestamps + memory traffic + DSL source mapping; Phase 2 owns
    /// WGSL-side atomic counters. Two completely separate fields,
    /// two completely separate code paths.
    ///
    /// Default `NONE` preserves the existing emit shape for every
    /// non-opt-in fixture (every production runtime today). The
    /// per-runtime BGL fanout (extra bindings on the ~11 runtimes
    /// that bind agent SoA columns) is deferred to a follow-up
    /// slice that lands an opt-in `*_debug_runtime` fixture; today
    /// no runtime opts in.
    pub debug_wgsl: DebugWgslFlags,
    /// Symbolic ability-name → 1-based AbilityId map for resolving the
    /// `apply_ability <Name> …` source surface (2026-05-12). When a
    /// statement carries `IrStmt::ApplyAbility { ability_name: Some(s),
    /// .. }`, the lowering driver looks up `s` in this map and rewrites
    /// the IR's `ability` field to a `LitInt(id as i64)` before
    /// downstream passes (verb_expand, schedule, emit) run. An entry
    /// that's not in the map surfaces as a typed
    /// [`LoweringError::UnknownAbilityName`] diagnostic with the
    /// sorted-name list as `available` for the user-facing message.
    ///
    /// The per-fixture build.rs populates this from the same source-of-
    /// truth that builds the runtime `PackedAbilityRegistry` (sorted
    /// `.ability` filenames under `assets/ability_test/<fixture>/` —
    /// see `crate::build_helper::compile_for_fixture`). Default empty
    /// means every `IrStmt::ApplyAbility { ability_name: Some(_), .. }`
    /// errors out — fixtures must opt in by populating this map (today
    /// the build_helper does it automatically when a `.ability` corpus
    /// exists).
    pub ability_names: std::collections::BTreeMap<String, u32>,
}

/// Compiler debug-mode level — graduated GPU + memory + DSL-source
/// instrumentation, GCC `-O0..-O3`-style.
///
/// Each level **strictly supersets** the previous (D2 includes D1's
/// timestamps, D3 includes D2's memory traffic, etc.). The numeric
/// representation lets per-runtime `build.rs` scripts opt in via
/// either Rust enum syntax (`DebugDepth::Kernel`) or a numeric ladder
/// (`3.into()`).
///
/// **Level semantics**:
///
/// - `D0 = Off` — zero instrumentation; the default. Every
///   `dispatch_<kernel>` helper is a plain `kernel.record(...)` call.
/// - `D1 = Stage` — per-stage GPU timestamps (mask, scoring,
///   dispatcher, fold, consumer). Adds a `DebugTimings` struct +
///   `record_<name>_timing` helpers; per-fixture runtimes call them
///   in lieu of `dispatch_<name>`.
/// - `D2 = StageMemory` — D1 + per-stage host↔GPU memory traffic
///   accounting. Adds a `MemDelta` struct + `memory_traffic()`
///   accessor.
/// - `D3 = Kernel` — D2 + per-WGSL-kernel granularity (one timestamp
///   slot per kernel rather than coarse stage groupings). The
///   `kernel_timings()` accessor returns one entry per kernel.
/// - `D4 = DslMapped` — D3 + each kernel timing annotated with its
///   `.sim` source location via the emitted `KERNEL_DSL_SOURCE_MAP`
///   table. Read via `dsl_source_map()`.
///
/// **P10 (no runtime panic) compatibility**: per-fixture runtimes
/// that opt in MUST gate the timing-helper calls on
/// `GpuContext::supports_timestamp_query()`; adapters that don't
/// expose `wgpu::Features::TIMESTAMP_QUERY` should fall back to the
/// non-instrumented dispatch path with an empty timings vec rather
/// than panicking.
#[repr(u8)]
#[derive(Copy, Clone, Debug, Default, PartialEq, Eq, PartialOrd, Ord, Hash)]
pub enum DebugDepth {
    /// D0 — no instrumentation, zero overhead. Default.
    #[default]
    Off = 0,
    /// D1 — per-stage GPU timestamps (mask, scoring, dispatcher, fold,
    /// consumer).
    Stage = 1,
    /// D2 — D1 + per-stage host↔GPU memory traffic.
    StageMemory = 2,
    /// D3 — D2 + per-WGSL-kernel timestamp granularity.
    Kernel = 3,
    /// D4 — D3 + each timestamp annotated with `.sim` source location.
    DslMapped = 4,
}

impl From<u8> for DebugDepth {
    /// GCC `-O3`-style numeric ladder. Values above 4 saturate to D4
    /// rather than panicking — keeps build.rs scripts robust against
    /// bumping past the highest defined level.
    fn from(v: u8) -> Self {
        match v {
            0 => Self::Off,
            1 => Self::Stage,
            2 => Self::StageMemory,
            3 => Self::Kernel,
            _ => Self::DslMapped,
        }
    }
}

impl DebugDepth {
    /// True iff the level emits per-kernel timestamp instrumentation
    /// (D1 and above).
    pub fn emits_timestamps(self) -> bool {
        self >= DebugDepth::Stage
    }
    /// True iff the level emits memory-traffic accounting (D2+).
    pub fn emits_memory_traffic(self) -> bool {
        self >= DebugDepth::StageMemory
    }
    /// True iff the level emits one timestamp per kernel rather than
    /// per stage (D3+).
    pub fn per_kernel_granularity(self) -> bool {
        self >= DebugDepth::Kernel
    }
    /// True iff the level emits the `KERNEL_DSL_SOURCE_MAP` table
    /// (D4 only).
    pub fn emits_source_map(self) -> bool {
        self >= DebugDepth::DslMapped
    }
}

/// WGSL-side atomic-counter instrumentation bitset (Compiler debug
/// mode Phase 2). Each axis is independently selectable; when an
/// axis is set, the affected WGSL emit sites add a parallel
/// `atomicAdd` call onto a per-axis counter buffer that the runtime
/// reads back via the per-runtime debug API (deferred — needs
/// opt-in `*_debug_runtime` fixture).
///
/// # Constitution alignment
///
/// - **P1 Compiler-First.** The atomic counters are emitted by the
///   compiler, not hand-written in any `*.wgsl` file under
///   `engine_gpu_rules/src/`.
/// - **P2 Schema-Hash.** The bitset is compile-time configuration
///   threaded through [`LowerOpts`]. The atomic counter buffers are
///   extra GPU-side state, NOT part of the SoA / event contract —
///   the schema hash stays unchanged.
/// - **P3 Cross-Backend Parity.** GPU-only. The CPU backend can
///   ignore [`Self`] entirely and return zero counters from the
///   runtime API.
/// - **P5 Determinism.** Atomic counters are observation-only and
///   don't change RNG draws or sim state.
/// - **P11 Reduction Determinism.** Atomic increments are
///   commutative — order doesn't matter for COUNTS (only for sums of
///   floats). Final values are deterministic regardless of work-item
///   order.
///
/// Default [`Self::NONE`] preserves the existing emit shape.
#[derive(Copy, Clone, Debug, Default, PartialEq, Eq, Hash)]
pub struct DebugWgslFlags {
    /// Per-`EventKindId` histogram: at every chronicle producer
    /// (`atomicAdd(&event_tail[0], 1u)` site emitted by the dispatcher
    /// + emit lowerings), bump
    /// `event_kind_counts[<statically-known kind>]` by 1. Total over
    /// all entries equals the chronicle ring high-water mark for the
    /// tick.
    pub event_kind_histogram: bool,
    /// Per-mask-kernel pass/total counter pair. Inside each
    /// `MaskPredicate` body, `atomicAdd(&mask_total[<mask_id>], 1u)`
    /// runs once per candidate visit; `atomicAdd(&mask_passed[<mask_id>], 1u)`
    /// runs once per candidate that satisfies the predicate. Hit rate
    /// = passed/total.
    pub mask_hit_rate: bool,
    /// Per-agent scoring kernel visit count. Bumps
    /// `score_kernel_visits[agent_id]` per *kernel visit* — semantics
    /// differ across row shapes:
    ///
    /// - **Pair-field rows** (target ≠ self): one increment per
    ///   *candidate* considered in the inner loop. So for an agent
    ///   that argmaxes over 200 in-radius candidates this tick, the
    ///   counter rises by 200.
    /// - **Self-only rows** (target = self): one increment per *row
    ///   visit* — the kernel runs once per agent per row, so the
    ///   counter rises by N for an agent visited across N rows.
    ///
    /// Renamed from `scoring_candidate_count` (2026-05-09 review): the
    /// asymmetry across row types makes "candidates" misleading on
    /// self-only rows where the kernel doesn't iterate. "Kernel visits"
    /// matches the actual work counted.
    pub score_kernel_visits: bool,
}

impl DebugWgslFlags {
    /// All-axes-off bitset. Identical to [`Self::default()`] but
    /// usable in `const` contexts.
    pub const NONE: Self = Self {
        event_kind_histogram: false,
        mask_hit_rate: false,
        score_kernel_visits: false,
    };

    /// All-axes-on bitset. Useful for top-down debugging and tests
    /// that want to exercise every counter path.
    pub const ALL: Self = Self {
        event_kind_histogram: true,
        mask_hit_rate: true,
        score_kernel_visits: true,
    };

    /// `true` when at least one axis is enabled. Used by the BGL
    /// composer follow-up (deferred) to decide whether to surface
    /// the new instrumentation buffer bindings.
    pub fn any(&self) -> bool {
        self.event_kind_histogram || self.mask_hit_rate || self.score_kernel_visits
    }
}

/// Backward-compat shorthand for [`lower_compilation_to_cg_with_opts`]
/// with [`LowerOpts::default()`]. Most fixtures today (no AOE) use
/// this entry point.
pub fn lower_compilation_to_cg(comp: &Compilation) -> Result<CgProgram, DriverOutcome> {
    lower_compilation_to_cg_with_opts(comp, LowerOpts::default())
}

/// Lower a fully resolved [`Compilation`] to a [`CgProgram`] with
/// per-fixture options.
///
/// See [`LowerOpts`] for the per-flag semantics.
pub fn lower_compilation_to_cg_with_opts(
    comp: &Compilation,
    opts: LowerOpts,
) -> Result<CgProgram, DriverOutcome> {
    let mut builder = CgProgramBuilder::new();
    let mut diagnostics: Vec<LoweringError> = Vec::new();

    // -- Phase -1: symbolic ability-name resolution (2026-05-12) --------
    //
    // The `apply_ability <Name> …` DSL surface (parser captures the
    // bare identifier on `ApplyAbilityStmt::ability_name`; resolver
    // forwards it as `IrStmt::ApplyAbility::ability_name`) is rewritten
    // here to a `LitInt(N)` ability expression. The substitution runs
    // BEFORE verb_expand because `verb_expand::extract_single_apply_ability_literal`
    // walks the IR for a `LitInt` ability operand to populate
    // `verb_ability_ids` for predicate-aware scoring — leaving the
    // placeholder `LitInt(0)` from the resolver would mis-bind every
    // verb's ability id to slot 0.
    //
    // Unknown names surface as `LoweringError::UnknownAbilityName`
    // with the sorted name list so the user sees `apply_ability Smite
    // — available: [Daze, Rally, Strike, Volley]` rather than a
    // mysterious WGSL failure downstream.
    let mut comp_owned: Compilation = comp.clone();
    resolve_ability_names_in_compilation(
        &mut comp_owned,
        &opts.ability_names,
        &mut diagnostics,
    );

    // -- Phase 0: verb expansion (Slice A: verb-probe-metric-emit plan) -
    //
    // `verb` declarations are composition sugar over (mask, cascade,
    // scoring entry) — see `docs/spec/dsl.md` §2.6. The plan
    // `docs/superpowers/plans/2026-05-03-verb-probe-metric-emit.md`
    // calls for the compiler to inject those primitives at lower
    // time so the existing mask / physics / scoring lowering passes
    // pick them up automatically. Today's expansion covers mask +
    // scoring; cascade is deferred (no action-selected event
    // source); see `verb_expand.rs` for the supported-shape table.
    //
    // Run before any registry population so the synthesised
    // scoring entries' action heads land in `populate_actions`'s
    // walk and the synthesised mask appears in `lower_all_masks`.
    let expansion = super::verb_expand::expand_verbs(&comp_owned);
    let comp = &expansion.compilation;
    diagnostics.extend(expansion.diagnostics);

    // -- Phase 1: registry population (allocates ids on the builder) -----
    //
    // Each registry has one id per source occurrence, allocated in
    // walk order. The maps below are the driver's view of the
    // assignments; they're handed to the per-construct lowerings via
    // `LoweringCtx`.
    let mut ctx = LoweringCtx::new(&mut builder);
    // 2026-05-07 (#121 BGL opt-in): thread the AOE flag onto the
    // shared lowering context so every `apply_ability` lowered under
    // this Compilation picks up the same flag value. The flag is read
    // by `cg::lower::physics::lower_apply_ability` and stamped onto
    // `CgStmt::ApplyAbility::with_aoe_dispatch`.
    ctx.aoe_dispatch = opts.aoe_dispatch;
    // 2026-05-07 (Wave 3 ToM Phase 3.7): thread the BeliefState opt-in
    // onto the same context. Read by `populate_namespace_registry`
    // (selects real-write WGSL stub bodies vs. no-op return-true) and
    // by `wire_belief_state_setter_writes` below (records writes on
    // ops whose body contains `set_beliefs_*` calls).
    ctx.belief_state = opts.belief_state;

    let event_rings = populate_event_kinds(comp, &mut ctx, &mut diagnostics);
    populate_variants_from_enums(comp, &mut ctx, &mut diagnostics);
    populate_actions(comp, &mut ctx, &mut diagnostics);
    populate_config_consts(comp, &mut ctx, &mut diagnostics);
    populate_views(comp, &mut ctx, &mut diagnostics);
    populate_view_bodies_and_signatures(comp, &mut ctx, &mut diagnostics);
    populate_namespace_registry(&mut ctx);
    populate_entity_field_catalog(comp, &mut ctx);
    populate_tables(comp, &mut ctx);

    // Predicate-aware scoring (Wave 1.5#7 follow-on): mirror the
    // verb-name → ability_id map produced by `expand_verbs` into the
    // interner, keyed by the now-allocated `ActionId`. The scoring
    // kernel emit reads this via `ctx.prog.interner.verb_action_ability_ids`
    // to inline per-effect when-predicate evaluation alongside utility
    // scoring (closing the layering gap documented on
    // `assets/sim/duel_abilities.sim::Reap`).
    populate_verb_action_ability_ids(&expansion.verb_ability_ids, &mut ctx);

    // -- Phase 2: per-construct lowering --------------------------------
    lower_all_masks(comp, &mut ctx, &mut diagnostics);
    lower_all_views(comp, &event_rings, &mut ctx, &mut diagnostics);
    lower_all_physics(comp, &event_rings, &mut ctx, &mut diagnostics);
    lower_all_scoring(comp, &mut ctx, &mut diagnostics);

    // -- Phase 2b: Movement synthesis (Phase 6 Task 3) ------------------
    //
    // Movement is a per-agent rule that consumes scoring's chosen
    // action+target output and writes the agent's position. It is
    // structurally a `PhysicsRule` op with `on_event = None`
    // (PerAgent dispatch over the alive bitmap), distinct from the
    // PerEvent physics rules `lower_all_physics` lowered above. The
    // body is a hand-written WGSL fragment at emit time
    // (`MOVEMENT_BODY` in cg/emit/kernel.rs); the op's reads/writes
    // are recorded explicitly so the BGL synthesis sees the right
    // bindings.
    //
    // The same shape generalizes to any future per-agent sweep
    // (cooldown ticking, stun expiry, need decay, regen, …) — each
    // becomes another `PhysicsRule { on_event: None }` op with its
    // own body template + reads/writes signature.
    //
    // **Phase 6 Task 4 (2026-04-30): Movement-as-rule synth deferred
    // pending Scoring lowering**. The CG-emitted Movement op produces
    // a placeholder kernel body (`MOVEMENT_BODY` const in
    // `cg/emit/kernel.rs`) that touches its bindings but does not
    // mutate position. Real position updates would require:
    //   1. The IR to express vec3 deltas + action-conditional
    //      branching (today there's no abstraction for either).
    //   2. The BGL to bind the agents SoA as `array<u32>` (single
    //      buffer, manual offset arithmetic) instead of the
    //      per-AgentField shape `BindingMetadata` produces today
    //      (`array<vec3<f32>>` aliases the same buffer at the wrong
    //      stride).
    //   3. Scoring to write real (action, target) tuples — today
    //      `scoring.wgsl`'s body is a stub writing ACTION_HOLD.
    //
    // While (1) and (2) are tractable structural extensions, (3) is
    // the upstream blocker: even with a perfect Movement WGSL body,
    // every agent's action is `ACTION_HOLD` and Movement's
    // conditional branch `if (action == ACTION_MOVE_TOWARD)` never
    // fires. The Route C splice
    // (`xtask::compile_dsl_cmd::route_c_movement`) carries a
    // hand-written `movement.wgsl` with the real body shape; it sits
    // at the end of the SCHEDULE and runs on the same
    // `transient.action_buf` Scoring writes to.
    //
    // For Phase 6 Task 4 we drop the CG-emitted FusedMovement
    // (placeholder, no-op) and rely on the Route C splice's Movement
    // (real body, blocked on Scoring stub). When Scoring lowers for
    // real (a follow-up Phase 6 task or its own plan), Movement-as-rule
    // can be re-synthesised here with a real WGSL body.
    let _ = synthesize_movement_op; // silence dead-code; keep helper for future re-enable
    if comp.scoring.is_empty() {
        // No scoring → no scoring_output to consume → no Movement.
        // (A pure-events test fixture would land here.)
    }

    // -- Phase 3: spatial-query synthesis -------------------------------
    //
    // Collect every distinct SpatialQueryKind referenced by user-op
    // dispatch shapes. If the set is non-empty, prepend BuildHash so
    // the per-cell index exists before any kin/engagement walk.
    let spatial_kinds = collect_required_spatial_kinds(ctx.builder.program());
    if let Err(e) = lower_spatial_queries(&spatial_kinds, &mut ctx) {
        diagnostics.push(e);
    }

    // -- Phase 4: ring-edge wiring (pre-gate) ---------------------------
    //
    // The plan amendment (lines 575–595 of
    // `docs/superpowers/plans/2026-04-29-dsl-compute-graph-ir.md`)
    // makes ring-edge symmetry a hard obligation on the driver. For
    // every PerEvent-shaped op the driver records an
    // `EventRingAccess::Read` on its source ring; for every
    // `CgStmt::Emit` reachable from any op's body the driver records
    // an `EventRingAccess::Append` on the destination ring (mapped
    // 1:1 by `EventRingId(i) ↔ EventKindId(i)` per Phase 1's
    // allocation rule). Without this, `check_well_formed`'s
    // `detect_cycles` (which consults only `op.reads` /
    // `op.writes`) silently misses event-ring producer/consumer
    // cycles between physics rules and view folds.
    //
    // The destination-ring walk needs the program's statement
    // arenas; we collect a snapshot first, compute (op_index, dest
    // rings) pairs against it, then apply both wirings to the
    // builder's ops via `ops_mut`.
    let arena_snapshot = ctx.builder.program().clone();
    let emit_writes = collect_emit_destination_rings(&arena_snapshot);
    wire_source_ring_reads(ctx.builder.ops_mut());
    apply_emit_destination_rings(ctx.builder.ops_mut(), &emit_writes);

    // -- Phase 4a': ApplyAbility AbilityRegistry-column read wiring ---
    //
    // The WGSL dispatcher emitted by `cg::emit::wgsl_body`'s
    // `CgStmt::ApplyAbility` arm references three SoA columns from the
    // PackedAbilityRegistry by name:
    //
    //   ability_registry_effect_kinds[base + i]
    //   ability_registry_effect_payload_a[base + i]
    //   ability_registry_effect_payload_b[base + i]
    //
    // Without explicit `record_read` calls on the matching
    // `DataHandle::AbilityRegistryColumn { … }` handles, the BGL
    // composer (`cg::emit::kernel`) never declares the bindings — so
    // the dispatcher's emitted WGSL references undeclared identifiers
    // and naga rejects the kernel at frontend-parse time. Format-string
    // assertions in `wgsl_body.rs` don't catch this gap (they check
    // body content, not binding declarations).
    //
    // Symmetric to `apply_emit_destination_rings` for the EventRing
    // (Append) write recording, but on the read side.
    wire_ability_registry_column_reads(&arena_snapshot, ctx.builder.ops_mut());

    // -- Phase 4a'': AOE Path B reads on flag-on ApplyAbility ops ------
    //
    // Sibling to `wire_ability_registry_column_reads` (above): walks
    // body-bearing PhysicsRule / ViewFold ops, but only records reads
    // on ops whose body contains at least one `ApplyAbility` with
    // `with_aoe_dispatch == true`. Adds the spatial walk's bindings
    // (`agent_pos`, `spatial_grid_cells`, `spatial_grid_starts`) plus
    // the `area_kinds` / `area_args` SoA columns the WGSL Path B emit
    // references.
    //
    // Default `LowerOpts::aoe_dispatch == false` means this walk is a
    // no-op for every production runtime — the BGL composer surfaces
    // zero spatial bindings on their dispatcher kernels and
    // `collect_required_spatial_kinds` never fires the spatial-build
    // phases. Only fixtures that opt in (today: smoke runtime via
    // `lower_compilation_to_cg_with_opts`) pay the binding cost.
    wire_apply_ability_aoe_reads(&arena_snapshot, ctx.builder.ops_mut());

    // -- Phase 4a''': BeliefState setter write wiring (Wave 3 ToM 3.7) -
    //
    // Sibling to `wire_apply_ability_aoe_reads` (above): walks
    // body-bearing PhysicsRule / ViewFold ops, but only records writes
    // on ops whose body contains at least one `agents.set_beliefs_*`
    // namespace call. Adds the matching
    // [`crate::cg::data_handle::DataHandle::BeliefStateColumn`] write
    // so the BGL composer surfaces the per-column `beliefs_<field>`
    // binding on the kernel's BGL.
    //
    // Default `LowerOpts::belief_state == false` means this walk is a
    // no-op for every production runtime — the per-column bindings
    // never appear and the setter WGSL stubs stay no-op `return true`.
    // Only `tom_probe_runtime` opts in.
    if opts.belief_state {
        wire_belief_state_setter_writes(&arena_snapshot, ctx.builder.ops_mut());
    }

    // -- Phase 4b: ActionSelected ring-write wiring on ScoringArgmax ---
    //
    // The verb expander (`cg::lower::verb_expand`) injects an
    // `ActionSelected { actor, action_id, target }` event kind the
    // first time a verb declares a non-empty `emit`, plus a
    // `verb_chronicle_<name>` physics rule that listens on it. The
    // scoring kernel's WGSL body
    // (`cg::emit::kernel::lower_scoring_argmax_body`) emits one
    // `ActionSelected` per agent per tick when the program has the
    // event kind registered — but the binding scanner only declares
    // the `event_ring` + `event_tail` bindings on a kernel when at
    // least one of its ops records an `EventRing { Append }` write.
    //
    // The auto-walker can't synthesize this write (the emit lives in
    // the kernel-emit body template, not in `CgStmt::Emit`), so the
    // driver records it explicitly here — symmetric to the
    // `apply_emit_destination_rings` call above for `CgStmt::Emit`-
    // bearing ops.
    wire_action_selected_writes(&arena_snapshot, ctx.builder.ops_mut());

    // -- Phase 4c: ScoringArgmax mask-bitmap reads ----------------------
    //
    // The scoring kernel emit (`cg::emit::kernel::lower_scoring_argmax_body`)
    // wraps each row whose action name matches a registered mask name
    // (the verb expander's `verb_<Name>` convention) in a mask-bit
    // gate. The gate body references `mask_<id>_bitmap` — an
    // `atomic<u32>` storage binding — so the binding scanner needs to
    // see a `MaskBitmap { mask: <id> }` read on the ScoringArgmax op
    // before BGL synthesis runs. Without this wiring, the WGSL would
    // reference an undeclared identifier.
    //
    // Closing GAP #3 from the verb-fire probe report
    // (`docs/superpowers/notes/2026-05-04-verb-fire-probe.md`):
    // before this change, the scoring kernel walked every row
    // unconditionally and the verb's mask predicate had no
    // observable effect on argmax.
    wire_scoring_mask_reads(&arena_snapshot, ctx.builder.ops_mut());

    // -- Phase 4c': ScoringArgmax predicate-eval bindings ---------------
    //
    // Predicate-aware scoring (Wave 1.5#7 follow-on). When the program
    // has at least one verb registered in the interner's
    // `verb_action_ability_ids` table (the verb expander populated it
    // above for verbs whose body is a single literal-id apply_ability
    // dispatch), the scoring kernel emit inlines per-effect when-
    // predicate evaluation alongside utility scoring. The eval reads
    // the same SoA columns the chronicle dispatcher reads
    // (`when_pred_*` plus the seven agent stat columns); without
    // explicit `record_read` calls here, the BGL composer never
    // declares the matching bindings and the WGSL references undeclared
    // identifiers (caught by naga at frontend-parse time).
    //
    // Symmetric to `wire_ability_registry_column_reads` but for
    // ScoringArgmax ops instead of body-bearing PhysicsRule / ViewFold
    // ops. Same SoA column set; same agent stat field set.
    wire_scoring_predicate_reads(&arena_snapshot, ctx.builder.ops_mut());

    // -- Phase 4d: declared-but-never-emitted event-kind warning --------
    //
    // Walk every interned `EventKindId` and check whether at least one
    // op body carries an `Emit { event: <id>, .. }` statement (or, for
    // verb-cascade emit shapes that get injected at scoring-emit time
    // via an `EventRing { Append }` write on a `ScoringArgmax` op,
    // checks the implicit injection too).
    //
    // Anything that doesn't pass either gate gets a non-fatal
    // [`CgDiagnosticKind::DeclaredEventNeverEmitted`] warning. This
    // catches the trade_market_probe-style "declared `Shipment` event
    // accepted silently" path (gap #6 in
    // `docs/superpowers/notes/2026-05-04-trade_market_probe.md`).
    //
    // The check is intentionally non-fatal: declared-then-unused event
    // kinds are sometimes intentional (placeholder for staged work,
    // declared-then-unblocked-later). Promoting to a hard error would
    // break the staged-work pattern.
    warn_declared_events_never_emitted(comp, &arena_snapshot, &mut ctx);

    // -- Phase 5: cycle gate (user-op-only program) ---------------------
    //
    // The plan amendment scopes the cycle gate to the program built
    // BEFORE plumbing synthesis. The plumbing synthesizer produces
    // structurally cyclic dependencies (PackAgents reads every
    // AgentField, UnpackAgents writes every AgentField) which Phase
    // 3 schedule synthesis resolves; running well_formed against a
    // post-plumbing program would always fire a false cycle.
    //
    // Ring edges (Phase 4) must be wired BEFORE this snapshot —
    // see the rationale on Phase 4.
    //
    // View signatures must be populated on the builder's program
    // BEFORE the snapshot too — `check_well_formed`'s view-key
    // relaxation rule (Task 5) consults `prog.view_signatures` when
    // accepting `Assign(ViewStorage{Primary}, scalar)` shapes whose
    // value is the underlying scalar (e.g., `f32 += 1.0` against
    // `view_key<f32>`). Without this, the cycle gate would see the
    // unpopulated registry and reject every materialized-view fold
    // body's `+= scalar`.
    let view_signatures_snapshot: BTreeMap<u32, crate::cg::program::ViewSignature> = ctx
        .view_signatures
        .iter()
        .map(|(view_id, (args, result))| {
            let storage_hint = ctx.view_storage_hints.get(view_id).copied();
            // Snapshot the fold-body operator alongside the storage
            // hint. Materialized views with a `+=` / `|=` body have
            // an entry; lazy / structurally-built views (test
            // builders that don't run the view-body lowerer) carry
            // `None` and emit falls back to the legacy result-type
            // branch. Closes Gap C from `docs/superpowers/notes/
            // 2026-05-04-quest_probe.md`.
            let fold_op = ctx.view_fold_ops.get(view_id).copied();
            // Mirror the AST-side @belief_gated annotation into the
            // CG signature so emit can branch the PerAgentEventScan
            // gate predicate per-view (omniscient vs belief-gated).
            // ViewId(i) ↔ comp.views[i] (see `populate_views`).
            let belief_gated = comp
                .views
                .get(view_id.0 as usize)
                .map(|v| v.belief_gated)
                .unwrap_or(false);
            // Plan I slice I.3b — pair-keyed K for views whose
            // second key is static (Item/Group/Quest entity count,
            // or `@key_pop(K=N)` literal). Agent×Agent stays None
            // (K = agent_cap at runtime). Read from comp.views[idx]
            // since `args` only carries types, not the source-level
            // annotation list.
            let pair_keyed_k: Option<u32> = comp
                .views
                .get(view_id.0 as usize)
                .and_then(|v| match v.params.as_slice() {
                    [a, b] if matches!(a.ty, dsl_ast::ir::IrType::AgentId) => {
                        match &b.ty {
                            dsl_ast::ir::IrType::U8
                            | dsl_ast::ir::IrType::U32
                            | dsl_ast::ir::IrType::I32 => {
                                // I.3b — K from @key_pop(K = N).
                                v.annotations
                                    .iter()
                                    .find(|a| a.name == "key_pop")
                                    .and_then(|ann| {
                                        ann.args.iter().find_map(|arg| {
                                            if arg.key.as_deref() == Some("K") {
                                                if let dsl_ast::ast::AnnotationValue::Int(n) = &arg.value {
                                                    Some(*n as u32)
                                                } else {
                                                    None
                                                }
                                            } else {
                                                None
                                            }
                                        })
                                    })
                            }
                            // Agent×Agent → None (runtime-variable K).
                            // Item/Group/Quest static counts aren't
                            // threaded here yet; they live in
                            // build_helper's `MaterializedViewInfo`.
                            // Add when a fixture needs reads from
                            // (Agent, Item) views (none today).
                            _ => None,
                        }
                    }
                    _ => None,
                });
            (
                view_id.0,
                crate::cg::program::ViewSignature {
                    args: args.clone(),
                    result: *result,
                    storage_hint,
                    fold_op,
                    belief_gated,
                    pair_keyed_k,
                },
            )
        })
        .collect();
    ctx.builder
        .set_view_signatures(view_signatures_snapshot.clone());

    let user_op_program = ctx.builder.program().clone();
    if let Err(errors) = check_well_formed(&user_op_program) {
        for cg_error in errors {
            diagnostics.push(LoweringError::WellFormed { error: cg_error });
        }
    }

    // -- Phase 6: plumbing synthesis ------------------------------------
    let plumbing_kinds = synthesize_plumbing_ops(ctx.builder.program());
    if let Err(e) = lower_plumbing(&plumbing_kinds, &mut ctx) {
        diagnostics.push(e);
    }

    // Snapshot the per-kind layouts populated by `populate_event_kinds`
    // BEFORE `finish` consumes the builder. The WGSL emit consults the
    // program's `event_layouts` — copying here is the single hand-off
    // from the lowering-time `LoweringCtx` to the post-finish program.
    let event_layouts_snapshot: BTreeMap<u32, EventLayout> = ctx
        .event_layouts
        .iter()
        .map(|(k, v)| (k.0, v.clone()))
        .collect();
    let namespace_registry_snapshot = ctx.namespace_registry.clone();
    let entity_field_catalog_snapshot = ctx.entity_field_catalog.clone();

    let tables_snapshot: std::collections::BTreeMap<String, Vec<u32>> = ctx
        .tables
        .iter()
        .map(|(k, v)| (k.clone(), v.clone()))
        .collect();

    let mut prog = builder.finish();
    prog.event_layouts = event_layouts_snapshot;
    prog.namespace_registry = namespace_registry_snapshot;
    prog.entity_field_catalog = entity_field_catalog_snapshot;
    prog.tables = tables_snapshot;
    // `view_signatures` was set on the builder's program BEFORE the
    // cycle gate (above); `finish()` preserves it. No re-snapshot
    // needed here.
    // 2026-05-09 (Compiler debug mode Phase 2): persist the WGSL
    // instrumentation bitset onto the program so the emit layer can
    // read it via `EmitCtx::debug_wgsl`. This is the single channel
    // by which a per-runtime build.rs opt-in (`LowerOpts {
    // debug_wgsl: ... }`) reaches `wgsl_body.rs`.
    prog.debug_wgsl = opts.debug_wgsl;

    if diagnostics.is_empty() {
        Ok(prog)
    } else {
        Err(DriverOutcome {
            program: prog,
            diagnostics,
        })
    }
}

/// Walk `comp` and rewrite every `IrStmt::ApplyAbility { ability_name:
/// Some(name), .. }` to a `LitInt(N)` ability operand resolved against
/// `ability_names` (filename-stem → 1-based AbilityId map; populated by
/// `build_helper` from the `.ability` corpus the runtime registry uses).
///
/// Unknown names append [`LoweringError::UnknownAbilityName`] to
/// `diagnostics` with the sorted name list as `available`. The statement
/// still rewrites the `ability` field to `LitInt(0)` so downstream
/// passes (verb_expand, schedule, emit) keep their literal-only walks
/// — the diagnostic is the user-visible signal that lowering refused
/// to bind the name.
///
/// Walks every nested-body container that can carry an
/// `IrStmt::ApplyAbility`: physics handlers, verb bodies, view fold
/// handlers, plus the recursive bodies inside `If` / `For` /
/// `ForEachAgent` / `Match` arms. The resolver already rejects
/// `apply_ability` inside view fold bodies, but the walk descends
/// defensively so a future relaxation doesn't silently drop the
/// symbolic-name substitution.
///
/// Closes the silent-mis-dispatch footgun from commit 08cc223e
/// (squad_skirmish): authors who wrote `apply_ability 1` thinking it
/// was Strike instead got Daze (alphabetically first). The symbolic
/// surface (`apply_ability Strike`) names the intended ability; this
/// helper does the binding.
fn resolve_ability_names_in_compilation(
    comp: &mut Compilation,
    ability_names: &std::collections::BTreeMap<String, u32>,
    diagnostics: &mut Vec<LoweringError>,
) {
    for physics in &mut comp.physics {
        for handler in &mut physics.handlers {
            resolve_ability_names_in_stmts(&mut handler.body, ability_names, diagnostics);
        }
    }
    for verb in &mut comp.verbs {
        resolve_ability_names_in_stmts(&mut verb.body, ability_names, diagnostics);
    }
    for view in &mut comp.views {
        if let ViewBodyIR::Fold { handlers, .. } = &mut view.body {
            for handler in handlers {
                resolve_ability_names_in_stmts(&mut handler.body, ability_names, diagnostics);
            }
        }
    }
}

fn resolve_ability_names_in_stmts(
    stmts: &mut [IrStmt],
    ability_names: &std::collections::BTreeMap<String, u32>,
    diagnostics: &mut Vec<LoweringError>,
) {
    for stmt in stmts {
        resolve_ability_names_in_stmt(stmt, ability_names, diagnostics);
    }
}

fn resolve_ability_names_in_stmt(
    stmt: &mut IrStmt,
    ability_names: &std::collections::BTreeMap<String, u32>,
    diagnostics: &mut Vec<LoweringError>,
) {
    match stmt {
        IrStmt::ApplyAbility { ability, ability_name, span, .. } => {
            if let Some(name) = ability_name.take() {
                match ability_names.get(&name) {
                    Some(id) => {
                        ability.kind = IrExpr::LitInt(*id as i64);
                    }
                    None => {
                        let available: Vec<String> = ability_names.keys().cloned().collect();
                        diagnostics.push(LoweringError::UnknownAbilityName {
                            name,
                            available,
                            span: *span,
                        });
                        // Leave `ability` as the resolver-emitted
                        // placeholder `LitInt(0)` — downstream lowering
                        // still walks the stmt but the diagnostic
                        // surfaces the source-level failure.
                    }
                }
            }
        }
        IrStmt::If { then_body, else_body, .. } => {
            resolve_ability_names_in_stmts(then_body, ability_names, diagnostics);
            if let Some(eb) = else_body {
                resolve_ability_names_in_stmts(eb, ability_names, diagnostics);
            }
        }
        IrStmt::Match { arms, .. } => {
            for arm in arms {
                resolve_ability_names_in_stmts(&mut arm.body, ability_names, diagnostics);
            }
        }
        IrStmt::For { body, .. } => {
            resolve_ability_names_in_stmts(body, ability_names, diagnostics);
        }
        IrStmt::ForEachAgent { body, .. } => {
            resolve_ability_names_in_stmts(body, ability_names, diagnostics);
        }
        IrStmt::Let { .. }
        | IrStmt::Emit(_)
        | IrStmt::SelfUpdate { .. }
        | IrStmt::SelfAppend { .. }
        | IrStmt::Expr(_)
        | IrStmt::BeliefObserve { .. } => {}
    }
}

/// The driver's failure shape. Returned when at least one diagnostic
/// fired during lowering. Callers that tolerate deferral variants
/// (most integration tests) inspect `diagnostics` for non-deferral
/// kinds and accept the `program` regardless.
#[derive(Debug, Clone)]
pub struct DriverOutcome {
    /// Best-effort lowered program. Contains every op the driver
    /// successfully constructed before any failure; ops past a
    /// per-construct failure are skipped, but unrelated constructs
    /// are still lowered.
    pub program: CgProgram,
    /// Every diagnostic the driver produced, in the order they were
    /// emitted (per-construct walk order: events → variants →
    /// actions → views → masks → views → physics → scoring →
    /// spatial → well_formed → plumbing).
    pub diagnostics: Vec<LoweringError>,
}

// ---------------------------------------------------------------------------
// Phase 1 helpers — registry population
// ---------------------------------------------------------------------------

/// Allocate one [`EventKindId`] per [`EventIR`] in source order, and
/// allocate ONE shared [`EventRingId`] for every event kind. Returns
/// the per-event-kind ring id table the per-construct lowerings
/// consult to build their [`HandlerResolution`]s.
///
/// All event kinds share `EventRingId(0)`, named `batch_events` on
/// the interner. This mirrors the runtime contract: the
/// resident-context owns ONE `batch_events_ring` buffer that carries
/// every event tag interleaved (see
/// `crates/engine_gpu_rules/src/resident_context.rs`). The earlier
/// 1:1 [`EventKindId`]↔[`EventRingId`] allocation rule was a
/// Phase-1 placeholder; per-kind ring identity is preserved at the
/// WGSL level via the in-kernel `event.tag` decode, and the
/// dispatch layer drives a single ring's tail count.
fn populate_event_kinds(
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) -> Vec<EventRingId> {
    let shared_ring = EventRingId(0);
    if let Err(e) = ctx
        .builder
        .intern_event_ring_name(shared_ring, "batch_events".to_string())
    {
        diagnostics.push(LoweringError::BuilderRejected {
            error: e,
            span: dsl_ast::ast::Span::dummy(),
        });
    }

    // Engine-aliased events (e.g. `EffectDamageApplied = 26`) use their
    // hardcoded discriminant so the kernel filter constant matches what
    // the `apply_ability` dispatcher writes. User events get the next
    // sequential id that is NOT reserved by the alias table — see
    // `dsl_ast::engine_events::assign_event_kind_ids`, the single
    // allocator `resolve_event_ref` and `build_helper`'s
    // `@host_callable` injector both mirror. (Pre-2026-07-22 this was a
    // bare `unwrap_or(i)`, and any fixture past ~25 user events had an
    // event silently aliased onto the dispatcher's damage tag.) See
    // `assets/sim/apply_ability_chronicle_consumer.sim` for the
    // motivating fixture and `assets/sim/many_events_ability.sim` for
    // the >25-event regression pin.
    let allocated_kind_ids = dsl_ast::engine_events::event_kind_ids(&comp.events);

    let mut ring_ids = Vec::with_capacity(comp.events.len());
    for (i, event) in comp.events.iter().enumerate() {
        let kind_id = EventKindId(allocated_kind_ids[i]);
        ring_ids.push(shared_ring);

        ctx.register_event_kind(event.name.clone(), kind_id);

        if let Err(e) = ctx
            .builder
            .intern_event_kind_name(kind_id, event.name.clone())
        {
            diagnostics.push(LoweringError::BuilderRejected {
                error: e,
                span: event.span,
            });
        }

        // Populate per-event payload layout + field-index registry.
        // The layout mirrors the runtime's `pack_event` source of truth
        // at `crates/engine_gpu/src/event_ring.rs`: every `event_tag`-
        // implied field (`tick`) plus the user-declared fields are
        // packed into the payload in declaration order. Variable-width
        // primitives (`Vec3` = 3 words, `u64`-bearing fields = 2 words)
        // are mirrored from `pack_event` here so the WGSL emit reads
        // the same layout the CPU writes.
        //
        // Today every kind shares the global stride 11 (2 header + 8
        // payload + 1 seq trailer — sized for `AgentMoved`/`AgentFled`); when the
        // runtime moves to per-kind ring fanout, this is where the
        // per-kind values populate.
        let mut fields = BTreeMap::new();
        let mut next_offset: u32 = 0;
        for fld in &event.fields {
            let (ty, word_count) = match cg_ty_for_event_field(&fld.ty) {
                Some(p) => p,
                None => {
                    // Defer: an event field whose IrType has no GPU
                    // representation (e.g. `String`, `List<...>`) is a
                    // runtime-only event channel; the GPU pack table
                    // wouldn't carry it either. Skip the field's entry
                    // in the layout — emits referencing it surface as
                    // a separate diagnostic via the existing
                    // `event_field_indices` path.
                    continue;
                }
            };
            // Mirror `event_field_indices`: declaration-order index.
            // Existing tests pre-register these; the driver here is
            // additive — they can coexist.
            let index_u8 = u8::try_from(fields.len()).unwrap_or(u8::MAX);
            ctx.register_event_field(kind_id, fld.name.clone(), index_u8);
            fields.insert(
                fld.name.clone(),
                FieldLayout {
                    word_offset_in_payload: next_offset,
                    word_count,
                    ty,
                },
            );
            next_offset += word_count;
        }
        // Implicit `tick: u32` is the second header word (index 1) —
        // see `event_ring.rs::EventRecord` (kind, tick, payload). It is
        // NOT a payload field, so it does not get a `FieldLayout` here;
        // a body that reads `tick` would resolve through a different
        // mechanism (today nothing reads it directly via the pattern
        // binder surface — `tick` is implicit, never named in `on
        // <Event> { ... }` bindings).
        let layout = EventLayout {
            // stride 11 = 2 header + 8 payload + 1 seq trailer.
            // See `crates/engine_gpu/src/event_ring.rs` PAYLOAD_WORDS = 8.
            record_stride_u32: 11,
            header_word_count: 2,
            // Post-iter-2 every event kind reads from the shared
            // `EventRingId(0)` ring; the structural namer drops the
            // `_<ring.0>` suffix so the binding name `event_ring`
            // matches the ViewFold preamble convention. When the
            // runtime moves to per-kind ring fanout, this becomes
            // `event_ring_<ring_id>` per kind (and the structural
            // namer restores its suffix in tandem).
            buffer_name: "event_ring".to_string(),
            fields,
        };
        ctx.register_event_layout(kind_id, layout);
    }
    ring_ids
}

/// Map an [`IrType`] to a `(CgTy, word_count)` pair for event-field
/// layout. `word_count` is the number of u32 words the CPU's
/// `pack_event` writes for this field; the WGSL emit reads the same
/// number of words back. Returns `None` for non-GPU-representable
/// types (variable-length lists, strings) — those fields are skipped
/// in the layout.
///
/// The mapping mirrors `pack_event` at
/// `crates/engine_gpu/src/event_ring.rs`:
/// - `AgentId`, `AbilityId`, `QuestId`, `ItemId`, `EventId`, `GroupId`
///   → 1 word, `CgTy::AgentId` (single u32 slot for any opaque id).
/// - `u8`, `u16`, `u32`, `i8`, `i16` → 1 word (CPU-side widening), `U32` / `I32`.
/// - `f32` → 1 word, `F32`.
/// - `vec3` → 3 words, `Vec3F32`.
/// - `u64`, `i64` → 2 words via `split_u64`, `U32` (typed as low/high
///   pair; the binder's lowering treats it as opaque u32 today —
///   future: explicit `U64` CgTy variant).
/// - User-declared `Enum { ... }` → 1 word, `U32`.
/// - `String`, `List<...>`, `Optional<...>` → not GPU-representable
///   today; layout omits them.
fn cg_ty_for_event_field(ty: &IrType) -> Option<(CgTy, u32)> {
    use IrType::*;
    Some(match ty {
        Bool => (CgTy::Bool, 1),
        I8 | I16 | I32 => (CgTy::I32, 1),
        U8 | U16 | U32 => (CgTy::U32, 1),
        F32 => (CgTy::F32, 1),
        Vec3 => (CgTy::Vec3F32, 3),
        // Opaque ids — the CPU packs every one into a single u32 slot.
        // The binder's CG type is `AgentId` for the agent ids the
        // pattern names; `AbilityId` / `QuestId` etc. surface as
        // `AgentId` at the IR level too because the IR's CgTy doesn't
        // distinguish opaque-id flavours yet. This is intentional —
        // type-safety on opaque ids is a separate concern from layout.
        AgentId | AbilityId | ItemId | GroupId | QuestId | AuctionId | EventId => {
            (CgTy::AgentId, 1)
        }
        // 64-bit fields are split into (lo, hi) by `split_u64` /
        // `join_u64`. The IR's CgTy doesn't have a U64 variant; the
        // binder reads only the low word as U32 today. A future
        // pattern-binder request for the full u64 would surface as a
        // separate concern (the runtime side already round-trips
        // correctly via the two-word slot).
        I64 | U64 => (CgTy::U32, 2),
        // User enums are repr(u8) but widened to u32 at the slot
        // boundary (see `EffectGoldTransfer`'s reason / kind_tag
        // handling). One slot, U32-typed.
        Enum { .. } => (CgTy::U32, 1),
        // Non-representable: deliberately left for a future task to
        // light up (no current event uses these in a payload binder).
        F64 | String | SortedVec(..) | RingBuffer(..) | SmallVec(..) | Array(..)
        | Optional(..) | Tuple(..) | List(..) | EntityRef(..) | EventRef(..) => return None,
        // Resolver placeholders — `Unknown` is the un-typed default;
        // `Named` is a forward-resolution stub. Neither has a stable
        // GPU width.
        Unknown | Named(_) => return None,
    })
}

/// Populate the stdlib namespace registry — schema for every
/// [`super::super::expr::CgExpr::NamespaceCall`] /
/// [`super::super::expr::CgExpr::NamespaceField`] the lowering may
/// produce. The registry is the source of truth for return types +
/// arg signatures + WGSL emit forms; adding a new namespace symbol is
/// a one-edit-here change, not an IR shape change.
///
/// **B1 stubs (Task 4 of the CG lowering gap closure plan):** the WGSL
/// stub bodies are semantic no-ops chosen so the shader compiles and
/// the kernel runs without panicking. Real implementations are runtime-
/// format work (Task 9-11 territory). The registered methods today are:
///
/// * `agents.is_hostile_to(target)` → `bool`. B1: returns `false`.
///   Real semantics: `CreatureType::is_hostile_to` from `entities.sim`.
/// * `agents.engaged_with_or(target, fallback)` → `AgentId`. B1:
///   returns `fallback`. Real semantics: read the target's
///   engagement slot, sentinel-coerce to `fallback` on `INVALID`.
/// * `query.nearest_hostile_to_or(actor, range, fallback)` →
///   `AgentId`. B1: returns `fallback`. Real semantics: spatial-
///   query walk for nearest hostile, sentinel on miss.
/// * `auctions.place_bid(bidder, good, amount)` → `bool`. B1: returns
///   `true`. Real semantics: validate bidder funds, write into
///   auction state.
/// * `auctions.allocate(good)` → `AgentId`. B1: returns `good`
///   itself. Real semantics: walk the good's bid list, return
///   highest-bidder agent.
/// * `auctions.last_winner(good)` → `AgentId`. B1: returns the
///   `NoneAgentId` sentinel. Real semantics: lookup the most recent
///   `Allocated` event for `good`.
///
/// And the registered fields:
///
/// * `world.tick` → `u32`. B1: kernel-preamble local `tick` (bound by
///   the fold-kernel's `let tick = cfg.tick;` line). The view-fold
///   preamble was renamed from `_tick` to `tick` so the access form
///   resolves cleanly; non-fold kernels that read `world.tick` would
///   need the same preamble entry, but today no non-fold kernel uses
///   it.
/// Build the WGSL body of a `agents.set_beliefs_<u8 column>` setter
/// for the q8-packed BeliefState columns (`creature_type`,
/// `confidence`, `suspicion`).
///
/// Each cell is one of 4 bytes packed LE into an `array<atomic<u32>>`
/// word. The two-step `atomicAnd` (mask-clear) + `atomicOr` (value-set)
/// shape mirrors `BELIEF_HELPERS_WGSL::write_packed_byte_atomic` from
/// the Phase 3.6 hand-written runtime kernels (now retired) — the
/// per-kernel concurrency rule (one writer per cell per dispatch) is
/// the same in the compiler-emitted shape, so the non-atomic
/// "intermediate state visible across two writes" gap doesn't apply.
fn build_packed_u8_setter_wgsl(fn_name: &str, buf_name: &str) -> String {
    format!(
        "fn {fn_name}(observer: u32, subject: u32, v: u32) -> bool {{\n    \
             let cap = cfg.agent_cap;\n    \
             let cell = observer * cap + subject;\n    \
             let word_idx = cell / 4u;\n    \
             let byte_in_word = cell % 4u;\n    \
             let shift = byte_in_word * 8u;\n    \
             let mask: u32 = 0xFFu << shift;\n    \
             let payload: u32 = (v & 0xFFu) << shift;\n    \
             atomicAnd(&{buf_name}[word_idx], ~mask);\n    \
             atomicOr(&{buf_name}[word_idx], payload);\n    \
             return true;\n\
         }}"
    )
}

/// Build the WGSL body of a `agents.beliefs_<u8 column>` GETTER for
/// the q8-packed BeliefState columns (`creature_type` / `confidence`
/// / `suspicion`). Mirror of [`build_packed_u8_setter_wgsl`] in shape:
/// `array<atomic<u32>>` storage with 4 packed LE bytes per word; read
/// via `atomicLoad` + bit-shift to extract the target byte.
///
/// Wave 3 ToM Phase 3.8 — paired with the .sim-authored scry / reveal
/// consumer rules in `tom_probe.sim` that copy a (observer, subject)
/// cell from one row to another (`agents.set_beliefs_<field>(a, s,
/// agents.beliefs_<field>(o, s))`).
fn build_packed_u8_getter_wgsl(fn_name: &str, buf_name: &str) -> String {
    format!(
        "fn {fn_name}(observer: u32, subject: u32) -> u32 {{\n    \
             let cap = cfg.agent_cap;\n    \
             let cell = observer * cap + subject;\n    \
             let word_idx = cell / 4u;\n    \
             let byte_in_word = cell % 4u;\n    \
             let shift = byte_in_word * 8u;\n    \
             let word = atomicLoad(&{buf_name}[word_idx]);\n    \
             return (word >> shift) & 0xFFu;\n\
         }}"
    )
}

fn populate_namespace_registry(ctx: &mut LoweringCtx<'_>) {
    let mut registry = NamespaceRegistry::default();

    // -- agents namespace --
    let mut agents = NamespaceDef {
        name: "agents".to_string(),
        ..NamespaceDef::default()
    };
    // `agents.is_hostile_to(a, b)` — verified against
    // `assets/sim/views.sim:25` (`@lazy view is_hostile`):
    //   `agents.is_hostile_to(a, b)`
    // → 2 args, both AgentId. Returns `bool`.
    agents.methods.insert(
        "is_hostile_to".to_string(),
        MethodDef {
            return_ty: CgTy::Bool,
            arg_tys: vec![CgTy::AgentId, CgTy::AgentId],
            wgsl_fn_name: "agents_is_hostile_to".to_string(),
            wgsl_stub: "fn agents_is_hostile_to(a: u32, b: u32) -> bool { return false; }"
                .to_string(),
        },
    );
    agents.methods.insert(
        "engaged_with_or".to_string(),
        MethodDef {
            return_ty: CgTy::AgentId,
            arg_tys: vec![CgTy::AgentId, CgTy::AgentId],
            wgsl_fn_name: "agents_engaged_with_or".to_string(),
            wgsl_stub:
                "fn agents_engaged_with_or(target: u32, fallback: u32) -> u32 { return fallback; }"
                    .to_string(),
        },
    );
    // Wave 3 ToM Phase 3.5 — 2-arg `agents.beliefs_<field>(observer,
    // subject)` view-call lowering. The 6 BeliefState SoA columns
    // (per-(observer, subject) cells indexed `observer_idx *
    // agent_count + subject_idx`) are runtime-allocated by
    // `tom_probe_runtime`. The DSL surface needs the call sites to
    // typecheck + lower for kernel-side reads in scry/reveal consumer
    // rules; the WGSL stubs return placeholder values today (the actual
    // GPU-side cell-copy lives in the runtime CPU consumer until a
    // future phase emits the WGSL kernel from the chronicle stream).
    //
    // Pairs with the `EffectOp::Scry` (kind=34) / `EffectOp::Reveal`
    // (kind=35) dispatcher arms — without these registry entries, a
    // future `agents.beliefs_pos(observer, subject)` call site would
    // fall through to `UnsupportedNamespaceCall`. Today the entries are
    // stubs-only (each WGSL function returns 0 / sentinel); the runtime
    // CPU consumer (`tom_probe_runtime::scry` / `::reveal`) does the
    // actual cell-copy work outside the WGSL kernel boundary.
    //
    // Field column inventory (mirrors `tom_probe_runtime::TomProbeState`):
    //   * beliefs_pos              — vec3 padded to vec4 (returns Vec3)
    //   * beliefs_creature_type    — u8 widened to u32
    //   * beliefs_last_seen_tick   — u32
    //   * beliefs_confidence       — u8 widened to u32 (q8)
    //   * beliefs_suspicion        — u8 widened to u32 (q8)
    //   * beliefs_flags            — u32 (Phase 1 bit-OR slot)
    //
    // Setters (`agents.set_beliefs_<field>(observer, subject, value)`)
    // mirror the readers with a `_value` arg; WGSL stubs are no-ops
    // (the runtime CPU consumer handles the actual SoA write).
    //
    // **Wave 3 ToM Phase 3.8 — getter real-read bodies.** When
    // `ctx.belief_state == true`, the getter stubs flip from
    // `return 0u` no-ops to REAL reads from the per-column
    // `beliefs_<field>` storage binding. Required for .sim-authored
    // scry / reveal consumer rules that copy from one cell to another
    // (`agents.set_beliefs_pos(a, s, agents.beliefs_pos(o, s))`); the
    // hand-written WGSL kernels in `tom_probe_runtime` are retired in
    // favour of the .sim consumer rules (per the user's "no
    // hand-written WGSL" constraint).
    let belief_state_g = ctx.belief_state;
    let getter_specs: [(&str, CgTy, String); 6] = if belief_state_g {
        [
            (
                "beliefs_pos",
                CgTy::Vec3F32,
                "fn agents_beliefs_pos(observer: u32, subject: u32) -> vec3<f32> {\n    \
                     let cap = cfg.agent_cap;\n    \
                     let v = beliefs_pos[observer * cap + subject];\n    \
                     return vec3<f32>(v.x, v.y, v.z);\n\
                 }".to_string(),
            ),
            (
                "beliefs_creature_type",
                CgTy::U32,
                build_packed_u8_getter_wgsl("agents_beliefs_creature_type", "beliefs_type"),
            ),
            (
                "beliefs_last_seen_tick",
                CgTy::U32,
                "fn agents_beliefs_last_seen_tick(observer: u32, subject: u32) -> u32 {\n    \
                     let cap = cfg.agent_cap;\n    \
                     return beliefs_tick[observer * cap + subject];\n\
                 }".to_string(),
            ),
            (
                "beliefs_confidence",
                CgTy::U32,
                build_packed_u8_getter_wgsl("agents_beliefs_confidence", "beliefs_confidence"),
            ),
            (
                "beliefs_suspicion",
                CgTy::U32,
                build_packed_u8_getter_wgsl("agents_beliefs_suspicion", "beliefs_suspicion"),
            ),
            (
                "beliefs_flags",
                CgTy::U32,
                "fn agents_beliefs_flags(observer: u32, subject: u32) -> u32 {\n    \
                     let cap = cfg.agent_cap;\n    \
                     return beliefs_flags[observer * cap + subject];\n\
                 }".to_string(),
            ),
        ]
    } else {
        [
            (
                "beliefs_pos",
                CgTy::Vec3F32,
                "fn agents_beliefs_pos(observer: u32, subject: u32) -> vec3<f32> { return vec3<f32>(0.0, 0.0, 0.0); }".to_string(),
            ),
            (
                "beliefs_creature_type",
                CgTy::U32,
                "fn agents_beliefs_creature_type(observer: u32, subject: u32) -> u32 { return 0u; }".to_string(),
            ),
            (
                "beliefs_last_seen_tick",
                CgTy::U32,
                "fn agents_beliefs_last_seen_tick(observer: u32, subject: u32) -> u32 { return 0u; }".to_string(),
            ),
            (
                "beliefs_confidence",
                CgTy::U32,
                "fn agents_beliefs_confidence(observer: u32, subject: u32) -> u32 { return 0u; }".to_string(),
            ),
            (
                "beliefs_suspicion",
                CgTy::U32,
                "fn agents_beliefs_suspicion(observer: u32, subject: u32) -> u32 { return 0u; }".to_string(),
            ),
            (
                "beliefs_flags",
                CgTy::U32,
                "fn agents_beliefs_flags(observer: u32, subject: u32) -> u32 { return 0u; }".to_string(),
            ),
        ]
    };
    for (method, ret_ty, stub_body) in getter_specs {
        agents.methods.insert(
            method.to_string(),
            MethodDef {
                return_ty: ret_ty,
                arg_tys: vec![CgTy::AgentId, CgTy::AgentId],
                wgsl_fn_name: format!("agents_{}", method),
                wgsl_stub: stub_body,
            },
        );
    }
    // Setters — 3-arg form `agents.set_beliefs_<field>(observer, subject, value)`.
    // Return Bool as a placeholder ack (matching `auctions.place_bid`'s
    // pattern). When `ctx.belief_state` is `false` (the default), the
    // stubs stay no-op `return true`s — matches the Phase 3.5 shape so
    // every non-opt-in fixture binding-set is unchanged. When `true`,
    // the stubs become REAL WGSL writes against the `beliefs_<field>`
    // module-scope storage decls the BGL composer surfaces.
    //
    // For the q8 columns (`beliefs_type` / `beliefs_confidence` /
    // `beliefs_suspicion`) the storage is `array<atomic<u32>>` with 4
    // packed LE bytes per word; the helper `_bel_write_packed_byte`
    // does a single-byte write via `atomicAnd` (mask-clear) +
    // `atomicOr` (value-set). The two-step write is safe under the
    // tom_probe usage pattern (one writer per cell per dispatch — see
    // `tom_probe_runtime/src/lib.rs` module-header notes).
    let belief_state = ctx.belief_state;
    let setter_specs: [(&str, CgTy, String); 6] = if belief_state {
        [
            (
                "set_beliefs_pos",
                CgTy::Vec3F32,
                // vec3<f32> argument widened to vec4 for std430 storage
                // (the runtime allocates `array<vec4<f32>>` per cell).
                // Pad lane 3 to 1.0 so the readback round-trips with the
                // existing `[10.0, 20.0, 30.0, 1.0]` shape the
                // observe_round_trip_pin pre-seeds.
                "fn agents_set_beliefs_pos(observer: u32, subject: u32, v: vec3<f32>) -> bool {\n    \
                     let cap = cfg.agent_cap;\n    \
                     beliefs_pos[observer * cap + subject] = vec4<f32>(v, 1.0);\n    \
                     return true;\n\
                 }".to_string(),
            ),
            (
                "set_beliefs_creature_type",
                CgTy::U32,
                build_packed_u8_setter_wgsl("agents_set_beliefs_creature_type", "beliefs_type"),
            ),
            (
                "set_beliefs_last_seen_tick",
                CgTy::U32,
                "fn agents_set_beliefs_last_seen_tick(observer: u32, subject: u32, v: u32) -> bool {\n    \
                     let cap = cfg.agent_cap;\n    \
                     beliefs_tick[observer * cap + subject] = v;\n    \
                     return true;\n\
                 }".to_string(),
            ),
            (
                "set_beliefs_confidence",
                CgTy::U32,
                build_packed_u8_setter_wgsl("agents_set_beliefs_confidence", "beliefs_confidence"),
            ),
            (
                "set_beliefs_suspicion",
                CgTy::U32,
                build_packed_u8_setter_wgsl("agents_set_beliefs_suspicion", "beliefs_suspicion"),
            ),
            (
                "set_beliefs_flags",
                CgTy::U32,
                "fn agents_set_beliefs_flags(observer: u32, subject: u32, v: u32) -> bool {\n    \
                     let cap = cfg.agent_cap;\n    \
                     beliefs_flags[observer * cap + subject] = v;\n    \
                     return true;\n\
                 }".to_string(),
            ),
        ]
    } else {
        [
            (
                "set_beliefs_pos",
                CgTy::Vec3F32,
                "fn agents_set_beliefs_pos(observer: u32, subject: u32, v: vec3<f32>) -> bool { return true; }".to_string(),
            ),
            (
                "set_beliefs_creature_type",
                CgTy::U32,
                "fn agents_set_beliefs_creature_type(observer: u32, subject: u32, v: u32) -> bool { return true; }".to_string(),
            ),
            (
                "set_beliefs_last_seen_tick",
                CgTy::U32,
                "fn agents_set_beliefs_last_seen_tick(observer: u32, subject: u32, v: u32) -> bool { return true; }".to_string(),
            ),
            (
                "set_beliefs_confidence",
                CgTy::U32,
                "fn agents_set_beliefs_confidence(observer: u32, subject: u32, v: u32) -> bool { return true; }".to_string(),
            ),
            (
                "set_beliefs_suspicion",
                CgTy::U32,
                "fn agents_set_beliefs_suspicion(observer: u32, subject: u32, v: u32) -> bool { return true; }".to_string(),
            ),
            (
                "set_beliefs_flags",
                CgTy::U32,
                "fn agents_set_beliefs_flags(observer: u32, subject: u32, v: u32) -> bool { return true; }".to_string(),
            ),
        ]
    };
    for (method, value_ty, stub_body) in setter_specs {
        agents.methods.insert(
            method.to_string(),
            MethodDef {
                return_ty: CgTy::Bool,
                arg_tys: vec![CgTy::AgentId, CgTy::AgentId, value_ty],
                wgsl_fn_name: format!("agents_{}", method),
                wgsl_stub: stub_body,
            },
        );
    }
    registry.namespaces.insert(NamespaceId::Agents, agents);

    // -- query namespace --
    let mut query = NamespaceDef {
        name: "query".to_string(),
        ..NamespaceDef::default()
    };
    // `query.nearest_hostile_to_or(actor, range, fallback)` — verified
    // against `assets/sim/physics.sim:441`:
    //   `query.nearest_hostile_to_or(mover, config.combat.engagement_range, mover)`
    // → 3 args: AgentId, F32, AgentId.
    query.methods.insert(
        "nearest_hostile_to_or".to_string(),
        MethodDef {
            return_ty: CgTy::AgentId,
            arg_tys: vec![CgTy::AgentId, CgTy::F32, CgTy::AgentId],
            wgsl_fn_name: "query_nearest_hostile_to_or".to_string(),
            wgsl_stub:
                "fn query_nearest_hostile_to_or(actor: u32, range: f32, fallback: u32) -> u32 { return fallback; }"
                    .to_string(),
        },
    );
    registry.namespaces.insert(NamespaceId::Query, query);

    // -- world namespace --
    let mut world = NamespaceDef {
        name: "world".to_string(),
        ..NamespaceDef::default()
    };
    world.fields.insert(
        "tick".to_string(),
        FieldDef {
            ty: CgTy::U32,
            wgsl_access: WgslAccessForm::PreambleLocal {
                local_name: "tick".to_string(),
            },
        },
    );
    registry.namespaces.insert(NamespaceId::World, world);

    // -- auctions namespace --
    //
    // B1 stubs (initial registration — the `auctions.*` namespace was
    // flagged in the spec audit as having ZERO coverage anywhere:
    // parser routed but no method registered, so any call site fell
    // through to `UnsupportedNamespaceCall`). These three methods make
    // the namespace resolvable + lowerable + emittable end-to-end so
    // the auction_market fixture can probe the path. Real auction
    // semantics (sealed-bid clearing, reserve prices, treasury debits)
    // are runtime-format work; today the stubs are semantic no-ops
    // chosen so the shader compiles and the kernel runs without
    // panicking — same pattern as `agents.is_hostile_to`.
    let mut auctions = NamespaceDef {
        name: "auctions".to_string(),
        ..NamespaceDef::default()
    };
    // `auctions.place_bid(bidder, good, amount)` → `bool`. B1: returns
    // `true` (always succeeds — placeholder). Real semantics: validate
    // bidder funds, write into auction state, return ack.
    auctions.methods.insert(
        "place_bid".to_string(),
        MethodDef {
            return_ty: CgTy::Bool,
            arg_tys: vec![CgTy::AgentId, CgTy::AgentId, CgTy::F32],
            wgsl_fn_name: "auctions_place_bid".to_string(),
            wgsl_stub:
                "fn auctions_place_bid(bidder: u32, good: u32, amount: f32) -> bool { return true; }"
                    .to_string(),
        },
    );
    // `auctions.allocate(good)` → `AgentId`. B1: returns the good
    // itself (placeholder — no real winner-selection algorithm yet).
    // Real semantics: walk the good's bid list, return highest-bidder
    // agent.
    auctions.methods.insert(
        "allocate".to_string(),
        MethodDef {
            return_ty: CgTy::AgentId,
            arg_tys: vec![CgTy::AgentId],
            wgsl_fn_name: "auctions_allocate".to_string(),
            wgsl_stub: "fn auctions_allocate(good: u32) -> u32 { return good; }".to_string(),
        },
    );
    // `auctions.last_winner(good)` → `AgentId`. B1: returns the
    // `NoneAgentId` sentinel (`0xFFFFFFFFu`) since no auction has
    // ever cleared. Real semantics: lookup the most recent
    // `Allocated` event for `good`.
    auctions.methods.insert(
        "last_winner".to_string(),
        MethodDef {
            return_ty: CgTy::AgentId,
            arg_tys: vec![CgTy::AgentId],
            wgsl_fn_name: "auctions_last_winner".to_string(),
            wgsl_stub: "fn auctions_last_winner(good: u32) -> u32 { return 0xFFFFFFFFu; }"
                .to_string(),
        },
    );
    registry.namespaces.insert(NamespaceId::Auctions, auctions);

    // -- quests namespace --
    //
    // B1 stub (initial registration — the `quests.*` namespace was
    // flagged in the spec audit / quest_probe report as having ZERO
    // coverage anywhere: parser routed, resolver tagged
    // `NamespaceId::Quests`, but no method registered, so any call
    // site fell through to `UnsupportedNamespaceCall`). Mirrors the
    // `auctions.*` B1 pattern: `is_active` is the simplest
    // collection-shaped accessor and matches the spec's quest-state
    // language. Real semantics (look up the runtime quest table,
    // consult the lifecycle state machine) are runtime-format work;
    // today the stub returns `true` so the shader compiles and the
    // kernel runs without panicking. Closes Gap B from
    // `docs/superpowers/notes/2026-05-04-quest_probe.md`.
    let mut quests = NamespaceDef {
        name: "quests".to_string(),
        ..NamespaceDef::default()
    };
    // `quests.is_active(quest_id)` → `bool`. B1: returns `true`
    // (always active — placeholder). Real semantics: lookup in the
    // runtime quest table, check the lifecycle state.
    quests.methods.insert(
        "is_active".to_string(),
        MethodDef {
            return_ty: CgTy::Bool,
            arg_tys: vec![CgTy::U32],
            wgsl_fn_name: "quests_is_active".to_string(),
            wgsl_stub: "fn quests_is_active(quest_id: u32) -> bool { return true; }"
                .to_string(),
        },
    );
    registry.namespaces.insert(NamespaceId::Quests, quests);

    // -- terrain namespace --
    //
    // Voxel-engine integration Phase D
    // (`docs/superpowers/plans/2026-05-09-voxel-engine-integration.md`).
    // The DSL surface for `terrain.line_of_sight` was registered at
    // resolve-time (Task 81) but never lowered; Phase D adds the WGSL
    // emit. The three methods below all read the `voxel_grid` storage
    // binding (Phase C's GPU mirror) via the helper functions emitted
    // by `VOXEL_GRID_TERRAIN_WGSL_PRELUDE`.
    //
    // # Helper signature
    //
    // The WGSL helpers `voxel_line_of_sight` / `voxel_height_at` /
    // `voxel_walkable` reference the `voxel_grid` module-scope storage
    // binding directly (no `ptr<storage, ...>` parameter — WGSL
    // function pointers to runtime-sized arrays don't work cleanly).
    // The kernel composer (`emit::kernel`) substring-checks for
    // `voxel_at(` / `voxel_line_of_sight(` etc. in the body and
    // synthesizes a `voxel_grid` binding when found.
    //
    // The grid extent is hardcoded to `engine_voxel::DEFAULT_EXTENT`
    // (256³) for the helper math today — fixtures using smaller
    // extents (e.g. voxel_probe at 16³) write to the matching
    // sub-region; reads outside the active extent return 0 (air),
    // which is the same default the FlatPlane backend produces.
    // A future helper revision could read extent from a uniform if a
    // fixture needs distinct grid sizes.
    let mut terrain = NamespaceDef {
        name: "terrain".to_string(),
        ..NamespaceDef::default()
    };
    // `terrain.line_of_sight(from: vec3, to: vec3) -> bool` — Amanatides-Woo
    // DDA over the voxel mirror. Returns `true` (clear) when no solid
    // voxel lies on the segment from→to. Out-of-bounds endpoints fall
    // back to `true` (matches the `FlatPlane` default + the helper's
    // P10 "no runtime panic" stance).
    terrain.methods.insert(
        "line_of_sight".to_string(),
        MethodDef {
            return_ty: CgTy::Bool,
            arg_tys: vec![CgTy::Vec3F32, CgTy::Vec3F32],
            wgsl_fn_name: "terrain_line_of_sight".to_string(),
            // `from` / `to` are reserved keywords in some WGSL
            // implementations (naga rejects `from` outright), so use
            // `seg_from` / `seg_to` for the parameter names.
            wgsl_stub:
                "fn terrain_line_of_sight(seg_from: vec3<f32>, seg_to: vec3<f32>) -> bool {\n    \
                 return voxel_line_of_sight(seg_from, seg_to);\n\
                 }"
                .to_string(),
        },
    );
    // `terrain.height_at(x: f32, y: f32) -> f32` — top face of the
    // highest occupied cell in column (floor(x), floor(y)). Empty
    // column or out-of-bounds returns 0.0.
    terrain.methods.insert(
        "height_at".to_string(),
        MethodDef {
            return_ty: CgTy::F32,
            arg_tys: vec![CgTy::F32, CgTy::F32],
            wgsl_fn_name: "terrain_height_at".to_string(),
            wgsl_stub:
                "fn terrain_height_at(x: f32, y: f32) -> f32 {\n    \
                 return voxel_height_at(x, y);\n\
                 }"
                .to_string(),
        },
    );
    // `terrain.walkable(pos: vec3, mode: u32) -> bool` — `mode`
    // mirrors `engine::state::agent::MovementMode`'s ordinal
    // (Walk=0, Climb=1, Swim=2, Fly=3, Fall=4). Fly/Fall always
    // return true; the rest check the cell at `floor(pos)` and
    // return false when solid. Out-of-bounds returns true (FlatPlane
    // parity + P10).
    terrain.methods.insert(
        "walkable".to_string(),
        MethodDef {
            return_ty: CgTy::Bool,
            arg_tys: vec![CgTy::Vec3F32, CgTy::U32],
            wgsl_fn_name: "terrain_walkable".to_string(),
            wgsl_stub:
                "fn terrain_walkable(pos: vec3<f32>, mode: u32) -> bool {\n    \
                 return voxel_walkable(pos, mode);\n\
                 }"
                .to_string(),
        },
    );
    registry.namespaces.insert(NamespaceId::Terrain, terrain);

    // -- navgrid namespace --
    //
    // Voxel-region-indices spec Phase 4b (2026-05-16). Mirrors the
    // terrain.* pattern: a single in-rule accessor that the kernel
    // composer synthesizes a `navgrid` storage binding for via a
    // substring scan on `navgrid_walkable(`. The runtime owns a
    // single global navgrid buffer keyed by cell index
    // `cz * size_x + cx`; the host fills it from a
    // `engine_voxel::NavgridIndex` and reads its packed u32 layout
    // (low 8 bits walkable, next 16 height) via a `voxel_navgrid_*`
    // helper prepended by `compose_wgsl_file`.
    //
    // # Multi-region note
    //
    // The spec calls for per-region navgrids
    // (`navgrid.walkable(region, cx, cz)`) but Phase 4b ships the
    // single-implicit-region shape only — every active region kind
    // today has `max_active = 1`. Multi-region dispatch lands when
    // a fixture has distinct co-active region instances and needs
    // them differentiated; the buffer + extent metadata stays
    // single-instance for now.
    let mut navgrid = NamespaceDef {
        name: "navgrid".to_string(),
        ..NamespaceDef::default()
    };
    navgrid.methods.insert(
        "walkable".to_string(),
        MethodDef {
            return_ty: CgTy::Bool,
            arg_tys: vec![CgTy::U32, CgTy::U32],
            wgsl_fn_name: "navgrid_walkable".to_string(),
            wgsl_stub:
                "fn navgrid_walkable(cx: u32, cz: u32) -> bool {\n    \
                 return voxel_navgrid_walkable(cx, cz);\n\
                 }"
                .to_string(),
        },
    );
    registry.namespaces.insert(NamespaceId::Navgrid, navgrid);

    ctx.namespace_registry = registry;
}

/// Walk every `entity X : Item { ... }` and `entity X : Group { ... }`
/// declaration in `comp.entities`, recording each field's name + type
/// into the per-fixture
/// [`crate::cg::program::EntityFieldCatalog`]. The catalog is consumed
/// by:
///   - The `(NamespaceId::Items, _)` / `(NamespaceId::Groups, _)` arms
///     of [`crate::cg::lower::expr::lower_namespace_call`] — `items.<field>(idx)`
///     looks up the field by name to produce a typed
///     [`crate::cg::data_handle::ItemFieldId`].
///   - The kernel-binding metadata in `cg/emit/kernel.rs` —
///     `<entity_snake>_<field_snake>` is the binding's external name on
///     the per-fixture runtime.
///
/// Agent-rooted entities are skipped: their fields are already covered
/// by the closed [`crate::cg::data_handle::AgentFieldId`] enum and the
/// engine's SoA. Only the user-declared catalog entities (Item, Group)
/// need this per-fixture record.
///
/// `EntityRef::0` is the entity's index in `comp.entities`, used as the
/// stable id key for the catalog. Field shape on the IR side is
/// [`dsl_ast::ir::EntityFieldValueIR::Type`] with an [`dsl_ast::ir::IrType`]
/// payload; we only handle the bare-type form (no struct literals, no
/// list literals). Fields whose value is anything else are silently
/// skipped — the resolver already accepts them, but they have no SoA
/// shape today.
/// Mirror `comp.tables` into `ctx.tables` so the expression-lowering
/// arm for `tables.<name>(<idx>)` can bake values into the resulting
/// `CgExpr::TableLookup` node. Each `i64` value was already bounds-
/// checked against the declared `u32` element type by the resolver,
/// so the `as u32` cast here is lossless.
fn populate_tables(comp: &Compilation, ctx: &mut LoweringCtx<'_>) {
    for t in &comp.tables {
        let values: Vec<u32> = t.values.iter().map(|v| *v as u32).collect();
        ctx.tables.insert(t.name.clone(), values);
    }
}

fn populate_entity_field_catalog(comp: &Compilation, ctx: &mut LoweringCtx<'_>) {
    use crate::cg::data_handle::AgentFieldTy;
    use crate::cg::program::{EntityFieldCatalog, EntityFieldEntry, EntityFieldRecord};
    use dsl_ast::ast::EntityRoot;
    use dsl_ast::ir::{EntityFieldValueIR, IrType};

    let mut catalog = EntityFieldCatalog::default();

    for (idx, entity) in comp.entities.iter().enumerate() {
        // Skip Agent-rooted entities — their SoA storage is the
        // engine's closed AgentFieldId / AgentFieldTy schema.
        let target = match entity.root {
            EntityRoot::Item => &mut catalog.items,
            EntityRoot::Group => &mut catalog.groups,
            EntityRoot::Agent => continue,
            // Quest-rooted entities are accepted as declare-only today
            // (no per-Quest SoA, no `quests.<field>(idx)` accessor on
            // the namespace registry yet). Skip the same way Agent is
            // skipped — the `quests` namespace exposes only stub
            // method calls (`quests.is_active(...)` etc.). See Gap A
            // closure note in `docs/superpowers/notes/2026-05-04-
            // quest_probe.md`.
            EntityRoot::Quest => continue,
        };
        let mut entries: Vec<EntityFieldEntry> = Vec::with_capacity(entity.fields.len());
        for f in &entity.fields {
            let ty = match &f.value {
                EntityFieldValueIR::Type(t) => match t {
                    IrType::F32 => Some(AgentFieldTy::F32),
                    IrType::U32 => Some(AgentFieldTy::U32),
                    IrType::Bool => Some(AgentFieldTy::Bool),
                    IrType::Vec3 => Some(AgentFieldTy::Vec3),
                    IrType::AgentId | IrType::ItemId | IrType::GroupId => {
                        Some(AgentFieldTy::U32)
                    }
                    _ => None,
                },
                // Struct literals, list literals, and bare-expression
                // values don't have a single-primitive SoA shape. Skip
                // them for now — a future extension might emit one
                // record per leaf field.
                _ => None,
            };
            if let Some(ty) = ty {
                entries.push(EntityFieldEntry {
                    name: f.name.clone(),
                    ty,
                });
            }
        }
        if entries.is_empty() {
            continue;
        }
        target.insert(
            idx as u16,
            EntityFieldRecord {
                entity_name: entity.name.clone(),
                fields: entries,
            },
        );
    }

    ctx.entity_field_catalog = catalog;
}

/// Allocate one [`VariantId`] per enum variant across every
/// [`EnumIR`] in source order. Variants from different enums
/// inhabit a flat id space — the typed registry keys on the
/// source-level variant name.
///
/// Today's physics matches consult `ctx.variant_ids` for stdlib
/// `EffectOp` arms; user-declared enums in `comp.enums` populate
/// the same map so a synthetic match arm naming a user variant
/// resolves cleanly. A duplicate variant name across enums (rare
/// in practice) overwrites the prior entry and pushes a typed
/// [`LoweringError::DuplicateVariantInRegistry`] — the driver
/// flags it but does not abort.
fn populate_variants_from_enums(
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    // Walk each enum's variants in declaration order, allocating
    // ids contiguously. Collisions across enums are surfaced via
    // `register_variant`'s return value (the prior id) — the
    // lowering treats the registry as last-write-wins and pushes
    // a typed diagnostic so callers can refuse the program.
    let mut next_id: u32 = 0;
    for enum_ir in &comp.enums {
        for variant_name in &enum_ir.variants {
            let id = VariantId(next_id);
            next_id += 1;
            if let Some(prior_id) = ctx.register_variant(variant_name.clone(), id) {
                diagnostics.push(LoweringError::DuplicateVariantInRegistry {
                    name: variant_name.clone(),
                    prior_id,
                    new_id: id,
                });
            }
        }
    }
}

/// Allocate one [`ActionId`] per distinct scoring-row head name
/// across every [`ScoringIR`] in source order.
///
/// Standard rows and per-ability rows share the same id space —
/// both are "actions" at the engine's apply layer. The first
/// occurrence of each name gets a fresh id; subsequent occurrences
/// reuse it (the registry is keyed on the bare action name).
fn populate_actions(
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    let mut next_id: u32 = 0;
    for scoring in &comp.scoring {
        for entry in &scoring.entries {
            allocate_action(&entry.head.name, &mut next_id, ctx, diagnostics, entry.head.span);
        }
        for row in &scoring.per_ability_rows {
            allocate_action(&row.name, &mut next_id, ctx, diagnostics, row.span);
        }
    }
}

fn allocate_action(
    name: &str,
    next_id: &mut u32,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
    span: dsl_ast::ast::Span,
) {
    if ctx.action_ids.contains_key(name) {
        return;
    }
    let id = ActionId(*next_id);
    *next_id += 1;
    ctx.register_action(name.to_string(), id);
    if let Err(e) = ctx.builder.intern_action_name(id, name.to_string()) {
        diagnostics.push(LoweringError::BuilderRejected { error: e, span });
    }
}

/// Populate [`crate::cg::program::Interner::verb_action_ability_ids`]
/// by joining the verb expander's `verb_<Name>` → ability_id map
/// against the action-id allocator's `verb_<Name>` → ActionId
/// assignment. Both maps share the same key space (the synthetic
/// action name); a verb name absent from `action_ids` (e.g., a verb
/// whose body is empty so no scoring entry was injected) silently
/// drops out of the join — the scoring kernel falls back to verb-mask
/// gating for those rows.
///
/// Called between `populate_actions` and `lower_all_*` so the
/// interner table is populated before the scoring kernel emit reads
/// it. Conflict (same action_id mapped to different ability_ids by
/// distinct verbs sharing a synthetic name) surfaces a
/// `BuilderError::DuplicateInternEntry`-shaped diagnostic.
fn populate_verb_action_ability_ids(
    verb_ability_ids: &std::collections::BTreeMap<String, u32>,
    ctx: &mut LoweringCtx<'_>,
) {
    for (synthetic_name, ability_id) in verb_ability_ids {
        if let Some(action_id) = ctx.action_ids.get(synthetic_name).copied() {
            // Errors here would indicate a driver-side defect
            // (duplicate verb name colliding on action_id); silently
            // skip on conflict — the predicate gate is a best-effort
            // refinement and the verb-mask still gates argmax.
            let _ = ctx
                .builder
                .record_verb_action_ability_id(action_id, *ability_id);
        }
    }
}

/// Allocate one [`ViewId`] per [`ViewIR`] in source order. Names
/// are interned so diagnostics + pretty-printing can render named
/// references. View signatures are NOT populated today — see the
/// module-level "Limitations" note on view-call signature
/// registration.
///
/// A duplicate registration (the same `AstViewRef` resolving twice)
/// is a driver-side defect — `ViewId`s are allocated in source
/// order and the AST resolver assigns each view a unique ref. The
/// driver pushes a typed
/// [`LoweringError::DuplicateViewInRegistry`] if it ever observes
/// one and continues with last-write-wins.
fn populate_views(
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    // The AST resolver assigns each view a `ViewRef(i)` matching
    // its position in `comp.views`; the driver mirrors that into a
    // typed `ViewId(i)` so expression-level `IrExpr::ViewCall`
    // lowerings can resolve their AST ref through `view_ids`. Name
    // interning happens inside `lower_view` (idempotent for the
    // same id+name pair); we don't pre-intern here.
    //
    // View signature registration is deliberately not performed —
    // see the module-level "Limitations" docstring.
    for i in 0..comp.views.len() {
        let view_id = ViewId(i as u32);
        let ast_ref = dsl_ast::ir::ViewRef(i as u16);
        if let Some(prior_id) = ctx.register_view(ast_ref, view_id) {
            diagnostics.push(LoweringError::DuplicateViewInRegistry {
                ast_ref,
                prior_id,
                new_id: view_id,
            });
        }
    }
}

/// Allocate one [`ConfigConstId`] per (block, field) pair across
/// every [`dsl_ast::ir::ConfigIR`] in source order, register each
/// into `ctx.config_const_ids` keyed on
/// `(NamespaceId::Config, "<block>.<field>")`, and intern the
/// human-readable name on the builder for diagnostics +
/// pretty-printing. The id allocation is deterministic — the
/// flat numeric `i` reflects walk order.
///
/// A duplicate registration (same (block, field) pair across two
/// `ConfigIR`s) is a driver-side defect; surfaced as a typed
/// [`LoweringError::DuplicateConfigConstInRegistry`] diagnostic
/// with last-write-wins semantics.
fn populate_config_consts(
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    let mut next_id: u32 = 0;
    for cfg in &comp.configs {
        for fld in &cfg.fields {
            let id = ConfigConstId(next_id);
            next_id += 1;
            let key = format!("{}.{}", cfg.name, fld.name);
            if let Some(prior) =
                ctx.register_config_const(NamespaceId::Config, key.clone(), id)
            {
                diagnostics.push(LoweringError::DuplicateConfigConstInRegistry {
                    key: key.clone(),
                    prior_id: prior,
                    new_id: id,
                });
            }
            if let Err(e) = ctx.builder.intern_config_const_name(id, key) {
                diagnostics.push(LoweringError::BuilderRejected {
                    error: e,
                    span: fld.span,
                });
            }
            // Capture the literal default into the program's
            // `config_const_values` map so the WGSL emit can produce
            // an inline `const config_<id>: <ty> = <value>;` for every
            // referenced const. The declared field type (`fld.ty`) picks
            // the WGSL scalar type via [`ConfigConstValue`]: a u32-
            // declared field emits `<n>u`, an i32-declared field emits
            // `<n>i`, otherwise f32 (the default for numeric defaults
            // without a sharper type annotation). Non-numeric defaults
            // (Bool / String) skip silently because no compute kernel
            // references them. See trade_market_probe doc GAP #1 for
            // the original symptom that motivated the type round-trip.
            use dsl_ast::ast::ConfigDefault;
            use dsl_ast::ir::IrType;
            let raw: Option<f64> = match &fld.default {
                ConfigDefault::Float(v) => Some(*v),
                ConfigDefault::Int(v) => Some(*v as f64),
                ConfigDefault::Uint(v) => Some(*v as f64),
                ConfigDefault::Bool(_) | ConfigDefault::String(_) => None,
            };
            if let Some(raw) = raw {
                let value = match &fld.ty {
                    IrType::U32
                    | IrType::U8
                    | IrType::U16
                    | IrType::U64
                    | IrType::AgentId
                    | IrType::ItemId
                    | IrType::GroupId
                    | IrType::QuestId
                    | IrType::AuctionId
                    | IrType::EventId
                    | IrType::AbilityId => ConfigConstValue::U32(raw as u32),
                    IrType::I8 | IrType::I16 | IrType::I32 | IrType::I64 => {
                        ConfigConstValue::I32(raw as i32)
                    }
                    // Default: F32. Covers IrType::F32 / IrType::F64
                    // explicitly plus every other shape that previously
                    // routed through the f32 path. The f32 default is
                    // safe — pre-this-fix every config const emitted
                    // as f32 regardless of declared type.
                    _ => ConfigConstValue::F32(raw as f32),
                };
                ctx.builder.set_config_const_value(id, value);
            }
            // Plan G tunable cfg — flag this id as runtime-tunable when
            // the source field carried `@runtime`. The kernel emit
            // consults `prog.runtime_config_consts` to swap the default
            // baked-WGSL-const path for a per-kernel cfg-uniform field.
            // We still register the literal default above so the host
            // initialises the cfg buffer with the same value (and so
            // kernels that don't cross-reference the runtime path stay
            // bit-identical).
            if fld.runtime {
                ctx.builder.mark_config_const_runtime(id);
            }
        }
    }
}

/// For every view in source order: capture lazy bodies into
/// `ctx.lazy_view_bodies` (so `lower_view_call` can inline them at
/// call sites), and register materialized view signatures into
/// `ctx.view_signatures` (so the type checker can resolve
/// `BuiltinId::ViewCall { view }` shapes). Task 5.5c.
fn populate_view_bodies_and_signatures(
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    for (i, view) in comp.views.iter().enumerate() {
        let view_id = ViewId(i as u32);
        match (&view.kind, &view.body) {
            (ViewKind::Lazy, ViewBodyIR::Expr(body)) => {
                let snapshot = super::expr::LazyViewSnapshot {
                    param_locals: view.params.iter().map(|p| p.local).collect(),
                    body: body.clone(),
                };
                if ctx.register_lazy_view_body(view_id, snapshot).is_some() {
                    diagnostics.push(LoweringError::DuplicateLazyViewBodyRegistration {
                        view: view_id,
                        span: view.span,
                    });
                }
            }
            (ViewKind::Materialized(hint), ViewBodyIR::Fold { .. }) => {
                let arg_tys: Vec<crate::cg::expr::CgTy> = view
                    .params
                    .iter()
                    .map(|p| super::expr::ir_type_to_cg_ty(&p.ty))
                    .collect();
                let result_ty = super::expr::ir_type_to_cg_ty(&view.return_ty);
                ctx.register_view_signature(view_id, arg_tys, result_ty);
                // Mirror the AST-level storage hint into the CG-side
                // enum so the kernel emit + dispatch sizing path can
                // branch on it without pulling dsl_ast into program.rs.
                let cg_hint = super::view::project_storage_hint(*hint);
                ctx.register_view_storage_hint(view_id, cg_hint);
            }
            // Kind/body mismatches are reported at lower_view time
            // with a structural diagnostic; the registry walk skips
            // them so the diagnostic isn't doubled.
            (ViewKind::Lazy, ViewBodyIR::Fold { .. })
            | (ViewKind::Materialized(_), ViewBodyIR::Expr(_)) => {}
            // Plan I (slice I.3) — register the belief's call
            // signature + storage hint with the CG context so
            // `belief.<name>(observer, subject)` reads through the
            // same BuiltinId::ViewCall lowering as `view.<name>(...)`.
            // The hint is inferred from the signature (today only the
            // pair-keyed (Agent, Agent) → PairMap shape is supported;
            // single-key shapes surface a typed UnsupportedBeliefShape
            // diagnostic at `lower_view` time so the build.rs sees it).
            (ViewKind::Belief, ViewBodyIR::Fold { .. }) => {
                let arg_tys: Vec<crate::cg::expr::CgTy> = view
                    .params
                    .iter()
                    .map(|p| super::expr::ir_type_to_cg_ty(&p.ty))
                    .collect();
                let result_ty = super::expr::ir_type_to_cg_ty(&view.return_ty);
                ctx.register_view_signature(view_id, arg_tys, result_ty);
                // Only register the storage hint when inference would
                // succeed; otherwise the lower_view pass surfaces the
                // diagnostic and there's no hint to register.
                // Annotation-driven storage wins over signature-based
                // inference (mirrors `infer_belief_storage_hint`).
                let ring_ann = view
                    .annotations
                    .iter()
                    .find(|a| a.name == "per_entity_ring");
                let inferred = if let Some(ann) = ring_ann {
                    // Parse `K = N` directly so the registry walk
                    // doesn't depend on the cg/lower helper.
                    ann.args
                        .iter()
                        .find_map(|arg| {
                            if arg.key.as_deref() == Some("K") {
                                if let dsl_ast::ast::AnnotationValue::Int(n) = &arg.value {
                                    let k_u16 = (*n).clamp(1, u16::MAX as i64) as u16;
                                    Some(dsl_ast::ir::StorageHint::PerEntityRing { k: k_u16 })
                                } else {
                                    None
                                }
                            } else {
                                None
                            }
                        })
                        // If the annotation is malformed the lower
                        // pass surfaces the typed diagnostic; the
                        // registry walk just skips registration.
                } else {
                    match view.params.as_slice() {
                        [a, b]
                            if matches!(a.ty, dsl_ast::ir::IrType::AgentId)
                                && matches!(b.ty, dsl_ast::ir::IrType::AgentId) =>
                        {
                            Some(dsl_ast::ir::StorageHint::PairMap)
                        }
                        // Plan I slice I.3b — `(observer: Agent, key:
                        // u8|u32|i32)` is also PairMap-shaped (storage
                        // is `agent_cap × K` cells via @key_pop(K=N)).
                        // Without this arm the registry walk fell
                        // through to `None`, the storage hint never
                        // got registered, and the WGSL emit defaulted
                        // to single-key indexing (`local_<last>` only)
                        // — silently dropping the pair-key compose so
                        // every (observer, *) event wrote to the same
                        // cell as (observer, 0).
                        [a, b]
                            if matches!(a.ty, dsl_ast::ir::IrType::AgentId)
                                && matches!(
                                    b.ty,
                                    dsl_ast::ir::IrType::U8
                                        | dsl_ast::ir::IrType::U32
                                        | dsl_ast::ir::IrType::I32
                                ) =>
                        {
                            Some(dsl_ast::ir::StorageHint::PairMap)
                        }
                        // Slice I.3a — single-key `(observer: Agent) -> T`
                        // belief. The per-view sizing path (in
                        // `build_helper::detect_pair_keyed_second_key`)
                        // gates on param count, so the PairMap hint here
                        // collapses to single-key sizing (N cells) at
                        // allocation time.
                        [a] if matches!(a.ty, dsl_ast::ir::IrType::AgentId) => {
                            Some(dsl_ast::ir::StorageHint::PairMap)
                        }
                        _ => None,
                    }
                };
                if let Some(hint) = inferred {
                    let cg_hint = super::view::project_storage_hint(hint);
                    ctx.register_view_storage_hint(view_id, cg_hint);
                }
            }
            (ViewKind::Belief, ViewBodyIR::Expr(_)) => {}
        }
    }
}

// ---------------------------------------------------------------------------
// Phase 2 helpers — per-construct lowering loops
// ---------------------------------------------------------------------------

/// Lower every [`MaskIR`] in source order. Each mask becomes one
/// [`ComputeOpKind::MaskPredicate`] op (or zero ops on lowering
/// failure — the diagnostic is accumulated and the next mask runs).
///
/// Spatial query selection: a mask with no `from` clause gets
/// [`None`] (resolves to [`DispatchShape::PerAgent`]); a mask with
/// a `from` clause gets [`SpatialQueryKind::KinQuery`] as the
/// default — see the module-level "Limitations" note on per-mask
/// kind selection.
fn lower_all_masks(
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    for (i, mask) in comp.masks.iter().enumerate() {
        let mask_id = MaskId(i as u32);
        let spatial_kind = mask_spatial_kind(mask, comp, ctx);
        if let Err(e) = lower_mask(mask_id, spatial_kind, mask, ctx) {
            diagnostics.push(e);
        }
    }
}

/// Lower a per-pair filter expression to a `CgExprId` with the
/// per-pair candidate binder (`target` / `candidate` LocalRef →
/// `PerPairCandidateId`) active for the duration of the lowering.
/// Mirrors the `target_local` flag toggle in
/// [`super::mask::lower_mask`] — the flag is restored before returning
/// so a recursive lowering can't leak the binding upward.
///
/// Returns the lowered `CgExprId`. Type-validation that the filter
/// is `Bool` happens later in `cg::well_formed` (the TypeCheckCtx
/// wiring lives there); this helper is purely the lowering shim.
///
/// Phase 7 Task 5 wired this into [`mask_spatial_kind`]: the
/// `from spatial.<name>(args)` mask source resolves the named
/// `spatial_query` decl, substitutes the call-site value-args via
/// [`walk_substitute`], then lowers the filter expression here.
fn lower_filter_for_mask(
    expr: &IrExprNode,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    let prev = ctx.target_local;
    ctx.target_local = true;
    let result = lower_expr(expr, ctx);
    ctx.target_local = prev;
    result
}

/// Substitute call-site value-args into a `spatial_query` filter
/// expression. Walks the IR tree, replacing each
/// `IrExpr::Local(LocalRef(i), _)` for `i >= 2` (value-args, since
/// `LocalRef(0) = self` and `LocalRef(1) = candidate`) with the
/// corresponding call-site argument expression.
///
/// `self` (`LocalRef(0)`) and `candidate` (`LocalRef(1)`) are NOT
/// substituted. They are bound by the lowering layer at filter-lower
/// time: [`lower_filter_for_mask`] sets `ctx.target_local = true`,
/// so `target` / `candidate` LocalRef reads resolve to
/// `CgExpr::PerPairCandidateId` and `self` resolves to
/// `CgExpr::AgentSelfId` via the standard lowering path.
///
/// Per Phase 7's call-site arity convention (Task 4 Adjustment A),
/// the call site at `from spatial.<name>(args)` passes
/// `(self, value_args...)` — `candidate` is not a call-site arg.
/// So `value_args` here corresponds to LocalRef(2..), indexed
/// sequentially. (Today every wolf-sim spatial_query has zero
/// value-args, so this loop is a no-op; the substitution machinery
/// is wired so that future `spatial.nearby_in_radius(self, radius)`
/// uses just work.)
///
/// Walk is fully exhaustive over [`IrExpr`]: every variant carrying
/// nested `IrExprNode` recurses; leaf variants clone. No new binders
/// are introduced inside spatial_query filters today (the resolver
/// rejects `for` / `let` / `match` inside the filter expression),
/// but the recursive structure tolerates them by passing
/// `value_args` straight through — a stray binder would just be
/// re-checked against the same value-arg slice.
fn walk_substitute(node: &IrExprNode, value_args: &[IrCallArg]) -> IrExprNode {
    let new_kind = match &node.kind {
        IrExpr::Local(local_ref, name) => {
            // Substitute LocalRef(2..) with the corresponding value
            // arg. LocalRef(0)=self / LocalRef(1)=candidate are not
            // substituted — they fall through and get resolved by
            // `lower_expr` (self → AgentSelfId; candidate → PerPair
            // when `ctx.target_local` is set).
            if local_ref.0 >= 2 {
                let idx = (local_ref.0 - 2) as usize;
                if idx < value_args.len() {
                    return value_args[idx].value.clone();
                }
            }
            IrExpr::Local(*local_ref, name.clone())
        }
        IrExpr::Field { base, field_name, field } => IrExpr::Field {
            base: Box::new(walk_substitute(base, value_args)),
            field_name: field_name.clone(),
            field: field.clone(),
        },
        IrExpr::Index(lhs, rhs) => IrExpr::Index(
            Box::new(walk_substitute(lhs, value_args)),
            Box::new(walk_substitute(rhs, value_args)),
        ),
        IrExpr::Binary(op, lhs, rhs) => IrExpr::Binary(
            *op,
            Box::new(walk_substitute(lhs, value_args)),
            Box::new(walk_substitute(rhs, value_args)),
        ),
        IrExpr::Unary(op, inner) => {
            IrExpr::Unary(*op, Box::new(walk_substitute(inner, value_args)))
        }
        IrExpr::In(lhs, rhs) => IrExpr::In(
            Box::new(walk_substitute(lhs, value_args)),
            Box::new(walk_substitute(rhs, value_args)),
        ),
        IrExpr::Contains(lhs, rhs) => IrExpr::Contains(
            Box::new(walk_substitute(lhs, value_args)),
            Box::new(walk_substitute(rhs, value_args)),
        ),
        IrExpr::Quantifier { kind, binder, binder_name, iter, body } => IrExpr::Quantifier {
            kind: *kind,
            binder: *binder,
            binder_name: binder_name.clone(),
            iter: Box::new(walk_substitute(iter, value_args)),
            body: Box::new(walk_substitute(body, value_args)),
        },
        IrExpr::Fold { kind, binder, binder_name, iter, body } => IrExpr::Fold {
            kind: kind.clone(),
            binder: *binder,
            binder_name: binder_name.clone(),
            iter: iter.as_ref().map(|i| Box::new(walk_substitute(i, value_args))),
            body: Box::new(walk_substitute(body, value_args)),
        },
        IrExpr::List(items) => IrExpr::List(
            items.iter().map(|i| walk_substitute(i, value_args)).collect(),
        ),
        IrExpr::Tuple(items) => IrExpr::Tuple(
            items.iter().map(|i| walk_substitute(i, value_args)).collect(),
        ),
        IrExpr::ViewCall(vr, args) => IrExpr::ViewCall(
            *vr,
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: walk_substitute(&a.value, value_args),
                    span: a.span,
                })
                .collect(),
        ),
        IrExpr::RingFieldRead(vr, field, args) => IrExpr::RingFieldRead(
            *vr,
            field.clone(),
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: walk_substitute(&a.value, value_args),
                    span: a.span,
                })
                .collect(),
        ),
        IrExpr::VerbCall(vr, args) => IrExpr::VerbCall(
            *vr,
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: walk_substitute(&a.value, value_args),
                    span: a.span,
                })
                .collect(),
        ),
        IrExpr::BuiltinCall(b, args) => IrExpr::BuiltinCall(
            *b,
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: walk_substitute(&a.value, value_args),
                    span: a.span,
                })
                .collect(),
        ),
        IrExpr::UnresolvedCall(name, args) => IrExpr::UnresolvedCall(
            name.clone(),
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: walk_substitute(&a.value, value_args),
                    span: a.span,
                })
                .collect(),
        ),
        IrExpr::NamespaceCall { ns, method, args } => IrExpr::NamespaceCall {
            ns: *ns,
            method: method.clone(),
            args: args
                .iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: walk_substitute(&a.value, value_args),
                    span: a.span,
                })
                .collect(),
        },
        IrExpr::StructLit { name, ctor, fields } => IrExpr::StructLit {
            name: name.clone(),
            ctor: ctor.clone(),
            fields: fields
                .iter()
                .map(|f| dsl_ast::ir::IrFieldInit {
                    name: f.name.clone(),
                    value: walk_substitute(&f.value, value_args),
                    span: f.span,
                })
                .collect(),
        },
        IrExpr::Ctor { name, ctor, args } => IrExpr::Ctor {
            name: name.clone(),
            ctor: ctor.clone(),
            args: args.iter().map(|a| walk_substitute(a, value_args)).collect(),
        },
        IrExpr::Match { scrutinee, arms } => IrExpr::Match {
            scrutinee: Box::new(walk_substitute(scrutinee, value_args)),
            arms: arms
                .iter()
                .map(|arm| dsl_ast::ir::IrMatchArm {
                    pattern: arm.pattern.clone(),
                    body: walk_substitute(&arm.body, value_args),
                    span: arm.span,
                })
                .collect(),
        },
        IrExpr::If { cond, then_expr, else_expr } => IrExpr::If {
            cond: Box::new(walk_substitute(cond, value_args)),
            then_expr: Box::new(walk_substitute(then_expr, value_args)),
            else_expr: else_expr
                .as_ref()
                .map(|e| Box::new(walk_substitute(e, value_args))),
        },
        IrExpr::PerUnit { expr, delta } => IrExpr::PerUnit {
            expr: Box::new(walk_substitute(expr, value_args)),
            delta: Box::new(walk_substitute(delta, value_args)),
        },
        IrExpr::AbilityOnCooldown(inner) => {
            IrExpr::AbilityOnCooldown(Box::new(walk_substitute(inner, value_args)))
        }
        IrExpr::BeliefsAccessor { observer, target, field } => IrExpr::BeliefsAccessor {
            observer: Box::new(walk_substitute(observer, value_args)),
            target: Box::new(walk_substitute(target, value_args)),
            field: field.clone(),
        },
        IrExpr::BeliefsConfidence { observer, target } => IrExpr::BeliefsConfidence {
            observer: Box::new(walk_substitute(observer, value_args)),
            target: Box::new(walk_substitute(target, value_args)),
        },
        IrExpr::BeliefsView { observer, view_name } => IrExpr::BeliefsView {
            observer: Box::new(walk_substitute(observer, value_args)),
            view_name: view_name.clone(),
        },
        // Leaves carrying no nested `IrExprNode` — clone directly.
        IrExpr::LitBool(_)
        | IrExpr::LitInt(_)
        | IrExpr::LitFloat(_)
        | IrExpr::LitString(_)
        | IrExpr::Event(_)
        | IrExpr::Entity(_)
        | IrExpr::View(_)
        | IrExpr::Verb(_)
        | IrExpr::Namespace(_)
        | IrExpr::NamespaceField { .. }
        | IrExpr::EnumVariant { .. }
        | IrExpr::AbilityTag { .. }
        | IrExpr::AbilityHint
        | IrExpr::AbilityHintLit(_)
        | IrExpr::AbilityRange
        | IrExpr::Raw(_) => node.kind.clone(),
    };
    IrExprNode {
        kind: new_kind,
        span: node.span,
    }
}

/// Pick the [`SpatialQueryKind`] for a mask. Three routing branches:
///
/// 1. **Phase 7 — `from spatial.<name>(args)`** (the new
///    general-spatial-queries surface). Look up the registered
///    `spatial_query <name>(self, candidate, …)` decl in
///    `comp.spatial_queries`, substitute the call-site value-args
///    into the filter via [`walk_substitute`], lower with
///    `target_local = true` via [`lower_filter_for_mask`], and wrap
///    the resulting `CgExprId` in
///    [`SpatialQueryKind::FilteredWalk`].
/// 2. **Legacy — `from query.nearby_agents(...)`** (pre-Phase-7
///    wolf-sim convention). Routes to
///    [`SpatialQueryKind::EngagementQuery`] when the predicate
///    references engagement-flavoured access patterns
///    (`agents.is_hostile_to`, `agents.engaged_with`, any
///    `IrExpr::ViewCall` — conservative widening), otherwise
///    [`SpatialQueryKind::KinQuery`]. Phase 7 Task 6 will retire
///    this branch once all wolf-sim masks have migrated; until
///    then, the heuristic stays for backwards compat.
/// 3. **No `from` clause** — returns `None` (resolves to
///    [`DispatchShape::PerAgent`]).
fn mask_spatial_kind(
    mask: &MaskIR,
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
) -> Option<SpatialQueryKind> {
    let source = mask.candidate_source.as_ref()?;
    match &source.kind {
        IrExpr::NamespaceCall {
            ns: NamespaceId::Spatial,
            method,
            args,
        } => {
            let decl = comp
                .spatial_queries
                .iter()
                .find(|s| &s.name == method)?;
            let filter_with_args = walk_substitute(&decl.filter, args);
            let filter_id = lower_filter_for_mask(&filter_with_args, ctx).ok()?;
            Some(SpatialQueryKind::FilteredWalk { filter: filter_id })
        }
        // No other from-clause shapes recognised. Phase 7 dropped the
        // legacy `query.nearby_agents` heuristic; only `spatial.<name>`
        // (registered `spatial_query` decls) is supported.
        _ => None,
    }
}


/// Lower every [`ViewIR`] in source order. Each materialized view
/// produces one [`ComputeOpKind::ViewFold`] op per fold handler;
/// lazy views produce zero ops (just intern the name).
///
/// The driver builds [`HandlerResolution`]s from the per-handler
/// [`FoldHandlerIR::pattern`]'s `EventRef`. An unresolved pattern
/// (the resolver should have populated `event` at parse time)
/// surfaces as a typed [`LoweringError::UnresolvedEventPattern`]
/// diagnostic and the view is skipped.
fn lower_all_views(
    comp: &Compilation,
    event_rings: &[EventRingId],
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    for (i, view) in comp.views.iter().enumerate() {
        let view_id = ViewId(i as u32);
        // Reset per-rule rng counter — same reasoning as
        // `lower_all_physics` above. Each view body's rng calls
        // (typically in propagation handlers) get their own
        // 0-based extra sequence.
        ctx.reset_rng_counter();
        let resolutions = match build_view_handler_resolutions(view, &comp.events, event_rings) {
            Ok(r) => r,
            Err(e) => {
                diagnostics.push(e);
                continue;
            }
        };
        if let Err(e) = lower_view(view_id, view, &resolutions, ctx) {
            diagnostics.push(e);
        }
    }
}

/// Build the per-handler `(EventKindId, EventRingId)` resolution
/// list for a view. Returns one entry per fold handler in the view's
/// body in source order; an empty vec for lazy views (their
/// handler list is empty by construction).
fn build_view_handler_resolutions(
    view: &ViewIR,
    events: &[dsl_ast::ir::EventIR],
    event_rings: &[EventRingId],
) -> Result<Vec<HandlerResolution>, LoweringError> {
    match (&view.kind, &view.body) {
        (ViewKind::Lazy, ViewBodyIR::Expr(_)) => Ok(Vec::new()),
        (ViewKind::Materialized(_), ViewBodyIR::Fold { handlers, .. }) => handlers
            .iter()
            .map(|h| build_fold_handler_resolution(view, h, events, event_rings))
            .collect(),
        // Kind/body mismatch is the view pass's concern — return an
        // empty resolution list so it can surface its own typed
        // ViewKindBodyMismatch diagnostic.
        (ViewKind::Lazy, ViewBodyIR::Fold { .. })
        | (ViewKind::Materialized(_), ViewBodyIR::Expr(_)) => Ok(Vec::new()),
        // Plan I — beliefs reuse the fold-handler resolution shape for
        // their propagation handlers (the parser-side I.1 emits
        // ViewBodyIR::Fold for belief bodies). When the parser lands
        // ViewKind::Belief, this arm walks the fold handlers via the
        // existing helper. Until I.1 lands no beliefs reach here.
        (ViewKind::Belief, ViewBodyIR::Fold { handlers, .. }) => handlers
            .iter()
            .map(|h| build_fold_handler_resolution(view, h, events, event_rings))
            .collect(),
        (ViewKind::Belief, ViewBodyIR::Expr(_)) => Ok(Vec::new()),
    }
}

fn build_fold_handler_resolution(
    _view: &ViewIR,
    handler: &FoldHandlerIR,
    events: &[dsl_ast::ir::EventIR],
    event_rings: &[EventRingId],
) -> Result<HandlerResolution, LoweringError> {
    let event_ref = handler
        .pattern
        .event
        .ok_or(LoweringError::UnresolvedEventPattern {
            event_name: handler.pattern.name.clone(),
            span: handler.pattern.span,
        })?;
    let (kind, ring) = resolve_event_ref(
        event_ref,
        &handler.pattern.name,
        handler.pattern.span,
        events,
        event_rings,
    )?;
    Ok(HandlerResolution {
        event_kind: kind,
        source_ring: ring,
    })
}

/// Lower every [`PhysicsIR`] in source order. Each rule produces
/// one [`ComputeOpKind::PhysicsRule`] op per handler (per-handler
/// lowering failures accumulate as diagnostics; the next rule
/// continues).
///
/// The driver picks [`ReplayabilityFlag::Replayable`] for every
/// rule today — see the module-level "Limitations" note on
/// replayability annotation parsing.
fn lower_all_physics(
    comp: &Compilation,
    event_rings: &[EventRingId],
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    for (i, rule) in comp.physics.iter().enumerate() {
        let rule_id = PhysicsRuleId(i as u32);
        // `@cpu_only` physics rules emit only on the host side
        // (chronicle prose with String payloads, dev-time logging,
        // …). The CG / WGSL pipeline doesn't get an op for them so
        // the GPU emit doesn't try to lower their bodies — every
        // GPU-only invariant (no Strings, only Pod fields, no
        // host-side intrinsics) is bypassed for the rule. The host
        // runtime walks `comp.physics` directly to dispatch them.
        if rule.cpu_only {
            continue;
        }
        // Reset per-rule rng counter so the first `rng.<method>()`
        // in each rule body gets `extra = 0` (bare per_agent_u32
        // form — preserves every existing fixture's RNG stream).
        ctx.reset_rng_counter();
        let resolutions = match build_physics_handler_resolutions(rule, &comp.events, event_rings) {
            Ok(r) => r,
            Err(e) => {
                diagnostics.push(e);
                continue;
            }
        };
        let replayable = physics_replayability(rule);
        // Record `@phase(post)` rules into the program-level side-table
        // for the well-formed P6 check. The replayability flag stays
        // `Replayable` (see [`physics_replayability`] doc) so the
        // schedule's fusion partitioning is unchanged.
        if is_post_phase_authored(&rule.annotations) {
            ctx.builder.mark_post_phase_physics_rule(rule_id);
        }
        // Record `@cascade(max_iter=N)` rules into the program-level
        // side-table so the schedule synthesizer can emit a per-rule
        // `DispatchOp::FixedPoint { max_iter: N }` instead of the
        // hardcoded default. Runtime FixedPoint dispatch is still a
        // catch-all no-op today (see build_helper.rs ~line 2708);
        // landing the surface here is a prerequisite for that wiring.
        if let Some(max_iter) = cascade_max_iter_authored(&rule.annotations) {
            ctx.builder.mark_cascade_max_iter(rule_id, max_iter);
        }
        if let Err(e) = lower_physics(rule_id, replayable, rule, &resolutions, ctx) {
            diagnostics.push(e);
        }
    }
}

/// Today every physics rule is treated as replayable. The plan
/// defers `@phase(post)` parsing to a follow-up; see the
/// module-level "Limitations" note.
///
/// The P6 check separately consults the rule's `@phase(post)`
/// annotation (via [`is_post_phase_authored`]) so authored chronicle
/// physics rules don't trip P6 false positives even though the
/// replayability flag still reads `Replayable` here. Wiring
/// `@phase(post)` through to fusion / emit ring routing is a
/// downstream change that must coordinate with each production
/// runtime crate's hardcoded fused kernel names; that work is out
/// of scope for the Gap X fix (2026-05-04 duel_1v1 discovery note).
fn physics_replayability(_rule: &PhysicsIR) -> ReplayabilityFlag {
    ReplayabilityFlag::Replayable
}

/// Is this rule annotated `@phase(post)`? Mirrors the bare-positional-
/// ident form recognised by [`super::physics::is_per_agent_phase`];
/// the args list must be exactly `[Ident("post")]`. Used by the well-
/// formed P6 check to exempt authored chronicle physics rules from
/// the "agent-field write outside ViewFold" diagnostic — agent
/// mutation IS the spec'd channel for `@phase(post)` (damage
/// application, status updates, ground-snap, …).
///
/// Verb-cascade-synthesised physics rules carry empty annotations
/// (`PhysicsIR::annotations: Vec::new()` per
/// [`super::verb_expand::synthesize_cascade_physics`]) — they don't
/// match here and still flow through the strict P6 check.
pub(crate) fn is_post_phase_authored(annotations: &[dsl_ast::ast::Annotation]) -> bool {
    use dsl_ast::ast::{AnnotationArg, AnnotationValue};
    annotations.iter().any(|a| {
        a.name == "phase"
            && matches!(
                a.args.as_slice(),
                [AnnotationArg { key: None, value: AnnotationValue::Ident(s), .. }]
                    if s == "post"
            )
    })
}

/// Extract the `max_iter` value from a `@cascade(max_iter=N)` annotation
/// on a physics rule. Returns `None` when the annotation is absent or
/// when the form doesn't match (no args, wrong key, non-positive int).
///
/// Accepted shape: `@cascade(max_iter = <positive int literal>)` —
/// exactly one keyword argument with key `max_iter`. Negative or zero
/// values fall through (return `None`) so the schedule synthesizer
/// keeps the legacy hardcoded `max_iter = 8` default; the resolver
/// handles emitting a hard error for malformed forms.
///
/// Verb-cascade-synthesised physics rules carry empty annotations
/// (`PhysicsIR::annotations: Vec::new()` per
/// [`super::verb_expand::synthesize_cascade_physics`]) — they don't
/// match here and continue to receive the default iteration ceiling.
///
/// **Runtime status (2026-05-12):** the runtime `DispatchOp::FixedPoint`
/// arm is still a catch-all no-op (see
/// `crates/dsl_compiler/src/build_helper.rs` near the
/// "DispatchOp::FixedPoint, DispatchOp::GatedBy" comment block). A rule
/// annotated `@cascade(max_iter=N)` will have its synthesized SCHEDULE
/// entry emit `FixedPoint { max_iter: N }`, but the host will not loop
/// the kernel — it will silently skip dispatch. Landing the parser /
/// resolver / lower surface here is a prerequisite for the runtime
/// wiring follow-up.
pub(crate) fn cascade_max_iter_authored(
    annotations: &[dsl_ast::ast::Annotation],
) -> Option<u32> {
    use dsl_ast::ast::{AnnotationArg, AnnotationValue};
    for ann in annotations {
        if ann.name != "cascade" {
            continue;
        }
        if let [AnnotationArg {
            key: Some(k),
            value: AnnotationValue::Int(n),
            ..
        }] = ann.args.as_slice()
        {
            if k == "max_iter" && *n > 0 && *n <= u32::MAX as i64 {
                return Some(*n as u32);
            }
        }
    }
    None
}

fn build_physics_handler_resolutions(
    rule: &PhysicsIR,
    events: &[dsl_ast::ir::EventIR],
    event_rings: &[EventRingId],
) -> Result<Vec<HandlerResolution>, LoweringError> {
    rule.handlers
        .iter()
        .map(|handler| build_physics_handler_resolution(handler, events, event_rings))
        .collect()
}

fn build_physics_handler_resolution(
    handler: &dsl_ast::ir::PhysicsHandlerIR,
    events: &[dsl_ast::ir::EventIR],
    event_rings: &[EventRingId],
) -> Result<HandlerResolution, LoweringError> {
    use dsl_ast::ir::IrPhysicsPattern;
    match &handler.pattern {
        IrPhysicsPattern::Kind(p) => {
            let event_ref = p.event.ok_or(LoweringError::UnresolvedEventPattern {
                event_name: p.name.clone(),
                span: p.span,
            })?;
            let (kind, ring) =
                resolve_event_ref(event_ref, &p.name, p.span, events, event_rings)?;
            Ok(HandlerResolution {
                event_kind: kind,
                source_ring: ring,
            })
        }
        IrPhysicsPattern::Tag { span, name, .. } => {
            // Tag patterns are deferred at the physics-pass layer
            // (see physics.rs's `UnsupportedPhysicsStmt {
            // ast_label: "TagPattern", .. }` gate). The driver
            // can't resolve a tag pattern to a single (kind, ring)
            // pair — it expands to N kind-pattern handlers — so
            // we surface the tag's source name as an unresolved
            // pattern diagnostic. The physics pass will then
            // surface its own deferral when it sees the same
            // pattern.
            Err(LoweringError::UnresolvedEventPattern {
                event_name: name.clone(),
                span: *span,
            })
        }
    }
}

/// Resolve an [`EventRef`] (an index into `comp.events`) to its
/// allocated `(EventKindId, EventRingId)` pair. The mapping mirrors
/// `populate_event_kinds`:
///
/// - Engine-aliased events (e.g. `EffectDamageApplied = 26`) read
///   their hardcoded discriminant from the IR's `engine_kind_id`
///   field. This makes the kernel filter constant agree with the
///   dispatcher's hardcoded write tag (closed loop for the chronicle
///   pipeline).
/// - User-declared events take the next sequential id that is not
///   reserved by the engine alias table.
///
/// Both cases go through `dsl_ast::engine_events::event_kind_id_at`,
/// which is the same allocator `populate_event_kinds` runs in batch —
/// so the two can't drift.
///
/// A ref pointing past the table surfaces as a typed diagnostic.
fn resolve_event_ref(
    event_ref: EventRef,
    name: &str,
    span: dsl_ast::ast::Span,
    events: &[dsl_ast::ir::EventIR],
    event_rings: &[EventRingId],
) -> Result<(EventKindId, EventRingId), LoweringError> {
    let i = event_ref.0 as usize;
    let ring = event_rings.get(i).copied().ok_or_else(|| {
        LoweringError::UnresolvedEventPattern {
            event_name: name.to_string(),
            span,
        }
    })?;
    let kind_id = dsl_ast::engine_events::event_kind_id_at(events, i).ok_or_else(|| {
        LoweringError::UnresolvedEventPattern {
            event_name: name.to_string(),
            span,
        }
    })?;
    Ok((EventKindId(kind_id), ring))
}

/// Lower every [`ScoringIR`] in source order. Each decl becomes
/// one [`ComputeOpKind::ScoringArgmax`] op (per-decl lowering
/// failures accumulate; the next decl continues).
fn lower_all_scoring(
    comp: &Compilation,
    ctx: &mut LoweringCtx<'_>,
    diagnostics: &mut Vec<LoweringError>,
) {
    for (i, scoring) in comp.scoring.iter().enumerate() {
        let scoring_id = ScoringId(i as u32);
        if let Err(e) = lower_scoring(scoring_id, scoring, ctx) {
            diagnostics.push(e);
        }
    }
}

/// Synthesize the Movement op: a per-agent
/// [`ComputeOpKind::PhysicsRule`] (with `on_event = None`) that
/// consumes scoring's chosen action+target output and updates each
/// agent's position. The op carries an empty body; its WGSL emit is
/// driven by the `MOVEMENT_BODY` template in `cg/emit/kernel.rs`,
/// which reads from the structural buffer bindings derived from the
/// op's `reads` / `writes` signature.
///
/// Allocates the next free [`PhysicsRuleId`] (one past the highest
/// rule id allocated by `lower_all_physics`) and interns the rule
/// name `"movement"` on the program's interner. Surfaces interner
/// duplicate-name conflicts as
/// [`LoweringError::BuilderRejected`].
///
/// Movement is `replayable` because the `AgentMoved` events it
/// emits feed into the deterministic ring (the engagement_on_move
/// physics rule and its descendants fold them into trace state).
/// `AgentFled` shares the same ring; both are listed in
/// `assets/sim/events.sim` as the canonical replayable surface.
///
/// # Phase 6 Task 3 contract
///
/// The op's `reads` set names every binding the WGSL body touches:
/// - `ScoringOutput` (action + target lookup).
/// - `AgentField { Pos, Self_ }` and `AgentField { Pos, Target(_) }`
///   (self pos + target pos, the latter resolves through the
///   structural placeholder until per-thread target resolution
///   lands).
/// - `AgentField { Alive, Self_ }` (dead-agent skip predicate).
/// - `SimCfgBuffer` (read for tick + move_speed).
///
/// The `writes` set names:
/// - `AgentField { Pos, Self_ }` (the per-agent position update).
/// - `EventRing { ring: 0, kind: Append }` (AgentMoved /
///   AgentFled emits land in the shared event ring).
fn synthesize_movement_op(ctx: &mut LoweringCtx<'_>) -> Result<(), LoweringError> {
    // Allocate the next PhysicsRuleId past whatever lower_all_physics
    // already used. The interner's `physics_rules` map size is the
    // high water mark — every PhysicsRuleId ever interned is keyed
    // there.
    let next_rule_id = PhysicsRuleId(
        ctx.builder.program().interner.physics_rules.len() as u32,
    );
    ctx.builder
        .intern_physics_rule_name(next_rule_id, "movement".to_string())
        .map_err(|e| LoweringError::BuilderRejected {
            error: e,
            span: dsl_ast::ast::Span::dummy(),
        })?;

    // Empty body: the WGSL emit short-circuits PerAgent PhysicsRule
    // to a hand-written `MOVEMENT_BODY` template, so no IR statements
    // are required for emit fidelity. The op's `reads` / `writes`
    // (recorded below via `record_read` / `record_write`) drive BGL
    // synthesis.
    let body = ctx
        .builder
        .add_stmt_list(CgStmtList::new(vec![]))
        .map_err(|e| LoweringError::BuilderRejected {
            error: e,
            span: dsl_ast::ast::Span::dummy(),
        })?;

    let kind = ComputeOpKind::PhysicsRule {
        rule: next_rule_id,
        on_event: None,
        body,
        replayable: ReplayabilityFlag::Replayable,
    };
    let op_id = ctx
        .builder
        .add_op(kind, DispatchShape::PerAgent, dsl_ast::ast::Span::dummy())
        .map_err(|e| LoweringError::BuilderRejected {
            error: e,
            span: dsl_ast::ast::Span::dummy(),
        })?;

    // Inject the structural reads + writes the WGSL body touches.
    // The auto-walker can't see them (the body is empty) so this is
    // the canonical seam — same shape as `wire_source_ring_reads`
    // for PerEvent rules.
    //
    // **Runtime aliasing constraint** (Phase 6 Task 5 / 6 territory):
    // every `AgentField { … }` handle structurally aliases onto the
    // single resident `agents` buffer. wgpu rejects two bindings to
    // the same buffer where one is read_only and the other is
    // read_write in the same compute pass. Movement records ONLY
    // `Pos` (a single read_write alias) here — the `Alive`-skip
    // predicate the body needs is bounded by `cfg.agent_cap` at the
    // PerAgent preamble layer (`if (agent_id >= cfg.agent_cap)
    // { return; }`); the dead-agent case is one extra branch that
    // doesn't change the buffer alias surface. This minimizes the
    // alias footprint; future Apply-actions (Phase 6 Task 4) deals
    // with the multi-AgentField alias issue at its layer.
    //
    // **EventRing append**: the `AgentMoved` / `AgentFled` events
    // Movement should emit are NOT recorded here yet — adding a
    // third binding (`event_ring`, atomic-rw) plus the ring-cycle
    // edge it implies isn't gated cleanly by today's runtime
    // cascade pipeline. The emit lands when Phase 6 Task 4
    // (Apply-actions chain) ports the event-emit layer into CG.
    let ops = ctx.builder.ops_mut();
    let op = &mut ops[op_id.0 as usize];
    op.record_read(DataHandle::ScoringOutput);
    op.record_read(DataHandle::SimCfgBuffer);
    op.record_write(DataHandle::AgentField {
        field: AgentFieldId::Pos,
        target: AgentRef::Self_,
    });

    Ok(())
}

// ---------------------------------------------------------------------------
// Phase 3 helpers — spatial-query synthesis
// ---------------------------------------------------------------------------

/// Walk `prog.ops` and collect every distinct
/// [`SpatialQueryKind`] referenced by a
/// [`DispatchShape::PerPair { source: PerPairSource::SpatialQuery(k) }`]
/// dispatch. If the result is non-empty, prepend
/// [`SpatialQueryKind::BuildHash`] so the per-cell index exists
/// before any walk.
///
/// Returns an empty `Vec` when no user op needs a spatial query —
/// the BuildHash op is only synthesised when at least one consumer
/// exists.
fn collect_required_spatial_kinds(prog: &CgProgram) -> Vec<SpatialQueryKind> {
    let mut consumers: BTreeSet<SpatialQueryKind> = BTreeSet::new();
    let mut needs_build_hash = false;
    for op in &prog.ops {
        if let DispatchShape::PerPair {
            source: PerPairSource::SpatialQuery(kind),
        } = op.shape
        {
            consumers.insert(kind);
            needs_build_hash = true;
        }
        // ForEachNeighbor consumers: any op (typically a per-agent
        // PhysicsRule) that surfaces a `SpatialStorage` read in its
        // dependency walk needs the spatial grid populated. The
        // ForEachNeighbor stmt's body-walk
        // (`collect_list_dependencies`) pushes
        // `DataHandle::SpatialStorage { GridCells/GridOffsets }` as
        // structural reads, so we detect them here regardless of the
        // op's dispatch shape.
        if op.reads.iter().any(|h| matches!(
            h,
            crate::cg::data_handle::DataHandle::SpatialStorage { .. }
        )) {
            needs_build_hash = true;
        }
    }

    if !needs_build_hash {
        return Vec::new();
    }

    // Real counting sort: schedule the three phases in dependency
    // order before any consumer. The bounded `BuildHash` legacy
    // variant is no longer scheduled — the new three-phase build
    // produces an uncapped per-cell layout that the tiled-MoveBoid
    // emit consumes via `spatial_grid_starts[c..c+1]` slicing.
    // Pre-existing FilteredWalk consumers (the wolf-sim mask flow,
    // currently dormant in this fixture) were also wired against
    // the bounded layout; if a fixture re-enables them, they need
    // to be ported to the new starts/cells layout too.
    let mut kinds = Vec::with_capacity(consumers.len() + 5);
    kinds.push(SpatialQueryKind::BuildHashCount);
    kinds.push(SpatialQueryKind::BuildHashScanLocal);
    kinds.push(SpatialQueryKind::BuildHashScanCarry);
    kinds.push(SpatialQueryKind::BuildHashScanAdd);
    kinds.push(SpatialQueryKind::BuildHashScatter);
    for k in consumers {
        kinds.push(k);
    }
    kinds
}

// ---------------------------------------------------------------------------
// Phase 4 helpers — ring-edge wiring (pre-gate)
// ---------------------------------------------------------------------------

/// For each [`ComputeOp`] in `ops` whose dispatch shape is
/// [`DispatchShape::PerEvent { source_ring }`], record an
/// [`EventRingAccess::Read`] read on `source_ring`.
///
/// Without this, the well_formed cycle detector would see an
/// asymmetric event-ring graph (the dispatch carries the ring
/// identity but the reads list does not), missing producer/consumer
/// cycles between physics rules and view folds. The plan
/// amendment makes this a hard obligation on the driver.
///
/// Operates on a `&mut [ComputeOp]` rather than `&mut CgProgram` so
/// the driver can call it on the in-progress builder via
/// [`CgProgramBuilder::ops_mut`] before the cycle gate snapshot.
fn wire_source_ring_reads(ops: &mut [ComputeOp]) {
    for op in ops.iter_mut() {
        if let DispatchShape::PerEvent { source_ring } = op.shape {
            op.record_read(DataHandle::EventRing {
                ring: source_ring,
                kind: EventRingAccess::Read,
            });
        }
    }
}

/// Walk every user op's body's statement list and collect, per op
/// index, the set of destination [`EventRingId`]s every reachable
/// [`CgStmt::Emit`] resolves to. The driver's allocation rule pairs
/// `EventKindId(i)` with `EventRingId(i)`, so the walker can
/// translate each `Emit { event: EventKindId(i), .. }` directly.
///
/// Returns `(op_index, dest_ring)` pairs — duplicates are preserved
/// (an op that emits twice into the same ring records two entries;
/// downstream `record_write` consumers tolerate duplicates the same
/// way the auto-walker does for repeated `Assign`s).
///
/// Two-phase shape (collect-then-apply) avoids holding a mutable
/// borrow on the op list while traversing the (immutable) statement
/// arenas. See [`apply_emit_destination_rings`] for the application
/// half.
fn collect_emit_destination_rings(prog: &CgProgram) -> Vec<(usize, EventRingId)> {
    let mut out: Vec<(usize, EventRingId)> = Vec::new();
    for (op_index, op) in prog.ops.iter().enumerate() {
        let body_list = body_list_for_op_kind(&op.kind);
        let Some(list_id) = body_list else { continue };
        let mut emits: Vec<EventKindId> = Vec::new();
        collect_emits_in_list(list_id, prog, &mut emits);
        for _kind in emits {
            // Iter-2 unification: every event kind shares the single
            // `EventRingId(0)` ring (named `batch_events`). Pre-iter-2
            // this allocated `EventRingId(kind.0)` per-kind, but the
            // runtime has only one ring buffer; the per-kind ring ids
            // produced bindings like `event_ring_37` that didn't match
            // the unified `event_ring_0` source binding.
            //
            // See `populate_event_kinds` — `shared_ring = EventRingId(0)`.
            out.push((op_index, EventRingId(0)));
        }
    }
    out
}

/// Apply the (op_index, dest_ring) pairs collected by
/// [`collect_emit_destination_rings`] to `ops` via
/// [`ComputeOp::record_write`]. Pairs naming an op index past the
/// slice's length are silently dropped — the caller built the pairs
/// from a snapshot of the same builder, so this should never trip
/// in practice.
fn apply_emit_destination_rings(ops: &mut [ComputeOp], pairs: &[(usize, EventRingId)]) {
    for &(op_index, ring) in pairs {
        if let Some(op) = ops.get_mut(op_index) {
            op.record_write(DataHandle::EventRing {
                ring,
                kind: EventRingAccess::Append,
            });
        }
    }
}

/// Agent SoA stat columns the dispatcher's `agent_stat()` switch reads
/// at `caster_slot` (or `pred_agent` for predicate eval) for the
/// `scale_bonus` computation and per-effect predicate atoms. Mirrors
/// the `ScalingStatRef` → `AgentFieldId` mapping in
/// `engine::ability::program::CasterStats::get`:
///   AttackDamage(0), AbilityPower(1), MaxHp(2), Hp(3), Armor(4),
///   MagicResist(5), MoveSpeed(6), Mana(7).
const APPLY_ABILITY_AGENT_STAT_FIELDS: &[crate::cg::data_handle::AgentFieldId] = &[
    crate::cg::data_handle::AgentFieldId::AttackDamage,
    crate::cg::data_handle::AgentFieldId::AbilityPower,
    crate::cg::data_handle::AgentFieldId::MaxHp,
    crate::cg::data_handle::AgentFieldId::Hp,
    crate::cg::data_handle::AgentFieldId::Armor,
    crate::cg::data_handle::AgentFieldId::MagicResist,
    crate::cg::data_handle::AgentFieldId::MoveSpeed,
    crate::cg::data_handle::AgentFieldId::Mana,
];

/// Walk every op's body for [`CgStmt::ApplyAbility`] and record reads
/// on the three [`DataHandle::AbilityRegistryColumn`] handles the
/// dispatcher accesses. Without this, the BGL composer never
/// declares the matching `ability_registry_*` storage bindings and
/// the emitted WGSL kernel references undeclared identifiers
/// (caught by naga at frontend-parse time).
///
/// Symmetric to [`apply_emit_destination_rings`] but on the read
/// side. Both helpers solve the same shape of gap: `CgStmt::Emit`
/// and `CgStmt::ApplyAbility` are the two stmt variants whose WGSL
/// emit references storage identifiers that must be wired into the
/// surrounding kernel's binding set, but neither stmt carries the
/// handles directly in its IR shape.
fn wire_ability_registry_column_reads(prog: &CgProgram, ops: &mut [ComputeOp]) {
    use crate::cg::data_handle::{AbilityRegistryColumn, AgentRef};
    use crate::cg::op::ComputeOpKind;
    // Mirror the dispatcher's emit (`cg::emit::wgsl_body`):
    // it reads `effect_kinds`, `effect_payload_a`, `effect_payload_b`
    // every iteration of its slot loop, and Wave 1.5#9 added an inner
    // walk that reads the parallel `nested_effect_*` SoA columns
    // after every primary effect's chronicle write. Wave 1.5#4 GPU
    // wire-up (this slice) added `scaling_stat_refs` + `scaling_percents`
    // + per-stat agent SoA columns for the per-effect `scale_bonus =
    // Σ percent * caster_stat` bonus emitted before the chronicle
    // arm-chain.
    const COLUMNS: &[AbilityRegistryColumn] = &[
        AbilityRegistryColumn::EffectKinds,
        AbilityRegistryColumn::EffectPayloadA,
        AbilityRegistryColumn::EffectPayloadB,
        AbilityRegistryColumn::NestedEffectKinds,
        AbilityRegistryColumn::NestedEffectPayloadA,
        AbilityRegistryColumn::NestedEffectPayloadB,
        AbilityRegistryColumn::ScalingStatRefs,
        AbilityRegistryColumn::ScalingPercents,
        // Wave 1.5#7 GPU eval — per-effect when-predicate columns.
        AbilityRegistryColumn::WhenPredBinder,
        AbilityRegistryColumn::WhenPredField,
        AbilityRegistryColumn::WhenPredOp,
        AbilityRegistryColumn::WhenPredLiteral,
        // Wave 1.5#5 GPU chance-gate — per-effect q16 thresholds
        // (sentinel `CHANCE_NONE_SENTINEL = 0xFFFFu`). The
        // dispatcher reads `chances[effect_base + i]` and gates the
        // chronicle write on a PCG draw against the q16 threshold
        // for byte-equal cross-backend parity (P11).
        AbilityRegistryColumn::Chances,
    ];

    for (op_index, op) in ops.iter_mut().enumerate() {
        let snapshot_op = match prog.ops.get(op_index) {
            Some(o) => o,
            None => continue,
        };
        // Body-bearing op kinds: PhysicsRule / ViewFold. Other op
        // kinds (Plumbing / Mask / Scoring / etc.) carry no statement
        // list, so they can't host an ApplyAbility.
        let body_id = match &snapshot_op.kind {
            ComputeOpKind::PhysicsRule { body, .. } => *body,
            ComputeOpKind::ViewFold { body, .. } => *body,
            _ => continue,
        };
        if !list_contains_apply_ability(body_id, prog) {
            continue;
        }
        for column in COLUMNS {
            op.record_read(DataHandle::AbilityRegistryColumn { column: *column });
        }
        for field in APPLY_ABILITY_AGENT_STAT_FIELDS {
            op.record_read(DataHandle::AgentField {
                field:  *field,
                target: AgentRef::Self_,
            });
        }
    }
}

/// Recursively walk a [`CgStmtList`] for any [`CgStmt::ApplyAbility`].
/// Returns on the first hit — purely a yes/no probe driving the
/// `wire_ability_registry_column_reads` walk above.
fn list_contains_apply_ability(list_id: CgStmtListId, prog: &CgProgram) -> bool {
    let Some(list) = prog.stmt_lists.get(list_id.0 as usize) else {
        return false;
    };
    for stmt_id in &list.stmts {
        let Some(stmt) = prog.stmts.get(stmt_id.0 as usize) else { continue };
        match stmt {
            CgStmt::ApplyAbility { .. } => return true,
            CgStmt::If { then, else_, .. } => {
                if list_contains_apply_ability(*then, prog) { return true; }
                if let Some(else_list) = else_ {
                    if list_contains_apply_ability(*else_list, prog) { return true; }
                }
            }
            CgStmt::Match { arms, .. } => {
                for arm in arms {
                    if list_contains_apply_ability(arm.body, prog) { return true; }
                }
            }
            CgStmt::ForEachNeighborBody { body, .. } => {
                if list_contains_apply_ability(*body, prog) { return true; }
            }
            CgStmt::ForEachAgentBody { body, .. } => {
                if list_contains_apply_ability(*body, prog) { return true; }
            }
            CgStmt::Emit { .. }
            | CgStmt::Assign { .. }
            | CgStmt::Let { .. }
            | CgStmt::ForEachAgent { .. }
            | CgStmt::ForEachNeighbor { .. }
            | CgStmt::ViewStorageAppend { .. } => {}
        }
    }
    false
}

/// Recursively walk a [`CgStmtList`] for any
/// [`CgStmt::ApplyAbility`] with `with_aoe_dispatch == true`. Returns
/// on the first hit. Sibling to [`list_contains_apply_ability`] used by
/// the AOE-only column read wiring (`wire_apply_ability_aoe_reads`).
///
/// Lighter than passing the bool through `list_contains_apply_ability`
/// because (a) the existing helper has its own callers that don't care
/// about the AOE flag and (b) this lets the AOE wiring stay a no-op
/// for every fixture whose dispatchers have `with_aoe_dispatch ==
/// false` (every production runtime today — the BGL composer surfaces
/// zero spatial bindings on those dispatcher ops).
fn list_contains_apply_ability_with_aoe(list_id: CgStmtListId, prog: &CgProgram) -> bool {
    let Some(list) = prog.stmt_lists.get(list_id.0 as usize) else {
        return false;
    };
    for stmt_id in &list.stmts {
        let Some(stmt) = prog.stmts.get(stmt_id.0 as usize) else { continue };
        match stmt {
            CgStmt::ApplyAbility { with_aoe_dispatch: true, .. } => return true,
            CgStmt::ApplyAbility { .. } => {}
            CgStmt::If { then, else_, .. } => {
                if list_contains_apply_ability_with_aoe(*then, prog) { return true; }
                if let Some(else_list) = else_ {
                    if list_contains_apply_ability_with_aoe(*else_list, prog) { return true; }
                }
            }
            CgStmt::Match { arms, .. } => {
                for arm in arms {
                    if list_contains_apply_ability_with_aoe(arm.body, prog) { return true; }
                }
            }
            CgStmt::ForEachNeighborBody { body, .. } => {
                if list_contains_apply_ability_with_aoe(*body, prog) { return true; }
            }
            CgStmt::ForEachAgentBody { body, .. } => {
                if list_contains_apply_ability_with_aoe(*body, prog) { return true; }
            }
            CgStmt::Emit { .. }
            | CgStmt::Assign { .. }
            | CgStmt::Let { .. }
            | CgStmt::ForEachAgent { .. }
            | CgStmt::ForEachNeighbor { .. }
            | CgStmt::ViewStorageAppend { .. } => {}
        }
    }
    false
}

/// Wire the AOE Path B-specific reads onto every body-bearing op
/// whose statement tree contains at least one
/// [`CgStmt::ApplyAbility`] with `with_aoe_dispatch == true` (#121
/// follow-on, 2026-05-07).
///
/// The WGSL emit for AOE-on dispatchers (in
/// `cg::emit::wgsl_body::build_apply_ability_per_target_body`) walks
/// the 27-cell spatial neighborhood around the explicit cast target's
/// world position when `area_kinds[effect_base + i] == 0u` (Circle).
/// That walk references five additional bindings beyond what the
/// non-AOE dispatcher uses:
///
///   - `agent_pos` (read, vec3<f32>) — both for `aoe_center =
///     agent_pos[target_slot]` and `agent_pos[candidate]` per cell.
///   - `spatial_grid_starts` (read, u32) — per-cell `[start..end)`
///     slice indexing.
///   - `spatial_grid_cells` (read, u32) — the per-slot AgentId payload.
///   - `ability_registry_area_kinds` (read, u32) — the area-shape tag
///     per effect slot (sentinel `0xFFu` = no area; gates the walk).
///   - `ability_registry_area_args` (read, f32) — the radius f32 per
///     effect slot (4 f32 per slot, args[0] = radius for Circle).
///
/// Sibling to [`wire_ability_registry_column_reads`] (which handles
/// the always-needed AbilityRegistry SoA columns + agent stat fields)
/// — that helper records reads on EVERY dispatcher; this helper only
/// records on dispatchers that opted into AOE. Production runtimes
/// (`with_aoe_dispatch == false`) never see these reads, so the BGL
/// composer keeps their dispatcher binding-clean.
///
/// The `agent_pos` read auto-fires the spatial-build phases via
/// `collect_required_spatial_kinds` (BuildHash → BuildHashScanLocal →
/// BuildHashScanCarry → BuildHashScanAdd → BuildHashScatter), so the
/// runtime owning a flag-on dispatcher is responsible for allocating
/// the matching spatial buffers + the `agent_pos` SoA. Today only the
/// `apply_ability_smoke_runtime` opts in.
fn wire_apply_ability_aoe_reads(prog: &CgProgram, ops: &mut [ComputeOp]) {
    use crate::cg::data_handle::{
        AbilityRegistryColumn, AgentFieldId, AgentRef, SpatialStorageKind,
    };
    use crate::cg::op::ComputeOpKind;

    const AOE_COLUMNS: &[AbilityRegistryColumn] = &[
        AbilityRegistryColumn::AreaKinds,
        AbilityRegistryColumn::AreaArgs,
    ];
    const AOE_SPATIAL: &[SpatialStorageKind] = &[
        SpatialStorageKind::GridCells,
        SpatialStorageKind::GridStarts,
    ];

    for (op_index, op) in ops.iter_mut().enumerate() {
        let snapshot_op = match prog.ops.get(op_index) {
            Some(o) => o,
            None => continue,
        };
        // Same body-bearing op-kind set as
        // `wire_ability_registry_column_reads`. Other op kinds
        // (Plumbing / Mask / Scoring / etc.) carry no statement list.
        let body_id = match &snapshot_op.kind {
            ComputeOpKind::PhysicsRule { body, .. } => *body,
            ComputeOpKind::ViewFold { body, .. } => *body,
            _ => continue,
        };
        if !list_contains_apply_ability_with_aoe(body_id, prog) {
            continue;
        }
        // Agent SoA: position read at both `target_slot` (cast center)
        // and at every candidate AgentId pulled from the spatial cells.
        // Both index through the shared `agent_pos` SoA — one
        // `AgentField { Pos, Self_ }` read covers the whole binding
        // (the BGL composer doesn't differentiate read sites; it only
        // cares the binding is declared).
        op.record_read(DataHandle::AgentField {
            field:  AgentFieldId::Pos,
            target: AgentRef::Self_,
        });
        for column in AOE_COLUMNS {
            op.record_read(DataHandle::AbilityRegistryColumn { column: *column });
        }
        for kind in AOE_SPATIAL {
            op.record_read(DataHandle::SpatialStorage { kind: *kind });
        }
    }
}

/// Walk a [`CgStmtList`] for any `agents.set_beliefs_<field>(...)`
/// namespace call and return the matching
/// [`crate::cg::data_handle::BeliefStateColumn`] discriminants.
///
/// Reads the program's expression arena to inspect each statement's
/// embedded `CgExpr::NamespaceCall` nodes (lowered from the source
/// `agents.set_beliefs_<field>(...)` form by
/// `lower_namespace_call`). The result drives `record_write` on the
/// hosting op so the BGL composer surfaces the per-column binding.
///
/// Returns the `Vec<BeliefStateColumn>` so the caller can dedup +
/// record one write per touched column.
fn collect_belief_state_setter_writes(
    list_id: CgStmtListId,
    prog: &CgProgram,
) -> Vec<crate::cg::data_handle::BeliefStateColumn> {
    use crate::cg::data_handle::BeliefStateColumn;
    let mut out = Vec::new();
    fn walk_expr(
        expr_id: crate::cg::data_handle::CgExprId,
        prog: &CgProgram,
        out: &mut Vec<BeliefStateColumn>,
    ) {
        let Some(expr) = prog.exprs.get(expr_id.0 as usize) else { return };
        use crate::cg::expr::CgExpr;
        match expr {
            CgExpr::NamespaceCall { ns, method, args, .. } => {
                if matches!(ns, dsl_ast::ir::NamespaceId::Agents) {
                    if let Some(col) = method_to_belief_column(method.as_str()) {
                        out.push(col);
                    }
                }
                for a in args {
                    walk_expr(*a, prog, out);
                }
            }
            // Recurse through every other expression shape so nested
            // setters (rare today, but possible inside a let-binding
            // RHS) still surface.
            other => {
                for child in expr_children(other) {
                    walk_expr(child, prog, out);
                }
            }
        }
    }

    fn walk_list(
        list_id: CgStmtListId,
        prog: &CgProgram,
        out: &mut Vec<BeliefStateColumn>,
    ) {
        let Some(list) = prog.stmt_lists.get(list_id.0 as usize) else { return };
        for stmt_id in &list.stmts {
            let Some(stmt) = prog.stmts.get(stmt_id.0 as usize) else { continue };
            match stmt {
                CgStmt::Assign { value, .. } => walk_expr(*value, prog, out),
                CgStmt::Let { value, .. } => walk_expr(*value, prog, out),
                CgStmt::If { cond, then, else_ } => {
                    walk_expr(*cond, prog, out);
                    walk_list(*then, prog, out);
                    if let Some(else_list) = else_ {
                        walk_list(*else_list, prog, out);
                    }
                }
                CgStmt::Match { scrutinee, arms, .. } => {
                    walk_expr(*scrutinee, prog, out);
                    for arm in arms {
                        walk_list(arm.body, prog, out);
                    }
                }
                CgStmt::ForEachAgent { init, projection, .. } => {
                    walk_expr(*init, prog, out);
                    walk_expr(*projection, prog, out);
                }
                CgStmt::ForEachNeighbor { init, projection, .. } => {
                    walk_expr(*init, prog, out);
                    walk_expr(*projection, prog, out);
                }
                CgStmt::ForEachNeighborBody { body, .. } => walk_list(*body, prog, out),
                CgStmt::ForEachAgentBody { body, .. } => walk_list(*body, prog, out),
                CgStmt::Emit { fields, .. } => {
                    for (_, expr_id) in fields {
                        walk_expr(*expr_id, prog, out);
                    }
                }
                CgStmt::ApplyAbility { caster, target, .. } => {
                    walk_expr(*caster, prog, out);
                    walk_expr(*target, prog, out);
                }
                CgStmt::ViewStorageAppend { fields, .. } => {
                    // Plan G G3b/G3c — each field's bound expression
                    // could carry an embedded BeliefState column read
                    // (e.g. `last_known_hp` lookup as a struct-cell
                    // value). Walk every field expr just like Emit.
                    for (_, expr_id) in fields {
                        walk_expr(*expr_id, prog, out);
                    }
                }
            }
        }
    }
    walk_list(list_id, prog, &mut out);
    out.sort();
    out.dedup();
    out
}

/// Helper: enumerate the direct child `CgExprId`s of a `CgExpr` for
/// the recursive walk. Conservative — overlooks no children. Only the
/// shapes that can hold setter calls deeper in their tree need to be
/// listed; leaves return an empty vec.
fn expr_children(expr: &crate::cg::expr::CgExpr) -> Vec<crate::cg::data_handle::CgExprId> {
    use crate::cg::expr::CgExpr;
    let mut out = Vec::new();
    match expr {
        CgExpr::Binary { lhs, rhs, .. } => { out.push(*lhs); out.push(*rhs); }
        CgExpr::Unary { arg, .. } => out.push(*arg),
        CgExpr::Builtin { args, .. } => out.extend(args.iter().copied()),
        CgExpr::Select { cond, then, else_, .. } => {
            out.push(*cond);
            out.push(*then);
            out.push(*else_);
        }
        CgExpr::NamespaceCall { args, .. } => out.extend(args.iter().copied()),
        // Every other variant is a leaf for our purposes (no nested
        // CgExprId children that could host another setter call).
        _ => {}
    }
    out
}

/// Map a setter method name (e.g. `"set_beliefs_pos"`) to its
/// matching [`crate::cg::data_handle::BeliefStateColumn`]. Returns
/// `None` for any other method name (the namespace registry has many
/// other entries).
fn method_to_belief_column(
    method: &str,
) -> Option<crate::cg::data_handle::BeliefStateColumn> {
    use crate::cg::data_handle::BeliefStateColumn::*;
    match method {
        "set_beliefs_pos"               => Some(Pos),
        "set_beliefs_creature_type"     => Some(CreatureType),
        "set_beliefs_last_seen_tick"    => Some(LastSeenTick),
        "set_beliefs_confidence"        => Some(Confidence),
        "set_beliefs_suspicion"         => Some(Suspicion),
        "set_beliefs_flags"             => Some(Flags),
        _ => None,
    }
}

/// Mirror of [`method_to_belief_column`] for GETTER method names
/// (no `set_` prefix). Used by the Wave 3 ToM Phase 3.8 read-walk to
/// surface BGL bindings when a .sim consumer rule reads a belief cell.
fn method_to_belief_column_getter(
    method: &str,
) -> Option<crate::cg::data_handle::BeliefStateColumn> {
    use crate::cg::data_handle::BeliefStateColumn::*;
    match method {
        "beliefs_pos"               => Some(Pos),
        "beliefs_creature_type"     => Some(CreatureType),
        "beliefs_last_seen_tick"    => Some(LastSeenTick),
        "beliefs_confidence"        => Some(Confidence),
        "beliefs_suspicion"         => Some(Suspicion),
        "beliefs_flags"             => Some(Flags),
        _ => None,
    }
}

/// Sibling of [`collect_belief_state_setter_writes`] for getters:
/// walks the body's expression tree for `agents.beliefs_<field>(...)`
/// calls (no `set_` prefix) and returns the matching
/// [`crate::cg::data_handle::BeliefStateColumn`] discriminants. Wave 3
/// ToM Phase 3.8 — required so .sim-authored scry / reveal consumer
/// rules that read-modify-write belief cells surface the right BGL
/// bindings and the WGSL stub references resolve.
fn collect_belief_state_getter_reads(
    list_id: CgStmtListId,
    prog: &CgProgram,
) -> Vec<crate::cg::data_handle::BeliefStateColumn> {
    use crate::cg::data_handle::BeliefStateColumn;
    let mut out = Vec::new();
    fn walk_expr(
        expr_id: crate::cg::data_handle::CgExprId,
        prog: &CgProgram,
        out: &mut Vec<BeliefStateColumn>,
    ) {
        let Some(expr) = prog.exprs.get(expr_id.0 as usize) else { return };
        use crate::cg::expr::CgExpr;
        match expr {
            CgExpr::NamespaceCall { ns, method, args, .. } => {
                if matches!(ns, dsl_ast::ir::NamespaceId::Agents) {
                    if let Some(col) = method_to_belief_column_getter(method.as_str()) {
                        out.push(col);
                    }
                }
                for a in args {
                    walk_expr(*a, prog, out);
                }
            }
            other => {
                for child in expr_children(other) {
                    walk_expr(child, prog, out);
                }
            }
        }
    }
    fn walk_list(
        list_id: CgStmtListId,
        prog: &CgProgram,
        out: &mut Vec<BeliefStateColumn>,
    ) {
        let Some(list) = prog.stmt_lists.get(list_id.0 as usize) else { return };
        for stmt_id in &list.stmts {
            let Some(stmt) = prog.stmts.get(stmt_id.0 as usize) else { continue };
            match stmt {
                CgStmt::Assign { value, .. } => walk_expr(*value, prog, out),
                CgStmt::Let { value, .. } => walk_expr(*value, prog, out),
                CgStmt::If { cond, then, else_ } => {
                    walk_expr(*cond, prog, out);
                    walk_list(*then, prog, out);
                    if let Some(else_list) = else_ {
                        walk_list(*else_list, prog, out);
                    }
                }
                CgStmt::Match { scrutinee, arms, .. } => {
                    walk_expr(*scrutinee, prog, out);
                    for arm in arms {
                        walk_list(arm.body, prog, out);
                    }
                }
                CgStmt::ForEachAgent { init, projection, .. } => {
                    walk_expr(*init, prog, out);
                    walk_expr(*projection, prog, out);
                }
                CgStmt::ForEachNeighbor { init, projection, .. } => {
                    walk_expr(*init, prog, out);
                    walk_expr(*projection, prog, out);
                }
                CgStmt::ForEachNeighborBody { body, .. } => walk_list(*body, prog, out),
                CgStmt::ForEachAgentBody { body, .. } => walk_list(*body, prog, out),
                CgStmt::Emit { fields, .. } => {
                    for (_, expr_id) in fields {
                        walk_expr(*expr_id, prog, out);
                    }
                }
                CgStmt::ApplyAbility { caster, target, .. } => {
                    walk_expr(*caster, prog, out);
                    walk_expr(*target, prog, out);
                }
                CgStmt::ViewStorageAppend { fields, .. } => {
                    for (_, expr_id) in fields {
                        walk_expr(*expr_id, prog, out);
                    }
                }
            }
        }
    }
    walk_list(list_id, prog, &mut out);
    out.sort();
    out.dedup();
    out
}

/// Wire BeliefState setter writes AND getter reads onto every
/// body-bearing op whose statement tree contains at least one
/// `agents.set_beliefs_<field>` (write) or `agents.beliefs_<field>`
/// (read) call. Mirrors [`wire_apply_ability_aoe_reads`] in shape —
/// body-bearing op-kinds (PhysicsRule / ViewFold) are walked, and
/// per-column writes / reads are recorded so the BGL composer
/// surfaces the matching `beliefs_<field>` binding.
///
/// Wave 3 ToM Phase 3.8 — getter sibling added so .sim-authored scry /
/// reveal consumer rules that read-modify-write belief cells surface
/// the right BGL bindings.
///
/// Only invoked when [`LowerOpts::belief_state`] is `true`. Production
/// runtimes opt out → never see this walk → BGL stays binding-clean.
fn wire_belief_state_setter_writes(prog: &CgProgram, ops: &mut [ComputeOp]) {
    use crate::cg::data_handle::DataHandle;
    use crate::cg::op::ComputeOpKind;
    for (op_index, op) in ops.iter_mut().enumerate() {
        let snapshot_op = match prog.ops.get(op_index) {
            Some(o) => o,
            None => continue,
        };
        let body_id = match &snapshot_op.kind {
            ComputeOpKind::PhysicsRule { body, .. } => *body,
            ComputeOpKind::ViewFold { body, .. } => *body,
            _ => continue,
        };
        let write_columns = collect_belief_state_setter_writes(body_id, prog);
        for column in write_columns {
            op.record_write(DataHandle::BeliefStateColumn { column });
        }
        let read_columns = collect_belief_state_getter_reads(body_id, prog);
        for column in read_columns {
            op.record_read(DataHandle::BeliefStateColumn { column });
        }
    }
}

/// Wire the implicit `EventRing { Append }` write each
/// [`ComputeOpKind::ScoringArgmax`] op acquires by virtue of the
/// scoring kernel's WGSL body emitting the verb-expander-injected
/// `ActionSelected` event after per-agent argmax.
///
/// The scoring kernel's body emit
/// (`cg::emit::kernel::lower_scoring_argmax_body`) inlines the
/// ring-append for `ActionSelected` only when the program has the
/// event kind registered (a verb with non-empty `emit` exists). The
/// gating shape mirrors the WGSL emit's gate so the binding scanner
/// declares the `event_ring` + `event_tail` bindings exactly when
/// the body references them — a fixture without any verb cascade
/// stays binding-clean.
///
/// `prog` is the snapshot taken in Phase 4. The function inspects
/// `prog.interner.event_kinds` for the canonical name; the
/// destination ring is the post-iter-2 unified `EventRingId(0)`
/// (matching the emit-walker's allocation rule in
/// [`collect_emit_destination_rings`]).
fn wire_action_selected_writes(prog: &CgProgram, ops: &mut [ComputeOp]) {
    use crate::cg::lower::verb_expand::ACTION_SELECTED_EVENT_NAME;

    // Gate: only emit when the verb expander injected the event
    // kind. Pre-iter-2 the kind id was per-event; today the ring is
    // shared so we just need to know the kind exists.
    let has_action_selected = prog
        .interner
        .event_kinds
        .values()
        .any(|name| name.as_str() == ACTION_SELECTED_EVENT_NAME);
    if !has_action_selected {
        return;
    }

    for op in ops.iter_mut() {
        if matches!(op.kind, ComputeOpKind::ScoringArgmax { .. }) {
            // Same allocation rule as `collect_emit_destination_rings`:
            // every event kind shares the unified `EventRingId(0)`
            // post-iter-2; the structural namer drops the ring suffix
            // so the resulting binding lands as `event_ring`.
            op.record_write(DataHandle::EventRing {
                ring: EventRingId(0),
                kind: EventRingAccess::Append,
            });
        }
    }
}

/// Wire the implicit `MaskBitmap { mask }` reads each
/// [`ComputeOpKind::ScoringArgmax`] op acquires by virtue of the
/// scoring kernel's WGSL body emit
/// (`cg::emit::kernel::lower_scoring_argmax_body`) wrapping each
/// row in a mask-bit gate when the row's action name matches a
/// registered mask name.
///
/// The auto-walker for `ScoringArgmax` only collects reads from
/// utility / target / guard expressions (see
/// [`ComputeOpKind::compute_dependencies`]); the mask-gate
/// reference is synthesised in the body template, not in any
/// `CgExpr` node, so the driver records the read explicitly here.
/// Same shape as `wire_action_selected_writes` for the `event_ring`
/// emit — both close binding-scanner gaps the kernel emit
/// introduces.
///
/// The bridge from row → mask is the shared interner name: the
/// verb expander (`cg::lower::verb_expand`) creates the scoring
/// entry head and the mask head with the same synthetic name
/// (`verb_<Name>`), so every row whose action interns to a name
/// also bound by a mask gets the mask read recorded. Standard
/// rows (`Hold`, `MoveToward`, …) have no matching mask and
/// contribute nothing here.
///
/// Duplicates are tolerated by `record_read` (it does no
/// dedup — see [`ComputeOp::record_read`]'s contract) but a row
/// only contributes once per (op, mask) pair because rows in a
/// single scoring decl have distinct action names.
fn wire_scoring_mask_reads(prog: &CgProgram, ops: &mut [ComputeOp]) {
    // Pre-build a name → MaskId table so the per-row lookup is
    // constant-time. Cheap (one BTreeMap walk per scoring op);
    // would matter only if we had thousands of masks, which the
    // engine doesn't.
    let mask_by_name: std::collections::HashMap<&str, MaskId> = prog
        .interner
        .masks
        .iter()
        .map(|(id, name)| (name.as_str(), MaskId(*id)))
        .collect();

    for op in ops.iter_mut() {
        if let ComputeOpKind::ScoringArgmax { rows, .. } = &op.kind {
            // Collect distinct mask ids first so we don't push the
            // same handle twice when a single mask gates multiple
            // rows (today rows have distinct action names so this
            // is defensive only — but cheap and explicit).
            let mut to_record: Vec<MaskId> = Vec::new();
            for row in rows {
                let Some(action_name) = prog.interner.get_action_name(row.action) else {
                    continue;
                };
                let Some(mask_id) = mask_by_name.get(action_name).copied() else {
                    continue;
                };
                if !to_record.contains(&mask_id) {
                    to_record.push(mask_id);
                }
            }
            for mask_id in to_record {
                op.record_read(DataHandle::MaskBitmap { mask: mask_id });
            }
        }
    }
}

/// Wire the implicit AbilityRegistry `when_pred_*` SoA column reads
/// + agent stat SoA reads each [`ComputeOpKind::ScoringArgmax`] op
/// acquires when at least one of its rows references a verb that
/// dispatches a single-literal apply_ability (registered in
/// [`crate::cg::program::Interner::verb_action_ability_ids`]).
///
/// Predicate-aware scoring (Wave 1.5#7 follow-on): the scoring kernel
/// emit inlines per-effect when-predicate evaluation alongside utility
/// scoring, reading the same SoA columns the chronicle dispatcher
/// reads (`when_pred_*` plus agent stat SoA at the predicate's
/// resolved agent index).
///
/// Symmetric to [`wire_ability_registry_column_reads`] (the dispatcher
/// side) and to [`wire_scoring_mask_reads`] (the mask-gate side) —
/// closes the BGL composer gap created by the scoring kernel emit
/// referencing identifiers not surfaced through any `CgExpr` node.
fn wire_scoring_predicate_reads(prog: &CgProgram, ops: &mut [ComputeOp]) {
    use crate::cg::data_handle::{AbilityRegistryColumn, AgentRef};
    // Same column set the dispatcher consumes for predicate eval.
    const COLUMNS: &[AbilityRegistryColumn] = &[
        AbilityRegistryColumn::WhenPredBinder,
        AbilityRegistryColumn::WhenPredField,
        AbilityRegistryColumn::WhenPredOp,
        AbilityRegistryColumn::WhenPredLiteral,
    ];

    // Skip if no verb→ability mapping exists in the program (no
    // predicate-eval emit will fire for any row).
    if prog.interner.verb_action_ability_ids.is_empty() {
        return;
    }

    for op in ops.iter_mut() {
        let ComputeOpKind::ScoringArgmax { rows, .. } = &op.kind else {
            continue;
        };
        // Gate on at least one row whose action has a verb→ability
        // mapping. Rows without one fall back to mask-only gating; if
        // every row falls back, this op never references the
        // predicate-eval bindings and we keep it binding-clean.
        let any_predicate_row = rows.iter().any(|r| {
            prog.interner
                .verb_action_ability_ids
                .contains_key(&r.action.0)
        });
        if !any_predicate_row {
            continue;
        }
        for column in COLUMNS {
            op.record_read(DataHandle::AbilityRegistryColumn { column: *column });
        }
        // Predicate eval reads agent stat SoA at either caster_slot
        // (binder=0) or target_slot (binder=1) — pre-resolved to
        // PerPairCandidate for the scoring kernel's per-pair inner
        // loop. Recording both `Self_` and `PerPairCandidate` would
        // duplicate the binding; `Self_` is the canonical handle and
        // the WGSL emit reads `agent_<field>[pred_agent]` at runtime
        // where `pred_agent` is computed from caster_slot /
        // per_pair_candidate. Mirrors the dispatcher's `Self_`-only
        // recording in `wire_ability_registry_column_reads`.
        for field in APPLY_ABILITY_AGENT_STAT_FIELDS {
            op.record_read(DataHandle::AgentField {
                field: *field,
                target: AgentRef::Self_,
            });
        }
    }
}

/// Pick the body [`CgStmtListId`] for ops whose kind carries one;
/// `None` for kinds that don't have a stmt-list body.
///
/// Listed exhaustively rather than with a `_ =>` fallthrough so a
/// future op kind that introduces a new body shape forces an
/// explicit decision here instead of silently bypassing the Emit
/// walker.
fn body_list_for_op_kind(kind: &ComputeOpKind) -> Option<CgStmtListId> {
    match kind {
        ComputeOpKind::PhysicsRule { body, .. } => Some(*body),
        ComputeOpKind::ViewFold { body, .. } => Some(*body),
        ComputeOpKind::MaskPredicate { .. } => None,
        ComputeOpKind::ScoringArgmax { .. } => None,
        ComputeOpKind::SpatialQuery { .. } => None,
        ComputeOpKind::Plumbing { .. } => None,
        // ViewDecay carries no `CgStmtList` body — the kernel is
        // hand-synthesised at emit time from the `(view, rate_bits)`
        // payload, so there's no Emit-walker work to do here.
        ComputeOpKind::ViewDecay { .. } => None,
        // BeliefSocialMerge ditto — the per-cell merge body is
        // hand-emitted from `(view, on_event, op)`.
        ComputeOpKind::BeliefSocialMerge { .. } => None,
    }
}

/// Walk every interned [`EventKindId`] and surface a non-fatal
/// [`crate::cg::program::CgDiagnosticKind::DeclaredEventNeverEmitted`]
/// warning for any kind that is BOTH never produced (no `CgStmt::Emit`
/// anywhere in the program) AND never consumed (no rule `on_event`
/// handler subscribes to it).
///
/// The "never emitted AND never consumed" gate (rather than just "never
/// emitted") matters because some event kinds — `Tick` is the canonical
/// example — are produced HOST-side by the runtime, not via a DSL
/// `emit` statement. Such kinds always have a `CgStmt::Emit` count of
/// zero but ARE consumed by user rules; flagging them would produce a
/// false positive on every fixture in the codebase.
///
/// The verb-injected `ActionSelected` shape is also exempted: its
/// emit is inlined at the scoring-kernel emit level rather than via
/// `CgStmt::Emit`, so the `emitted` set wouldn't catch it even when
/// the kernel body DOES emit it.
///
/// Closes gap #6 from
/// `docs/superpowers/notes/2026-05-04-trade_market_probe.md`: the
/// trade_market_probe declares a `Shipment` event with no emit site
/// AND no `on Shipment` handler, and pre-this-fix the compiler
/// accepted it silently. Now the declaration surfaces as a warning so
/// a future "declared then forgot to wire" defect is visible at
/// compile time.
///
/// Soft warning rather than hard error because declared-then-unused
/// events are sometimes intentional (placeholder for staged work).
fn warn_declared_events_never_emitted(
    comp: &Compilation,
    prog: &CgProgram,
    ctx: &mut LoweringCtx<'_>,
) {
    use crate::cg::lower::verb_expand::ACTION_SELECTED_EVENT_NAME;
    use crate::cg::program::{CgDiagnostic, CgDiagnosticKind, Severity};

    // Collect every event kind referenced by an `Emit` statement.
    let mut emitted: std::collections::BTreeSet<EventKindId> =
        std::collections::BTreeSet::new();
    for op in &prog.ops {
        let Some(list_id) = body_list_for_op_kind(&op.kind) else {
            continue;
        };
        let mut buf: Vec<EventKindId> = Vec::new();
        collect_emits_in_list(list_id, prog, &mut buf);
        for kind in buf {
            emitted.insert(kind);
        }
    }

    // Collect every event kind a rule `on_event` handler subscribes to.
    // The walk has two sources because `@phase(per_agent)` rules degrade
    // the op-level `on_event` to `None` at lowering time even when the
    // source `on Tick { }` pattern names a specific kind. The IR walk
    // catches the source-level subscription so `Tick` (consumed by every
    // per-agent rule via `on Tick { } where (...)`) doesn't trip the
    // warning.
    let mut consumed_names: std::collections::BTreeSet<&str> =
        std::collections::BTreeSet::new();
    for rule in &comp.physics {
        for handler in &rule.handlers {
            consumed_names.insert(handler.pattern.display_name());
        }
    }
    // Materialised view fold-handlers are also consumers — same shape
    // as physics handlers.
    for view in &comp.views {
        if let dsl_ast::ir::ViewBodyIR::Fold { handlers, .. } = &view.body {
            for handler in handlers {
                consumed_names.insert(handler.pattern.name.as_str());
            }
        }
    }

    let mut consumed: std::collections::BTreeSet<EventKindId> =
        std::collections::BTreeSet::new();
    for op in &prog.ops {
        match &op.kind {
            ComputeOpKind::PhysicsRule { on_event, .. } => {
                if let Some(kind) = on_event {
                    consumed.insert(*kind);
                }
            }
            ComputeOpKind::ViewFold { on_event, .. } => {
                consumed.insert(*on_event);
            }
            // Other op kinds (Mask, Scoring, ScoringArgmax, Movement,
            // SpatialQuery, Plumbing) don't subscribe to event kinds.
            _ => {}
        }
    }

    // Walk every interned event kind. Skip `ActionSelected` — the verb
    // expander injects it implicitly at the scoring-kernel emit level
    // rather than via a `CgStmt::Emit`, so the `emitted` set above
    // wouldn't see it even when it IS emitted by the kernel body.
    for (id, name) in &prog.interner.event_kinds {
        if name == ACTION_SELECTED_EVENT_NAME {
            continue;
        }
        let kind = EventKindId(*id);
        let consumed_at_op = consumed.contains(&kind);
        let consumed_at_source = consumed_names.contains(name.as_str());
        if !emitted.contains(&kind) && !consumed_at_op && !consumed_at_source {
            ctx.builder.add_diagnostic(CgDiagnostic::new(
                Severity::Warning,
                CgDiagnosticKind::DeclaredEventNeverEmitted { event: kind },
            ));
        }
    }
}

/// Recursively collect every [`CgStmt::Emit`]'s [`EventKindId`] from
/// the statement list named by `list_id`, descending through `If`
/// arms (both `then` and `else_`) and `Match` arm bodies.
///
/// Listed exhaustively over [`CgStmt`] variants — no `_ =>` arm —
/// so a future statement variant that introduces an emit-bearing
/// body forces an explicit case here.
fn collect_emits_in_list(list_id: CgStmtListId, prog: &CgProgram, out: &mut Vec<EventKindId>) {
    let Some(list) = prog.stmt_lists.get(list_id.0 as usize) else {
        return;
    };
    for &stmt_id in &list.stmts {
        let Some(stmt) = prog.stmts.get(stmt_id.0 as usize) else {
            continue;
        };
        match stmt {
            CgStmt::Emit { event, .. } => out.push(*event),
            CgStmt::If { then, else_, .. } => {
                collect_emits_in_list(*then, prog, out);
                if let Some(else_list) = else_ {
                    collect_emits_in_list(*else_list, prog, out);
                }
            }
            CgStmt::Match { arms, .. } => {
                for arm in arms {
                    collect_emits_in_list(arm.body, prog, out);
                }
            }
            CgStmt::ForEachNeighborBody { body, .. } => {
                // Body-form spatial walk carries an emit-bearing
                // body — descend into it so the per-pair
                // `Emit { … }` statements register their event
                // ring writes via `record_write` upstream.
                collect_emits_in_list(*body, prog, out);
            }
            CgStmt::ForEachAgentBody { body, .. } => {
                // Body-form unbounded walk over alive agent slots —
                // same recursion shape as `ForEachNeighborBody` so any
                // `emit` statements inside the body register their
                // event ring writes upstream.
                collect_emits_in_list(*body, prog, out);
            }
            CgStmt::Assign { .. }
            | CgStmt::Let { .. }
            | CgStmt::ForEachAgent { .. }
            | CgStmt::ForEachNeighbor { .. }
            | CgStmt::ViewStorageAppend { .. } => {
                // Plan G G3b/G3c — view-storage append writes to the
                // per-entity ring's primary + cursors slots, NOT to an
                // event ring. No emit-destination contribution.
            }
            CgStmt::ApplyAbility { .. } => {
                // #136 slice β step 4: ApplyAbility's WGSL dispatcher
                // (cg/emit/wgsl_body.rs) atomic-appends to the
                // chronicle ring once per non-EMPTY effect slot — the
                // dispatcher's silent-skip arms are no-ops at runtime
                // but the structural binding is required so the BGL
                // composer wires `event_ring` + `event_tail` into the
                // physics kernel.
                //
                // `collect_emit_destination_rings` collapses every
                // returned kind to the single shared ring
                // `EventRingId(0)` regardless of variant — so a
                // synthetic placeholder kind is enough to trigger
                // the EventRing(Append) write recording without
                // committing to the dispatcher's full per-event
                // layout map (that lands later when chronicle-append
                // wiring replaces the TODO markers).
                out.push(EventKindId(0));
            }
        }
    }
}

// ---------------------------------------------------------------------------
// Tests
// ---------------------------------------------------------------------------

#[cfg(test)]
mod tests {
    use super::*;
    use crate::cg::op::ComputeOpKind;
    use dsl_ast::ir::Compilation;

    /// Empty Compilation produces a well-formed program with only
    /// plumbing ops (the always-on UploadSimCfg / PackAgents /
    /// UnpackAgents / KickSnapshot quartet).
    #[test]
    fn empty_compilation_lowers_to_plumbing_only() {
        let comp = Compilation::default();
        let prog = lower_compilation_to_cg(&comp).expect("empty Compilation should lower cleanly");

        // Four always-on plumbing ops.
        assert_eq!(prog.ops.len(), 4);
        for op in &prog.ops {
            match &op.kind {
                ComputeOpKind::Plumbing { .. } => {}
                other => panic!("unexpected op kind: {other:?}"),
            }
        }
    }

    /// `lower_compilation_to_cg` runs the well_formed gate on the
    /// user-op-only program — no plumbing-derived cycle should fire
    /// in the diagnostic accumulator.
    #[test]
    fn empty_compilation_well_formed_gate_passes() {
        let comp = Compilation::default();
        let prog = lower_compilation_to_cg(&comp).expect("empty Compilation");
        // The plumbing layer's PackAgents/UnpackAgents pair would
        // form a cycle if the gate ran post-plumbing; assert the
        // returned program contains the cycle-creating ops without
        // a diagnostic firing (i.e., the gate ran pre-plumbing).
        let has_pack = prog.ops.iter().any(|op| {
            matches!(
                op.kind,
                ComputeOpKind::Plumbing {
                    kind: crate::cg::op::PlumbingKind::PackAgents
                }
            )
        });
        let has_unpack = prog.ops.iter().any(|op| {
            matches!(
                op.kind,
                ComputeOpKind::Plumbing {
                    kind: crate::cg::op::PlumbingKind::UnpackAgents
                }
            )
        });
        assert!(has_pack && has_unpack);
    }

    /// `wire_source_ring_reads` records one `EventRing { Read }`
    /// per `PerEvent`-shaped op. Using a synthetic builder-only
    /// fixture so we exercise the post-construction wiring without
    /// a full Compilation.
    #[test]
    fn wire_source_ring_reads_records_one_read_per_per_event_op() {
        use crate::cg::data_handle::EventRingId;
        use crate::cg::dispatch::DispatchShape;
        use crate::cg::op::{ComputeOpKind, PlumbingKind};
        use crate::cg::stmt::CgStmtList;
        use dsl_ast::ast::Span;

        let mut builder = CgProgramBuilder::new();
        // Add a plumbing op (PerAgent, no record_read fires).
        builder
            .add_op(
                ComputeOpKind::Plumbing {
                    kind: PlumbingKind::PackAgents,
                },
                DispatchShape::PerAgent,
                Span::dummy(),
            )
            .unwrap();
        // Add a body list for the PhysicsRule op below.
        let body = builder
            .add_stmt_list(CgStmtList::new(Vec::new()))
            .expect("empty list");
        // Add a PhysicsRule op with PerEvent shape.
        let _ = builder
            .add_op(
                ComputeOpKind::PhysicsRule {
                    rule: PhysicsRuleId(0),
                    on_event: Some(EventKindId(0)),
                    body,
                    replayable: ReplayabilityFlag::Replayable,
                },
                DispatchShape::PerEvent {
                    source_ring: EventRingId(7),
                },
                Span::dummy(),
            )
            .unwrap();

        let mut prog = builder.finish();
        wire_source_ring_reads(&mut prog.ops);

        // Op 0 (Plumbing/PerAgent) should have NO new EventRing read
        // appended for op 0 (auto-walker may have synthesized other
        // reads from PlumbingKind::dependencies).
        let op0 = &prog.ops[0];
        let added_event_ring = op0
            .reads
            .iter()
            .filter(|h| {
                matches!(
                    h,
                    DataHandle::EventRing {
                        ring: EventRingId(7),
                        kind: EventRingAccess::Read
                    }
                )
            })
            .count();
        assert_eq!(added_event_ring, 0);

        // Op 1 (PhysicsRule/PerEvent ring=7) should carry exactly one
        // EventRing { Read, ring=7 } from the wiring step (the
        // auto-walker doesn't synthesize source-ring reads — see
        // the physics.rs module docs).
        let op1 = &prog.ops[1];
        let wired = op1
            .reads
            .iter()
            .filter(|h| {
                matches!(
                    h,
                    DataHandle::EventRing {
                        ring: EventRingId(7),
                        kind: EventRingAccess::Read
                    }
                )
            })
            .count();
        assert_eq!(wired, 1);
    }

    /// `collect_required_spatial_kinds` returns an empty Vec when
    /// no user op shapes reference a spatial query, and a
    /// BuildHash-prefixed list when at least one does.

    /// `populate_variants_from_enums` surfaces a typed
    /// `DuplicateVariantInRegistry` diagnostic when two enums declare
    /// the same source-level variant name. Last-write-wins semantics
    /// remain in place; the diagnostic exists so callers (or future
    /// tests) can refuse the program without scanning the registry by
    /// hand.
    #[test]
    fn populate_variants_from_enums_flags_duplicate_variant() {
        use dsl_ast::ast::Span;
        use dsl_ast::ir::EnumIR;

        let mut comp = Compilation::default();
        // Two enums, both declaring a `Damage` variant. The second
        // occurrence collides with the first.
        comp.enums.push(EnumIR {
            name: "EffectOpA".to_string(),
            variants: vec!["Damage".to_string(), "Heal".to_string()],
            annotations: Vec::new(),
            span: Span::dummy(),
        });
        comp.enums.push(EnumIR {
            name: "EffectOpB".to_string(),
            variants: vec!["Damage".to_string()], // collides with EnumA's Damage
            annotations: Vec::new(),
            span: Span::dummy(),
        });

        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let mut diagnostics: Vec<LoweringError> = Vec::new();
        populate_variants_from_enums(&comp, &mut ctx, &mut diagnostics);

        // Exactly one duplicate diagnostic for `Damage` — the second
        // registration. `Heal` was unique; the first `Damage`
        // registered without conflict.
        let dup_count = diagnostics
            .iter()
            .filter(|d| matches!(d, LoweringError::DuplicateVariantInRegistry { name, .. } if name == "Damage"))
            .count();
        assert_eq!(
            dup_count, 1,
            "expected one DuplicateVariantInRegistry for `Damage`; got diagnostics: {diagnostics:?}"
        );
    }

    // ---- Task 5.5c, Patch 1: populate_config_consts -----------------

    /// Two ConfigIR blocks → 4 entries with ids 0..3 in source order.
    #[test]
    fn populate_config_consts_allocates_per_block_field_in_source_order() {
        use dsl_ast::ast::{ConfigDefault, Span};
        use dsl_ast::ir::{ConfigFieldIR, ConfigIR, IrType};

        let mut comp = Compilation::default();
        comp.configs.push(ConfigIR {
            name: "combat".to_string(),
            fields: vec![
                ConfigFieldIR {
                    name: "attack_range".to_string(),
                    ty: IrType::F32,
                    default: ConfigDefault::Float(1.0),
                    runtime: false,
                    span: Span::dummy(),
                },
                ConfigFieldIR {
                    name: "aggro_range".to_string(),
                    ty: IrType::F32,
                    default: ConfigDefault::Float(2.0),
                    runtime: false,
                    span: Span::dummy(),
                },
            ],
            annotations: Vec::new(),
            span: Span::dummy(),
        });
        comp.configs.push(ConfigIR {
            name: "movement".to_string(),
            fields: vec![ConfigFieldIR {
                name: "move_speed_mps".to_string(),
                ty: IrType::F32,
                default: ConfigDefault::Float(3.0),
                runtime: false,
                span: Span::dummy(),
            }],
            annotations: Vec::new(),
            span: Span::dummy(),
        });

        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let mut diagnostics: Vec<LoweringError> = Vec::new();
        populate_config_consts(&comp, &mut ctx, &mut diagnostics);

        assert!(diagnostics.is_empty(), "no diagnostics: {diagnostics:?}");
        assert_eq!(ctx.config_const_ids.len(), 3);
        assert_eq!(
            ctx.config_const_ids
                .get(&(NamespaceId::Config, "combat.attack_range".to_string())),
            Some(&ConfigConstId(0))
        );
        assert_eq!(
            ctx.config_const_ids
                .get(&(NamespaceId::Config, "combat.aggro_range".to_string())),
            Some(&ConfigConstId(1))
        );
        assert_eq!(
            ctx.config_const_ids
                .get(&(NamespaceId::Config, "movement.move_speed_mps".to_string())),
            Some(&ConfigConstId(2))
        );
    }

    /// Pre-seeding the registry surfaces a typed
    /// DuplicateConfigConstInRegistry diagnostic.
    #[test]
    fn populate_config_consts_flags_duplicate_key() {
        use dsl_ast::ast::{ConfigDefault, Span};
        use dsl_ast::ir::{ConfigFieldIR, ConfigIR, IrType};

        let mut comp = Compilation::default();
        comp.configs.push(ConfigIR {
            name: "combat".to_string(),
            fields: vec![ConfigFieldIR {
                name: "attack_range".to_string(),
                ty: IrType::F32,
                default: ConfigDefault::Float(1.0),
                runtime: false,
                span: Span::dummy(),
            }],
            annotations: Vec::new(),
            span: Span::dummy(),
        });

        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        // Pre-seed a colliding entry.
        ctx.register_config_const(
            NamespaceId::Config,
            "combat.attack_range".to_string(),
            ConfigConstId(99),
        );

        let mut diagnostics: Vec<LoweringError> = Vec::new();
        populate_config_consts(&comp, &mut ctx, &mut diagnostics);

        let dup = diagnostics.iter().find_map(|d| match d {
            LoweringError::DuplicateConfigConstInRegistry {
                key,
                prior_id,
                new_id,
            } => Some((key.clone(), prior_id.0, new_id.0)),
            _ => None,
        });
        assert_eq!(
            dup,
            Some(("combat.attack_range".to_string(), 99, 0)),
            "expected DuplicateConfigConstInRegistry; diagnostics: {diagnostics:?}"
        );
    }

    /// Type-driven config-const default routing: a `u32`-declared field
    /// emits as [`ConfigConstValue::U32`] (not `F32`), so the WGSL
    /// composer materialises `const config_<id>: u32 = <n>u;`. Without
    /// this routing the const would emit `f32 = <n>.0;` and a downstream
    /// `atomicStore(&event_ring[...], (config_<id>))` (where the slot is
    /// `array<atomic<u32>>`) would crash the WGSL validator with an
    /// `f32 → u32` auto-conversion error. See trade_market_probe doc
    /// GAP #1.
    #[test]
    fn populate_config_consts_routes_u32_default_to_u32_variant() {
        use dsl_ast::ast::{ConfigDefault, Span};
        use dsl_ast::ir::{ConfigFieldIR, ConfigIR, IrType};

        let mut comp = Compilation::default();
        comp.configs.push(ConfigIR {
            name: "market".to_string(),
            fields: vec![
                ConfigFieldIR {
                    name: "observation_bit".to_string(),
                    ty: IrType::U32,
                    default: ConfigDefault::Uint(5),
                    runtime: false,
                    span: Span::dummy(),
                },
                ConfigFieldIR {
                    name: "trade_amount".to_string(),
                    ty: IrType::F32,
                    default: ConfigDefault::Float(1.5),
                    runtime: false,
                    span: Span::dummy(),
                },
                ConfigFieldIR {
                    name: "delta".to_string(),
                    ty: IrType::I32,
                    default: ConfigDefault::Int(-3),
                    runtime: false,
                    span: Span::dummy(),
                },
            ],
            annotations: Vec::new(),
            span: Span::dummy(),
        });

        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let mut diagnostics: Vec<LoweringError> = Vec::new();
        populate_config_consts(&comp, &mut ctx, &mut diagnostics);
        assert!(diagnostics.is_empty(), "no diagnostics: {diagnostics:?}");

        let prog = builder.finish();
        let v0 = prog
            .config_const_values
            .get(&0)
            .expect("config const 0 missing");
        assert_eq!(
            *v0,
            ConfigConstValue::U32(5),
            "expected ConfigConstValue::U32(5) for u32-declared observation_bit; got {v0:?}"
        );
        assert_eq!(v0.wgsl_scalar_ty(), "u32");
        assert_eq!(v0.wgsl_literal(), "5u");

        let v1 = prog
            .config_const_values
            .get(&1)
            .expect("config const 1 missing");
        assert_eq!(*v1, ConfigConstValue::F32(1.5));
        assert_eq!(v1.wgsl_scalar_ty(), "f32");

        let v2 = prog
            .config_const_values
            .get(&2)
            .expect("config const 2 missing");
        assert_eq!(*v2, ConfigConstValue::I32(-3));
        assert_eq!(v2.wgsl_scalar_ty(), "i32");
        assert_eq!(v2.wgsl_literal(), "-3i");
    }

    // ---- Task 5.5c, Patch 3: mask_spatial_kind routing --------------

    fn mk_mask(predicate_kind: IrExpr, has_from: bool) -> MaskIR {
        use dsl_ast::ast::Span;
        use dsl_ast::ir::{IrActionHead, IrActionHeadShape, IrExprNode};
        MaskIR {
            head: IrActionHead {
                name: "M".to_string(),
                shape: IrActionHeadShape::None,
                span: Span::dummy(),
            },
            predicate: IrExprNode {
                kind: predicate_kind,
                span: Span::dummy(),
            },
            candidate_source: if has_from {
                Some(IrExprNode {
                    kind: IrExpr::NamespaceCall {
                        ns: NamespaceId::Query,
                        method: "nearby_agents".to_string(),
                        args: Vec::new(),
                    },
                    span: Span::dummy(),
                })
            } else {
                None
            },
            annotations: Vec::new(),
            span: Span::dummy(),
        }
    }

    /// Helper: build an empty Compilation + LoweringCtx for the
    /// `mask_spatial_kind` tests. The legacy heuristic branches don't
    /// touch `comp.spatial_queries` or `ctx`, so a default builder is
    /// safe; the new `from spatial.<name>` branch needs a registered
    /// decl which the legacy-routing tests intentionally don't exercise.
    fn mk_test_ctx() -> (Compilation, CgProgramBuilder) {
        (Compilation::default(), CgProgramBuilder::new())
    }





    #[test]
    fn mask_spatial_kind_returns_none_when_no_candidate_source() {
        let mask = mk_mask(IrExpr::LitBool(true), false);
        let (comp, mut builder) = mk_test_ctx();
        let mut ctx = LoweringCtx::new(&mut builder);
        assert_eq!(mask_spatial_kind(&mask, &comp, &mut ctx), None);
    }


    /// `populate_views` surfaces a typed `DuplicateViewInRegistry`
    /// diagnostic if `register_view` ever observes the same AST view
    /// ref twice. Driver allocates `ViewId(i)` in source order, so a
    /// real-world collision would be a driver-side defect — the
    /// typed surface lets a test assert the contract.
    #[test]
    fn populate_views_flags_duplicate_view() {
        use dsl_ast::ir::ViewRef;

        // We can't easily make `populate_views` itself emit a
        // duplicate (it iterates `0..comp.views.len()` and assigns
        // unique ids), but the typed registry is the same one used
        // by `register_view`. Pre-register a colliding entry to
        // exercise the diagnostic path; then run `populate_views`
        // on a one-view Compilation and assert the collision is
        // surfaced.
        let mut comp = Compilation::default();
        comp.views.push(dsl_ast::ir::ViewIR {
            name: "v0".to_string(),
            kind: dsl_ast::ir::ViewKind::Lazy,
            params: Vec::new(),
            return_ty: dsl_ast::ir::IrType::F32,
            body: dsl_ast::ir::ViewBodyIR::Expr(dsl_ast::ir::IrExprNode {
                kind: dsl_ast::ir::IrExpr::LitFloat(0.0),
                span: dsl_ast::ast::Span::dummy(),
            }),
            annotations: Vec::new(),
            decay: None,
            belief_gated: false,
            storage_packing: dsl_ast::ir::Packing::None,
            social_merges: Vec::new(),
            span: dsl_ast::ast::Span::dummy(),
        });

        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        // Pre-seed the registry with a stale entry for ViewRef(0)
        // so the driver's call collides.
        let prior_id = ViewId(99);
        let prior = ctx.register_view(ViewRef(0), prior_id);
        assert!(prior.is_none(), "registry should be empty before pre-seed");

        let mut diagnostics: Vec<LoweringError> = Vec::new();
        populate_views(&comp, &mut ctx, &mut diagnostics);

        let dup = diagnostics.iter().find_map(|d| match d {
            LoweringError::DuplicateViewInRegistry {
                ast_ref,
                prior_id,
                new_id,
            } => Some((ast_ref.0, prior_id.0, new_id.0)),
            _ => None,
        });
        assert_eq!(
            dup,
            Some((0, 99, 0)),
            "expected DuplicateViewInRegistry(ast_ref=0, prior=99, new=0); got diagnostics: {diagnostics:?}"
        );
    }

    // ---- lower_filter_for_mask helper -------------------------------------

    #[test]
    fn lower_filter_for_mask_binds_target_to_per_pair_candidate() {
        use crate::cg::expr::CgExpr;
        use crate::cg::program::CgProgramBuilder;
        use dsl_ast::ir::{IrExpr, IrExprNode, LocalRef};

        // Filter expression: bare `target` local. With target_local=true,
        // this should lower to CgExpr::PerPairCandidateId.
        let target_local = IrExprNode {
            kind: IrExpr::Local(LocalRef(0), "target".to_string()),
            span: dsl_ast::ast::Span::dummy(),
        };

        let mut builder = CgProgramBuilder::new();
        let filter_id = {
            let mut ctx = LoweringCtx::new(&mut builder);
            let id = lower_filter_for_mask(&target_local, &mut ctx)
                .expect("lowers target to PerPairCandidateId");
            // Helper must restore target_local to false on exit — verify
            // while ctx is still in scope (before it drops / builder is freed).
            assert!(
                !ctx.target_local,
                "target_local should be restored to false after lower_filter_for_mask"
            );
            id
        };

        let prog = builder.finish();
        let node = &prog.exprs[filter_id.0 as usize];
        match node {
            CgExpr::PerPairCandidateId => {} // expected
            other => panic!("expected PerPairCandidateId, got {other:?}"),
        }
    }

    #[test]
    fn lower_filter_for_mask_restores_target_local_on_lower_expr_failure() {
        use crate::cg::program::CgProgramBuilder;
        use dsl_ast::ir::{IrExpr, IrExprNode, LocalRef};

        // `IrExpr::Local` with an unrecognized name (not "self" or "target")
        // and no let-binding → `lower_bare_local` returns
        // `LoweringError::UnsupportedLocalBinding`. This exercises the
        // error path of `lower_filter_for_mask` without relying on any
        // arena or upstream-resolver machinery.
        let bad_expr = IrExprNode {
            kind: IrExpr::Local(LocalRef(99), "undefined_local".to_string()),
            span: dsl_ast::ast::Span::dummy(),
        };

        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        assert!(!ctx.target_local, "precondition: target_local starts false");

        let result = lower_filter_for_mask(&bad_expr, &mut ctx);
        assert!(result.is_err(), "lowering of undefined local should error");
        // Flag must be restored to its prior value (false) even on the
        // error path — the same save/restore contract as lower_mask.
        assert!(!ctx.target_local, "target_local must be restored even on error");
    }

    /// Wave 3 ToM Phase 3.5 — `populate_namespace_registry` exposes the
    /// 6 read methods + 6 setter methods for `agents.beliefs_<field>(o,
    /// s)` 2-arg view-call lowering. This is the registry surface that
    /// makes scry/reveal consumer rules typecheck and lower; the WGSL
    /// stubs are placeholders today (the actual SoA cell access lives
    /// in the runtime CPU consumer until a future phase emits a WGSL
    /// kernel from the chronicle stream).
    ///
    /// A regression that drops one of the 12 entries would surface in
    /// the .sim authors' first call site as `UnsupportedNamespaceCall`;
    /// pinning the count + the per-method shape here makes the gap
    /// loud at the registry boundary.
    #[test]
    fn populate_namespace_registry_includes_2arg_beliefs_methods() {
        use crate::cg::expr::CgTy;

        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        populate_namespace_registry(&mut ctx);

        let agents = ctx
            .namespace_registry
            .namespaces
            .get(&NamespaceId::Agents)
            .expect("agents namespace registered");

        // 6 readers — each takes (observer, subject) AgentIds.
        for (method, expected_ret_ty) in &[
            ("beliefs_pos", CgTy::Vec3F32),
            ("beliefs_creature_type", CgTy::U32),
            ("beliefs_last_seen_tick", CgTy::U32),
            ("beliefs_confidence", CgTy::U32),
            ("beliefs_suspicion", CgTy::U32),
            ("beliefs_flags", CgTy::U32),
        ] {
            let def = agents
                .methods
                .get(*method)
                .unwrap_or_else(|| panic!("agents.{method} should be registered"));
            assert_eq!(def.return_ty, *expected_ret_ty, "agents.{method} return type");
            assert_eq!(
                def.arg_tys, vec![CgTy::AgentId, CgTy::AgentId],
                "agents.{method} should take (observer, subject) AgentIds",
            );
            assert_eq!(
                def.wgsl_fn_name, format!("agents_{}", method),
                "agents.{method} WGSL fn name",
            );
        }

        // 6 setters — each takes (observer, subject, value).
        for (method, expected_value_ty) in &[
            ("set_beliefs_pos", CgTy::Vec3F32),
            ("set_beliefs_creature_type", CgTy::U32),
            ("set_beliefs_last_seen_tick", CgTy::U32),
            ("set_beliefs_confidence", CgTy::U32),
            ("set_beliefs_suspicion", CgTy::U32),
            ("set_beliefs_flags", CgTy::U32),
        ] {
            let def = agents
                .methods
                .get(*method)
                .unwrap_or_else(|| panic!("agents.{method} should be registered"));
            assert_eq!(def.return_ty, CgTy::Bool, "agents.{method} return type — bool ack");
            assert_eq!(
                def.arg_tys,
                vec![CgTy::AgentId, CgTy::AgentId, *expected_value_ty],
                "agents.{method} should take (observer, subject, value)",
            );
        }
    }

    // ---- Compiler debug mode Phase 2 (DebugWgslFlags) plumbing ----

    /// `DebugWgslFlags::NONE` is the default; `any()` is `false`.
    /// `ALL` flips every axis; `any()` is `true`.
    #[test]
    fn debug_wgsl_flags_default_and_const_any() {
        assert_eq!(DebugWgslFlags::default(), DebugWgslFlags::NONE);
        assert!(!DebugWgslFlags::NONE.any());
        assert!(DebugWgslFlags::ALL.any());
        assert!(DebugWgslFlags::ALL.event_kind_histogram);
        assert!(DebugWgslFlags::ALL.mask_hit_rate);
        assert!(DebugWgslFlags::ALL.score_kernel_visits);
    }

    /// `LowerOpts::default()` carries `DebugWgslFlags::NONE` and
    /// `DebugDepth::Off` — every existing fixture's
    /// `lower_compilation_to_cg(comp)` call inherits the
    /// zero-overhead shape.
    #[test]
    fn lower_opts_default_carries_off_and_none() {
        let opts = LowerOpts::default();
        assert_eq!(opts.debug, DebugDepth::Off);
        assert_eq!(opts.debug_wgsl, DebugWgslFlags::NONE);
        // Pre-existing fields preserve their defaults.
        assert!(!opts.aoe_dispatch);
        assert!(!opts.belief_state);
    }

    /// `LowerOpts.debug_wgsl` is plumbed through the driver onto
    /// the resulting `CgProgram.debug_wgsl`. The emit layer reads
    /// from the program's field via `EmitCtx::structural`.
    #[test]
    fn lower_opts_debug_wgsl_threads_to_cg_program() {
        let comp = Compilation::default();
        let opts = LowerOpts {
            debug_wgsl: DebugWgslFlags {
                event_kind_histogram: true,
                ..DebugWgslFlags::NONE
            },
            ..LowerOpts::default()
        };
        let prog = lower_compilation_to_cg_with_opts(&comp, opts)
            .expect("empty Compilation lowers cleanly");
        assert!(prog.debug_wgsl.event_kind_histogram);
        assert!(!prog.debug_wgsl.mask_hit_rate);
        assert!(!prog.debug_wgsl.score_kernel_visits);
    }
}
