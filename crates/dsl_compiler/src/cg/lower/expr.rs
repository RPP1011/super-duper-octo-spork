//! Expression lowering — `IrExprNode → CgExprId`.
//!
//! Walks resolved DSL IR (`dsl_ast::ir::IrExprNode`) and pushes nodes
//! into a [`CgProgramBuilder`]. Every constructed [`CgExpr`] is
//! type-checked via [`crate::cg::expr::type_check`] before its id is
//! returned, so a successful lowering produces a node whose claimed
//! [`CgTy`] matches its operand types.
//!
//! See `docs/superpowers/plans/2026-04-29-dsl-compute-graph-ir.md`,
//! Task 2.1, for the design rationale and step list.
//!
//! # Diagnostics vs hard errors
//!
//! `lower_expr` operates on a *single* `IrExprNode` — the expression
//! tree. If lowering fails (anywhere in the tree), the caller gets back
//! a [`LoweringError`] and no node is pushed. This is the unit at this
//! layer; the next-layer-up driver (mask / scoring / fold lowering, in
//! later tasks) decides whether to accumulate per-rule diagnostics or
//! short-circuit. Diagnostic accumulation lives on
//! [`LoweringCtx::diagnostics`] for that future use; this pass does not
//! push to it directly.

use std::collections::HashMap;

use dsl_ast::ast::{BinOp, Span, UnOp};
use dsl_ast::ir::{
    Builtin, IrCallArg, IrExpr, IrExprNode, LocalRef, NamespaceId, ViewRef as AstViewRef,
};

use crate::cg::data_handle::{
    AgentFieldId, AgentFieldTy, AgentRef, CgExprId, ConfigConstId, DataHandle, RngPurpose, ViewId,
};
use crate::cg::expr::{
    data_handle_ty, type_check, BinaryOp, BuiltinId, CgExpr, CgTy, LitValue, NumericTy,
    TypeCheckCtx, TypeError, UnaryOp,
};
use crate::cg::op::{ActionId, EventKindId};
use crate::cg::program::CgProgramBuilder;
use crate::cg::stmt::{CgStmt, LocalId, VariantId};

pub use super::error::LoweringError;

// ---------------------------------------------------------------------------
// LoweringCtx
// ---------------------------------------------------------------------------

/// Context threaded through expression lowering.
///
/// Carries the in-flight [`CgProgramBuilder`] (the recipient of every
/// `add_expr` call) plus typed lookup tables that map AST resolved-ids
/// to CG newtype ids. The maps are populated by the surrounding
/// op-lowering driver (Task 2.7); for Task 2.1's tests, they're built
/// directly (typically empty).
pub struct LoweringCtx<'a> {
    /// Builder receiving every freshly-allocated [`CgExpr`].
    pub builder: &'a mut CgProgramBuilder,
    /// AST `ViewRef` → CG `ViewId` map. Empty at expression-pass tests
    /// that don't exercise `IrExpr::ViewCall`; populated by the driver.
    pub view_ids: HashMap<AstViewRef, ViewId>,
    /// Optional view signature resolver — passed through to
    /// [`type_check`]. `None` means `IrExpr::ViewCall` lowering itself
    /// pins the result type from `view_ids` but the type checker can't
    /// validate operand types; the builder's `validate_expr_refs`
    /// catches dangling ids and the lowering catches arity at AST level.
    pub view_signatures: HashMap<ViewId, (Vec<CgTy>, CgTy)>,
    /// Per-view CG-side storage hint — `view_id → CgStorageHint`. Only
    /// materialized views are present; lazy views skip the entry. The
    /// driver registers entries alongside [`Self::view_signatures`]; the
    /// snapshot lands on
    /// [`crate::cg::program::ViewSignature::storage_hint`] before the
    /// kernel-emit composer reads it back. Empty for tests that don't
    /// drive view emission.
    pub view_storage_hints: HashMap<ViewId, crate::cg::program::CgStorageHint>,
    /// Per-view fold-body operator — `view_id → ViewFoldOp` (Add / Or).
    /// Recorded by the view-body lowering at the same point it accepts
    /// the `+=` / `|=` operator gate. Snapshotted onto
    /// [`crate::cg::program::ViewSignature::fold_op`] alongside the
    /// storage hint; emit branches on `(fold_op, result_ty)` to pick
    /// `atomicAdd` vs `atomicOr` vs CAS+add. Without this, `+= 1u` on
    /// a u32 view silently routes through `atomicOr` (Gap C from
    /// `docs/superpowers/notes/2026-05-04-quest_probe.md`).
    pub view_fold_ops: HashMap<ViewId, crate::cg::program::ViewFoldOp>,
    /// Sum-type variant-name → typed [`VariantId`] resolver, keyed on
    /// the source-level variant identifier (`"Damage"`, `"Heal"`, …).
    /// Used by physics-pass `Match` lowering to resolve arm patterns
    /// to their typed variant id. The driver populates this from the
    /// stdlib enum registry (today only `EffectOp` is matched); tests
    /// populate the map directly.
    ///
    /// **Distinct from [`Self::event_kind_ids`].** Sum-type variants
    /// (matched in arms) and event kinds (named in `Emit` and fold
    /// handlers) inhabit independent id spaces. A driver populating
    /// both with the natural per-sequence allocation pattern (e.g.,
    /// `Damage → 0` and `AgentDied → 0`) must not let an emit-name
    /// resolution route through this map — that's exactly the silent
    /// mis-routing the split prevents.
    pub variant_ids: HashMap<String, VariantId>,
    /// Event-name → typed [`EventKindId`] resolver, keyed on the
    /// source-level event variant identifier (`"AgentDied"`,
    /// `"ChronicleEntry"`, …). Used by physics `Emit` lowering and
    /// view-fold handler resolution to map the event name in the
    /// source surface to the typed id the IR carries. The driver
    /// populates this from the event registry; tests populate it
    /// directly.
    ///
    /// **Distinct from [`Self::variant_ids`].** See its doc for the
    /// rationale.
    pub event_kind_ids: HashMap<String, EventKindId>,
    /// Per-event field-name → field-index resolver, keyed on the
    /// `(EventKindId, field_name)` pair. Populated by the driver
    /// (Task 5.7) from each event variant's declared field list;
    /// tests populate it directly via [`Self::register_event_field`].
    /// Used by physics `Emit` lowering to resolve each
    /// `IrFieldInit { name, value, .. }` to a typed
    /// [`crate::cg::stmt::EventField`] with `(event, index)`. A
    /// missing entry surfaces as
    /// [`LoweringError::UnknownEventField`].
    pub event_field_indices: HashMap<(EventKindId, String), u8>,
    /// AST [`LocalRef`] → typed [`LocalId`] resolver. Pattern binders
    /// resolved by the AST resolver carry a `LocalRef`; physics-pass
    /// `Match` lowering converts each binding's local through this
    /// map. The driver populates it; tests populate it directly.
    pub local_ids: HashMap<LocalRef, LocalId>,
    /// Action-name → typed [`ActionId`] resolver. Scoring-row heads
    /// (`Hold`, `MoveToward`, `Attack`, … and `row <name>
    /// per_ability` row names) resolve through this map. The driver
    /// populates this from the action surface (one allocation per
    /// distinct head name across the scoring decl); tests populate it
    /// directly via [`Self::register_action`].
    ///
    /// Standard scoring rows AND per-ability scoring rows share this
    /// id space — both are "actions" in the engine's apply layer (the
    /// engine maps the winning [`ActionId`] to a behaviour). The
    /// driver allocates each distinct name to a unique id; using the
    /// same map for both row shapes preserves the contract.
    pub action_ids: HashMap<String, ActionId>,
    /// Accumulator for per-rule diagnostics. The expression lowering
    /// itself returns `Err` on first defect; this vector exists so
    /// later op-lowering passes can collect non-fatal rule-level
    /// diagnostics in the same context.
    pub diagnostics: Vec<LoweringError>,
    /// Whether `target` is bound as the per-pair candidate in the
    /// current lowering context.
    ///
    /// Set by op-level driver passes that lower a pair-bound construct
    /// (`mask <Name>(target) from query.nearby_agents(...)` today;
    /// Task 5.5b/c will extend this to per-pair scoring rows and
    /// fold-body event binders). When `true`, `target.<field>` accesses
    /// in the predicate / body resolve to a `Read(AgentField {
    /// field, target: AgentRef::PerPairCandidate })` — see
    /// [`AgentRef::PerPairCandidate`]'s docstring for the resolution
    /// contract. When `false` (the default), any `target.<field>` access
    /// surfaces as [`LoweringError::UnsupportedFieldBase`] (the same
    /// shape as other unbound receivers) so the driver-side invariant is
    /// enforced at every layer.
    pub target_local: bool,
    /// Slice δ part 2 (#161): set to `true` while lowering a body
    /// inside a `@phase(per_agent)` physics rule, `false` for
    /// PerEvent rules. Inspected by `IrStmt::ApplyAbility` lowering
    /// to choose between caster=`AgentSelfId` (PerAgent — works
    /// today) and caster=event-payload-actor (PerEvent — not yet
    /// implemented; surfaces as a typed error so the user sees the
    /// gap clearly instead of broken WGSL).
    ///
    /// `lower_one_handler` toggles this around its `lower_stmt_list`
    /// call and restores afterward. Default `false` matches the
    /// most-restrictive shape so callers that forget to set it get
    /// the typed error rather than silent agent_id-undeclared WGSL.
    pub current_per_agent_rule: bool,
    /// `(NamespaceId::Config, "<block>.<field>")` → typed `ConfigConstId`
    /// resolver. Populated by the driver's
    /// [`super::driver::populate_config_consts`] walk over
    /// `Compilation::configs` (one id per block × field, allocated in
    /// source order). Used by `IrExpr::NamespaceField`'s expression
    /// lowering to map a `config.<block>.<field>` access to
    /// `Read(DataHandle::ConfigConst { id })`. An unknown
    /// `(ns, field)` pair surfaces as
    /// [`LoweringError::UnknownConfigField`]; the legacy
    /// [`LoweringError::UnsupportedNamespaceField`] now only fires for
    /// non-`Config` namespaces.
    pub config_const_ids: HashMap<(NamespaceId, String), ConfigConstId>,
    /// Captured `@lazy` view bodies for at-call-site inlining.
    /// `ViewId` → snapshot. Populated by
    /// [`super::view::lower_view`]'s lazy arm in Phase 2; consumed by
    /// [`lower_view_call`]. A view absent from this map is materialized
    /// — the call lowers through `BuiltinId::ViewCall { view }` as
    /// before, with the type checker resolving against
    /// `ctx.view_signatures`. Task 5.5c.
    pub lazy_view_bodies: HashMap<ViewId, LazyViewSnapshot>,
    /// Typed `LocalId → CgTy` map. Populated by `IrStmt::Let` lowering
    /// (Task 5.5b/d) at the moment each binding's CG type becomes
    /// known. Used by `IrExpr::Local` resolution (Task 5.5d) to
    /// reconstruct `CgExpr::ReadLocal { local, ty }` for bare-local
    /// reads.
    ///
    /// Distinct from [`Self::local_ids`]: that map carries
    /// `LocalRef → LocalId` (binder identity), this one carries
    /// `LocalId → CgTy` (binder type).
    pub local_tys: HashMap<LocalId, CgTy>,
    /// Per-event-kind payload layouts. Populated by the driver's
    /// `populate_event_kinds` walk over the event registry; consumed by
    /// physics + view-fold handler lowering when synthesizing
    /// `CgStmt::Let` for each event-pattern binding (the `actor: c,
    /// target: t, amount: a` shape introduces three locals whose
    /// values come from typed `CgExpr::EventField` reads keyed on this
    /// schema). At `finish()` time the lowering driver copies this
    /// table onto [`crate::cg::program::CgProgram::event_layouts`] so
    /// the WGSL emit can resolve the layout per-kind without a
    /// separate registry walk.
    pub event_layouts: HashMap<EventKindId, super::super::program::EventLayout>,
    /// Per-rule rng-call counter, keyed by `RngPurpose`. Each call to
    /// `lower_rng_call` looks up the current count for the purpose,
    /// assigns it as the resulting `CgExpr::Rng.extra`, then bumps.
    /// Reset by `reset_rng_counter()` at every rule-body entry. The
    /// first occurrence of each purpose gets `extra = 0` (renders as
    /// the bare `per_agent_u32(...)` — backwards compat preserved);
    /// subsequent occurrences get distinct `extra` values so the
    /// WGSL emit routes them through `per_agent_u32_with_extra(...,
    /// extra)`, giving them independent PCG streams.
    pub rng_purpose_count: HashMap<RngPurpose, u32>,
    /// Static lookup tables from `table <name>: u32[N] = […]` decls.
    /// Keyed by snake_case table name; value is the materialised
    /// element list (u32 only in the first cut) bounds-checked by
    /// the resolver. Consulted by [`lower_namespace_call`]'s
    /// `tables.<name>(<idx>)` arm to bake the values directly into
    /// the resulting `CgExpr::TableLookup` node — so the kernel
    /// emit doesn't need a separate registry walk.
    pub tables: HashMap<String, Vec<u32>>,
    /// Stdlib namespace registry — schema for `CgExpr::NamespaceCall`
    /// and `CgExpr::NamespaceField` lowering. Populated by the driver's
    /// `populate_namespace_registry`; consumed by `lower_namespace_call`
    /// and the `IrExpr::NamespaceField` arm of `lower_expr`. At
    /// `finish()` time the driver copies this onto
    /// [`crate::cg::program::CgProgram::namespace_registry`] so the
    /// WGSL emit can resolve return types + access forms without a
    /// separate registry walk.
    pub namespace_registry: super::super::program::NamespaceRegistry,
    /// Statements an in-flight expression lowering wants prepended to
    /// the surrounding statement list. The N²-fold lowering uses this:
    /// `IrExpr::Fold { Sum|Count, ... }` allocates a [`CgStmt::ForEachAgent`]
    /// for the accumulator loop and pushes its id here, then returns a
    /// [`crate::cg::expr::CgExpr::ReadLocal`] that reads the just-
    /// populated accumulator. The driver-level `lower_stmt_list` (in
    /// `physics.rs`) drains this buffer before each child stmt so the
    /// fold loop runs ahead of its consumer in source order.
    pub pending_pre_stmts: Vec<crate::cg::stmt::CgStmtId>,
    /// Source-level name of the binder bound by the innermost active
    /// fold (if any). Set by the fold lowering before lowering the
    /// projection expression and cleared after; consumed by
    /// [`lower_field`] / [`lower_bare_local`] so reads of `<binder>` /
    /// `<binder>.<field>` resolve to [`AgentRef::PerPairCandidate`] /
    /// [`crate::cg::expr::CgExpr::PerPairCandidateId`] just like the
    /// existing pair-bound surfaces. `None` outside a fold context.
    ///
    /// Single-slot rather than a stack because today's fixtures don't
    /// nest folds; a future fixture that does (`sum(other in agents :
    /// sum(third in agents : ...))`) would need this to grow into a
    /// stack and the fold lowering to save / restore around the
    /// nested call.
    pub fold_binder_name: Option<String>,
    /// Per-fixture catalog of `entity X : Item { ... }` and
    /// `entity Y : Group { ... }` field declarations. Walked by the
    /// `(NamespaceId::Items, _)` / `(NamespaceId::Groups, _)` arms of
    /// [`lower_namespace_call`] so an `items.<field>(idx)` call resolves
    /// the field name against the catalog and produces a typed
    /// [`DataHandle::ItemField`] / [`DataHandle::GroupField`] read.
    /// At `finish()` time the driver copies this onto
    /// [`crate::cg::program::CgProgram::entity_field_catalog`] so the
    /// kernel binding metadata can resolve (entity ref, slot) →
    /// (entity name, field name, ty) without a separate registry walk.
    pub entity_field_catalog: super::super::program::EntityFieldCatalog,
    /// 2026-05-07 (#121 BGL opt-in): per-fixture flag controlling
    /// whether `apply_ability` lowers as the AOE-shaped dispatcher
    /// (spatial walk + multi-target chronicle write) or the existing
    /// single-target chain. Source: caller-supplied
    /// [`super::driver::LowerOpts::aoe_dispatch`] threaded through
    /// [`super::driver::lower_compilation_to_cg_with_opts`].
    ///
    /// Default `false` so every fixture's existing emit shape is
    /// preserved byte-for-byte until the runtime opts in. The smoke
    /// fixture (`apply_ability_smoke_runtime`) is the canonical
    /// opt-in caller — its build.rs flips the flag for the AOE Path B
    /// parity sweep + behavioral pin. Production runtimes
    /// (duel_abilities, tactical_squad_5v5, boss_fight, etc.) keep
    /// the default and don't auto-fire the spatial-build phases.
    pub aoe_dispatch: bool,
    /// 2026-05-07 (Wave 3 ToM Phase 3.7): per-fixture flag controlling
    /// whether `agents.set_beliefs_<field>(...)` calls lower as real
    /// SoA writes (BGL-bound `beliefs_<field>` storage + atomic byte
    /// writes for the q8 columns) or stay no-op stubs.
    ///
    /// Source: caller-supplied
    /// [`super::driver::LowerOpts::belief_state`] threaded through
    /// [`super::driver::lower_compilation_to_cg_with_opts`]. Today
    /// only `tom_probe_runtime`'s build.rs flips it on.
    pub belief_state: bool,
    /// Plan G G3f follow-up — gap (b) from threats_struct_probe.sim:
    /// when `true`, the bare-name resolver in `lower_bare_local`
    /// admits `source_candidate` as the per-pair candidate id (same
    /// kernel-local the WGSL emit declares for PerAgentEventScan
    /// dispatch). Set by the view-fold body lowerer for fold handlers
    /// of views with `@dispatch(per_agent_event_scan)`; restored on
    /// exit so the surface stays scoped to that body.
    pub per_agent_event_scan_local: bool,
}

/// Captured form of a `@lazy` view's resolved AST: enough to
/// substitute its body at every call site without re-lowering the
/// view declaration itself. Populated by
/// [`super::view::lower_view`] on the lazy arm; consumed by
/// [`lower_view_call`] when it observes a call to a lazy view.
///
/// `param_locals` is the i-th positional parameter's `LocalRef`,
/// in declaration order. The substitution walk replaces every
/// `IrExpr::Local(LocalRef, _)` whose ref appears in this slice
/// with the matching positional argument expression.
#[derive(Debug, Clone)]
pub struct LazyViewSnapshot {
    pub param_locals: Vec<LocalRef>,
    pub body: IrExprNode,
}

impl<'a> LoweringCtx<'a> {
    /// Construct a context with empty maps and no diagnostics.
    ///
    /// `target_local` defaults to `false`: `target.<field>` accesses
    /// produce [`LoweringError::UnsupportedFieldBase`] until an
    /// op-level driver pass sets the flag (today the pair-bound mask
    /// driver in [`crate::cg::lower::mask`]; Task 5.5b/c will extend
    /// this to per-pair scoring + fold-body event binders).
    pub fn new(builder: &'a mut CgProgramBuilder) -> Self {
        Self {
            builder,
            view_ids: HashMap::new(),
            view_signatures: HashMap::new(),
            view_storage_hints: HashMap::new(),
            view_fold_ops: HashMap::new(),
            variant_ids: HashMap::new(),
            event_kind_ids: HashMap::new(),
            event_field_indices: HashMap::new(),
            local_ids: HashMap::new(),
            action_ids: HashMap::new(),
            diagnostics: Vec::new(),
            target_local: false,
            current_per_agent_rule: false,
            config_const_ids: HashMap::new(),
            lazy_view_bodies: HashMap::new(),
            local_tys: HashMap::new(),
            event_layouts: HashMap::new(),
            rng_purpose_count: HashMap::new(),
            tables: HashMap::new(),
            namespace_registry: super::super::program::NamespaceRegistry::default(),
            pending_pre_stmts: Vec::new(),
            fold_binder_name: None,
            entity_field_catalog: super::super::program::EntityFieldCatalog::default(),
            // Default `false` — non-opt-in fixtures keep their existing
            // single-target dispatcher emit. Caller-side opt-in via
            // `lower_compilation_to_cg_with_opts(LowerOpts { aoe_dispatch: true })`
            // flips this for the smoke runtime's AOE parity sweep.
            aoe_dispatch: false,
            // Default `false` — non-opt-in fixtures keep the no-op
            // setter stubs (Phase 3.5 shape). Caller-side opt-in via
            // `lower_compilation_to_cg_with_opts(LowerOpts { belief_state: true })`
            // flips this for `tom_probe_runtime`'s ToM consumer rules.
            belief_state: false,
            per_agent_event_scan_local: false,
        }
    }

    /// Register a sum-type variant-name → typed id mapping. Returns
    /// the prior `VariantId` if one was registered for the same name
    /// (a duplicate registration is a driver-side defect — surfacing
    /// it lets tests assert exclusive allocation).
    ///
    /// Note: this populates [`Self::variant_ids`] only — event-kind
    /// names use the dedicated [`Self::register_event_kind`] helper.
    pub fn register_variant(&mut self, name: impl Into<String>, id: VariantId) -> Option<VariantId> {
        self.variant_ids.insert(name.into(), id)
    }

    /// Register an event-name → typed [`EventKindId`] mapping. Returns
    /// the prior `EventKindId` if one was registered for the same name
    /// (a duplicate registration is a driver-side defect — surfacing
    /// it lets tests assert exclusive allocation).
    ///
    /// Note: this populates [`Self::event_kind_ids`] only — sum-type
    /// variant names use the dedicated [`Self::register_variant`]
    /// helper. The two id spaces are distinct; see their field docs.
    pub fn register_event_kind(
        &mut self,
        name: impl Into<String>,
        id: EventKindId,
    ) -> Option<EventKindId> {
        self.event_kind_ids.insert(name.into(), id)
    }

    /// Register an `(EventKindId, field_name) → field_index` entry.
    /// Used by physics `Emit` lowering to resolve each
    /// `IrFieldInit { name, .. }` to a typed
    /// [`crate::cg::stmt::EventField`] with `(event, index)`.
    /// Driver populates the table from each event variant's
    /// declared field list (in declaration order); tests populate
    /// it directly. Returns the prior index if one was registered
    /// for the same `(event, field_name)` pair (driver-side
    /// duplicate).
    pub fn register_event_field(
        &mut self,
        event: EventKindId,
        field_name: impl Into<String>,
        index: u8,
    ) -> Option<u8> {
        self.event_field_indices.insert((event, field_name.into()), index)
    }

    /// Register the per-event-kind payload layout. Used by physics +
    /// view-fold handler lowering when synthesizing `CgStmt::Let` for
    /// each event-pattern binding (the binder's value comes from a
    /// typed `CgExpr::EventField` keyed on the layout's `field_offset`
    /// + `field_ty`). The driver populates this from the event registry
    /// via `populate_event_kinds`; tests populate it directly. Returns
    /// the prior layout if one was registered for the same kind
    /// (driver-side duplicate).
    pub fn register_event_layout(
        &mut self,
        event: EventKindId,
        layout: super::super::program::EventLayout,
    ) -> Option<super::super::program::EventLayout> {
        self.event_layouts.insert(event, layout)
    }

    /// Register an AST `LocalRef` → typed [`LocalId`] mapping. Returns
    /// the prior `LocalId` if one was registered for the same ref
    /// (driver-side duplicate).
    pub fn register_local(&mut self, ast_ref: LocalRef, id: LocalId) -> Option<LocalId> {
        self.local_ids.insert(ast_ref, id)
    }

    /// Allocate a fresh [`LocalId`] disjoint from every id already
    /// present in [`Self::local_ids`]. Used by physics `Let` lowering
    /// (Task 5.5b) to introduce a binding for `IrStmt::Let { local: ast_ref, .. }`
    /// when the driver has not pre-registered the mapping. The
    /// allocation strategy picks one past the maximum existing
    /// `LocalId`, so successive calls produce a strictly increasing
    /// sequence regardless of insertion order.
    pub fn allocate_local(&mut self, ast_ref: LocalRef) -> LocalId {
        // Pick max + 1 over both registries: AST-bound locals
        // (`local_ids`) AND typed-only accumulator locals
        // (`local_tys`-only entries are produced by the N²-fold
        // lowering, which allocates anonymous `LocalId`s for fold
        // accumulators without a corresponding `LocalRef`). Without
        // chaining `local_tys` keys here, a fold accumulator allocated
        // before a user `let` would share its id and the WGSL emit
        // would produce `let local_0: ... = local_0;` aliasing.
        let next = self
            .local_ids
            .values()
            .map(|id| id.0)
            .chain(self.local_tys.keys().map(|id| id.0))
            .max()
            .map(|m| m + 1)
            .unwrap_or(0);
        let id = LocalId(next);
        self.local_ids.insert(ast_ref, id);
        id
    }

    /// Register an action-name → typed [`ActionId`] mapping. Returns
    /// the prior `ActionId` if one was registered for the same name
    /// (driver-side duplicate). Used by scoring lowering to resolve
    /// row heads to stable typed action ids.
    pub fn register_action(&mut self, name: impl Into<String>, id: ActionId) -> Option<ActionId> {
        self.action_ids.insert(name.into(), id)
    }

    /// Register an AST view ref → CG view id mapping. Returns the prior
    /// `ViewId` if one was registered for the same ref (shouldn't
    /// happen in practice — surfacing it lets tests assert exclusive
    /// allocation).
    pub fn register_view(&mut self, ast_ref: AstViewRef, view_id: ViewId) -> Option<ViewId> {
        self.view_ids.insert(ast_ref, view_id)
    }

    /// Register the typed signature of `view_id`. Used by the recursive
    /// type-checker when it encounters a `CgExpr::Builtin { fn_id:
    /// ViewCall { view }, .. }`. Tests that don't exercise view calls
    /// can leave this empty.
    pub fn register_view_signature(
        &mut self,
        view_id: ViewId,
        args: Vec<CgTy>,
        result: CgTy,
    ) -> Option<(Vec<CgTy>, CgTy)> {
        self.view_signatures.insert(view_id, (args, result))
    }

    /// Reset the per-rule rng-call counter. Called by every rule-body
    /// lowering entry point so each rule's RNG-call indexing starts
    /// fresh. Without this, cross-rule rng-call counts would shift
    /// every existing fixture's first-call extra=0 to extra=N
    /// silently, breaking determinism across compiles.
    pub fn reset_rng_counter(&mut self) {
        self.rng_purpose_count.clear();
    }

    /// Register the CG-side storage hint of `view_id`. Materialized-only;
    /// lazy views skip the entry. The driver populates this alongside
    /// [`Self::register_view_signature`] from
    /// `populate_view_bodies_and_signatures`. Returns the prior entry
    /// if any (caller-side defect; the driver allocates each view id
    /// once).
    pub fn register_view_storage_hint(
        &mut self,
        view_id: ViewId,
        hint: crate::cg::program::CgStorageHint,
    ) -> Option<crate::cg::program::CgStorageHint> {
        self.view_storage_hints.insert(view_id, hint)
    }

    /// Register the fold-body operator (`+=` / `-=` / `|=` / `=`) for
    /// `view_id`. Recorded by the view-body lowerer at the same point
    /// it accepts the operator gate. Snapshotted by the driver onto
    /// [`crate::cg::program::ViewSignature::fold_op`]; emit branches
    /// on `(fold_op, result_ty)` to pick the right atomic primitive.
    /// Returns the prior entry if any.
    ///
    /// LIMITATION (Gap T1b in `docs/architecture/gaps_observed.md`):
    /// the storage is keyed per-view, not per-handler. A multi-handler
    /// view with mixed operators (e.g. trade_caravans's `inventory`
    /// view: `+=` on Bought + `-=` on Sold) overwrites the first
    /// handler's op with the second's, so both emit branches use the
    /// last-registered op. Fixing this requires threading `fold_op`
    /// per-handler (on each handler's Assign op, or by expanding
    /// [`crate::cg::program::ViewSignature::fold_op`] to a
    /// per-handler vector). Today the prior-entry return value is
    /// surfaced for debug instrumentation but no caller errors on a
    /// non-`None` return.
    pub fn register_view_fold_op(
        &mut self,
        view_id: ViewId,
        op: crate::cg::program::ViewFoldOp,
    ) -> Option<crate::cg::program::ViewFoldOp> {
        self.view_fold_ops.insert(view_id, op)
    }

    /// Register a `(NamespaceId, "<block>.<field>")` → typed
    /// [`ConfigConstId`] mapping. Returns the prior id if one was
    /// registered for the same key (a duplicate is a driver-side
    /// defect — surfacing it lets tests assert exclusive allocation).
    ///
    /// The driver populates this from
    /// `Compilation::configs` in source order; tests populate it
    /// directly. Used by `IrExpr::NamespaceField` lowering.
    pub fn register_config_const(
        &mut self,
        ns: NamespaceId,
        field: impl Into<String>,
        id: ConfigConstId,
    ) -> Option<ConfigConstId> {
        self.config_const_ids.insert((ns, field.into()), id)
    }

    /// Register the captured body of a `@lazy` view for at-call-site
    /// inlining. Returns the prior snapshot if one was registered for
    /// the same id (driver-side defect). Used by
    /// [`super::view::lower_view`]'s lazy arm.
    pub fn register_lazy_view_body(
        &mut self,
        view_id: ViewId,
        snapshot: LazyViewSnapshot,
    ) -> Option<LazyViewSnapshot> {
        self.lazy_view_bodies.insert(view_id, snapshot)
    }

    /// Record `local_id → ty` for later `IrExpr::Local` resolution.
    /// Called by physics-Let lowering after the bound expression's CG
    /// type is known. Returns the prior `CgTy` if one was registered
    /// for the same id (driver-side duplicate — surfacing it lets
    /// tests assert exclusive allocation).
    pub fn record_local_ty(&mut self, local_id: LocalId, ty: CgTy) -> Option<CgTy> {
        self.local_tys.insert(local_id, ty)
    }
}

// ---------------------------------------------------------------------------
// Public entry point
// ---------------------------------------------------------------------------

/// Lower a resolved DSL expression to a CG expression id.
///
/// On success returns the newly-allocated `CgExprId`; the corresponding
/// `CgExpr` is in `ctx.builder.program().exprs[id.0 as usize]`. On
/// failure returns a typed [`LoweringError`] naming the offending node
/// (via its `Span`) and the structural reason. The arena is not rolled
/// back on failure — see [`add`]'s "Orphan behavior" note for the full
/// story; in short, partial children (and possibly the just-pushed
/// parent itself) remain as orphans that downstream emit walks ignore.
///
/// Type-checking runs after every node is constructed: a successful
/// return means the produced `CgExpr` matches its operand types under
/// the operator's signature.
pub fn lower_expr(ast: &IrExprNode, ctx: &mut LoweringCtx<'_>) -> Result<CgExprId, LoweringError> {
    let span = ast.span;
    match &ast.kind {
        // ---- Literals ----
        IrExpr::LitBool(b) => add(ctx, CgExpr::Lit(LitValue::Bool(*b)), span),
        IrExpr::LitInt(v) => {
            // The DSL surface uses signed `i64` literals; the CG IR's
            // numeric literals are 32-bit. We pick `I32` for negative
            // values and `U32` for non-negative ones, narrowing the
            // i64. Out-of-range narrowings surface as typed
            // ill-typed errors so silent truncation can't sneak past.
            if *v < 0 {
                if *v < i32::MIN as i64 {
                    return Err(LoweringError::LiteralOutOfRange {
                        value: *v,
                        target: CgTy::I32,
                        span,
                    });
                }
                add(ctx, CgExpr::Lit(LitValue::I32(*v as i32)), span)
            } else {
                if *v > u32::MAX as i64 {
                    return Err(LoweringError::LiteralOutOfRange {
                        value: *v,
                        target: CgTy::U32,
                        span,
                    });
                }
                add(ctx, CgExpr::Lit(LitValue::U32(*v as u32)), span)
            }
        }
        IrExpr::LitFloat(v) => add(ctx, CgExpr::Lit(LitValue::F32(*v as f32)), span),

        // ---- Field access ----
        IrExpr::Field {
            base, field_name, ..
        } => lower_field(base, field_name, span, ctx),

        // ---- Local references ----
        //
        // Resolution order in `lower_bare_local`: let-bound locals
        // first (via `ctx.local_ids` → `ctx.local_tys`), then bare
        // `self` and pair-bound `target`, then a typed deferral.
        IrExpr::Local(local_ref, name) => lower_bare_local(*local_ref, name, span, ctx),

        // ---- Operators ----
        IrExpr::Binary(op, lhs, rhs) => lower_binary(*op, lhs, rhs, span, ctx),
        IrExpr::Unary(op, arg) => lower_unary(*op, arg, span, ctx),

        // ---- Conditional expression ----
        IrExpr::If {
            cond,
            then_expr,
            else_expr,
        } => match else_expr {
            Some(else_box) => lower_select(cond, then_expr, else_box, span, ctx),
            // `if … then …` without `else` has no value type; only the
            // statement form supports a None else-branch.
            None => Err(LoweringError::UnsupportedAstNode {
                ast_label: "If(without-else)",
                span,
            }),
        },

        // ---- Calls ----
        IrExpr::BuiltinCall(b, args) => lower_builtin_call(*b, args, span, ctx),
        IrExpr::ViewCall(view_ref, args) => lower_view_call(*view_ref, args, span, ctx),
        IrExpr::RingFieldRead(view_ref, field, args) => {
            lower_ring_field_read(*view_ref, field, args, span, ctx)
        }
        IrExpr::NamespaceCall { ns, method, args } => {
            lower_namespace_call(*ns, method.as_str(), args, span, ctx)
        }
        IrExpr::NamespaceField { ns, field, .. } => {
            // `config.<block>.<field>` (the only NamespaceField shape the
            // resolver produces today via the dedicated `Config`
            // namespace) lowers to a typed `Read(ConfigConst { id })`.
            // Other namespaces consult the schema-driven
            // `namespace_registry` (Task 4 of the CG lowering gap
            // closure plan) to lower `world.tick` and friends as
            // typed `CgExpr::NamespaceField` nodes.
            if *ns == NamespaceId::Config {
                match ctx.config_const_ids.get(&(*ns, field.clone())) {
                    Some(id) => add(ctx, CgExpr::Read(DataHandle::ConfigConst { id: *id }), span),
                    None => Err(LoweringError::UnknownConfigField {
                        ns: *ns,
                        field: field.clone(),
                        span,
                    }),
                }
            } else if let Some(def) = ctx
                .namespace_registry
                .namespaces
                .get(ns)
                .and_then(|nd| nd.fields.get(field))
            {
                let ty = def.ty;
                add(
                    ctx,
                    CgExpr::NamespaceField {
                        ns: *ns,
                        field: field.clone(),
                        ty,
                    },
                    span,
                )
            } else {
                Err(LoweringError::UnsupportedNamespaceField {
                    ns: *ns,
                    field: field.clone(),
                    span,
                })
            }
        }
        IrExpr::Namespace(ns) => {
            // A bare namespace token is a *qualifier*, not a value. The
            // resolver routes unqualified `tick` to
            // `IrExpr::Namespace(NamespaceId::Tick)`; the author
            // typically meant a qualified field on it (e.g.
            // `world.tick` for the per-tick counter). Surface the gap
            // as a typed diagnostic so verb `when` predicates that
            // mistakenly write `(tick % 3 == 0)` produce a pointed
            // error instead of silently dropping their MaskPredicate
            // op. See `docs/superpowers/notes/2026-05-04-diplomacy_probe.md`
            // Gap #1.
            //
            // The qualified-form hint is closed-set per namespace — only
            // a handful of stdlib namespaces have a single canonical
            // value-bearing field; for the rest we default to a generic
            // hint so the diagnostic still points at the surface area.
            let hint: &'static str = match ns {
                NamespaceId::Tick | NamespaceId::World => "world.tick",
                _ => "<namespace>.<field>",
            };
            Err(LoweringError::BareNamespaceInExpression {
                ns: *ns,
                hint,
                span,
            })
        }
        IrExpr::Event(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Event",
            span,
        }),
        IrExpr::Entity(r) => {
            // Entity-name-as-value: lower to its declaration-order
            // discriminant. Used in `where (self.creature_type ==
            // <EntityName>)` per-handler filters; the per-creature
            // SoA AgentField::CreatureType (`AgentFieldTy::OptEnumU32`,
            // CgTy::U32 at the expression layer) is compared against
            // this constant so the where-guard's body only fires for
            // matching agents.
            //
            // Discriminant convention: EntityRef.0 (declaration order
            // index). The runtime is responsible for setting
            // `agent.creature_type = entity_ref_index` when spawning
            // an agent of that entity declaration. Since the
            // EntityRef index is stable across compiles for a given
            // .sim, the runtime can hard-code or look up the mapping
            // off `comp.entities` order.
            add(
                ctx,
                CgExpr::Lit(LitValue::U32(r.0 as u32)),
                span,
            )
        }
        IrExpr::View(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "View",
            span,
        }),
        IrExpr::Verb(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Verb",
            span,
        }),
        IrExpr::VerbCall(_, _) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "VerbCall",
            span,
        }),
        IrExpr::UnresolvedCall(_, _) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "UnresolvedCall",
            span,
        }),
        IrExpr::EnumVariant { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "EnumVariant",
            span,
        }),
        IrExpr::LitString(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "LitString",
            span,
        }),
        IrExpr::Index(_, _) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Index",
            span,
        }),
        IrExpr::In(_, _) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "In",
            span,
        }),
        IrExpr::Contains(_, _) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Contains",
            span,
        }),
        IrExpr::Quantifier { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Quantifier",
            span,
        }),
        // `count(binder in iter where pred)` / `sum(...)` / `max(...)` /
        // `min(...)`. The resolver shapes every aggregation comprehension
        // as `IrExpr::Fold { kind, binder, iter, body }`. Lowering today
        // recognises **only** `FoldKind::Count` over the `agents`
        // namespace iterator — the shape Boids' `neighbor_count` lazy
        // view uses (`assets/sim/boids.sim`).
        //
        // ## What this arm produces
        //
        // A typed-zero short-circuit at the expression position. The
        // Fold is **not** materialised as compute — neither as a CG IR
        // variant carrying the loop, nor as a real WGSL `for` walk.
        // Real fold emit requires either (a) a top-level WGSL helper-fn
        // prelude (out of scope: would need to edit
        // `cg/emit/program.rs::compose_wgsl_file`) or (b) statement
        // injection from the lowering layer (out of scope: would need a
        // `CgStmt::Fold` shape and changes to `physics.rs` /
        // `view.rs` / scoring lowering to splice the synthesised stmt
        // before its consumer). Both paths reach beyond the file scope
        // pinned by the Fold-lowering subagent task.
        //
        // ## Why a literal short-circuit is honest here
        //
        // The B1 conventions across this emit stack (the
        // `b1_default_for_field_ty` fallback in
        // `wgsl_body.rs::lower_cg_expr_to_wgsl`, the wildcard PerUnit
        // collapse a few arms below, the `MOVEMENT_BODY` /
        // `SPATIAL_BUILD_HASH_BODY` placeholders in
        // `cg/emit/kernel.rs`) all share the same posture: structural
        // scaffolding lands first, real semantics layers on once the
        // surrounding infrastructure exists. Boids' `neighbor_count`
        // is consumed only by the `MoveBoid` per-agent physics body,
        // which is itself a `MOVEMENT_BODY` placeholder today — so a
        // real fold value would have nothing to feed.
        //
        // ## What this unblocks
        //
        // The Boids fixture lowers cleanly through the lazy-view inline
        // path (`lower_view_call`'s `lazy_view_bodies` branch above),
        // which substitutes `neighbor_count`'s body at every call site
        // and walks it through `lower_expr` recursively. Without this
        // arm, every such call surfaces as `UnsupportedAstNode {
        // ast_label: "Fold" }` and the entire enclosing op fails. With
        // it, the call lowers to `0i` and the rest of the body
        // continues. The real fold semantic lands when:
        //   1. A kernel actually consumes a `count(...)` result (today
        //      no kernel does — the only consumer is `MOVEMENT_BODY`'s
        //      hand-written placeholder).
        //   2. The compose_wgsl_file pipeline grows a fold-helper-fn
        //      prelude OR `CgStmt::Fold` lands with statement-injection
        //      lowering wired through physics + view + scoring bodies.
        //
        // ## Sum / Min / Max
        //
        // Out of scope for the Boids unblock — Boids only uses Count.
        // Future fixtures wanting `sum_vec3(...)` etc. surface as their
        // own `UnsupportedAstNode` deferrals here; extend the match
        // when a real consumer arrives.
        // N²-fold over `agents` — Sum-projection or Count-predicate
        // shape, lowered as a `CgStmt::ForEachAgent` injected via
        // `pending_pre_stmts` plus a `CgExpr::ReadLocal` reading the
        // populated accumulator. See `lower_fold_over_agents` for the
        // shape contract. Min/Max remain UnsupportedAstNode until a
        // fixture asks for them — they require a different
        // accumulator init (NEG_INFINITY / INFINITY) and per-iteration
        // op (max / min instead of `+`), so the same scaffolding
        // generalises easily but isn't useful today.
        IrExpr::Fold { kind, binder_name, iter, body, .. } => {
            use dsl_ast::ast::FoldKind;
            match kind {
                FoldKind::Count | FoldKind::Sum => {
                    lower_fold_over_agents(
                        *kind,
                        binder_name.as_deref(),
                        iter.as_deref(),
                        body,
                        span,
                        ctx,
                    )
                }
                FoldKind::Min | FoldKind::Max | FoldKind::Mean => {
                    Err(LoweringError::UnsupportedAstNode {
                        ast_label: "Fold",
                        span,
                    })
                }
            }
        }
        IrExpr::List(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "List",
            span,
        }),
        IrExpr::Tuple(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Tuple",
            span,
        }),
        IrExpr::StructLit { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "StructLit",
            span,
        }),
        IrExpr::Ctor { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Ctor",
            span,
        }),
        IrExpr::Match { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Match",
            span,
        }),
        // PerUnit semantic simplification (Phase 6 Task 1, refined Task 2.5):
        // `<expr> per_unit <delta>` lowers as `expr * delta` per the AST
        // docstring. The "iterate over each unit in the result" semantic
        // that pertains inside scoring contexts is deferred — for view
        // storage that's empty (smoke fixture, idle agents) the result
        // is identical (0 * delta = 0). Closing the gap for richer
        // fixtures requires per-unit-fold-over-view-storage IR primitive;
        // tracked as future work.
        //
        // Wildcard short-circuit: when `expr` contains a wildcard `_`
        // (e.g. `view::threat_level(self, _) per_unit 0.01`), the inner
        // view call has typed-mismatch issues because `_` substitutes as
        // a u32 placeholder while the view signature expects an AgentId.
        // The wildcard semantically means "iterate over all candidates
        // and sum" — under the B1 simplification the per-unit fold is
        // unperformed, so the contribution is 0 regardless. Short-circuit
        // the entire PerUnit to a literal `0.0_f32` to avoid the
        // type-mismatch path. Same semantic as the non-wildcard
        // simplification (modifier contributes 0 for empty storage).
        IrExpr::PerUnit { expr, delta } => {
            if expr_contains_wildcard(expr) {
                add(ctx, CgExpr::Lit(LitValue::F32(0.0)), span)
            } else {
                lower_binary(BinOp::Mul, expr, delta, span, ctx)
            }
        }
        IrExpr::AbilityTag { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "AbilityTag",
            span,
        }),
        IrExpr::AbilityHint => Err(LoweringError::UnsupportedAstNode {
            ast_label: "AbilityHint",
            span,
        }),
        IrExpr::AbilityHintLit(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "AbilityHintLit",
            span,
        }),
        IrExpr::AbilityRange => Err(LoweringError::UnsupportedAstNode {
            ast_label: "AbilityRange",
            span,
        }),
        IrExpr::AbilityOnCooldown(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "AbilityOnCooldown",
            span,
        }),
        IrExpr::Raw(_) => Err(LoweringError::UnsupportedAstNode {
            ast_label: "Raw",
            span,
        }),
        IrExpr::BeliefsAccessor { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "BeliefsAccessor",
            span,
        }),
        IrExpr::BeliefsConfidence { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "BeliefsConfidence",
            span,
        }),
        IrExpr::BeliefsView { .. } => Err(LoweringError::UnsupportedAstNode {
            ast_label: "BeliefsView",
            span,
        }),
    }
}

// ---------------------------------------------------------------------------
// Per-shape helpers
// ---------------------------------------------------------------------------

/// Push `expr` into the builder, type-check it, and return its id.
///
/// Wraps the builder error and the type-check error in
/// [`LoweringError`] so every push goes through one funnel.
///
/// **Orphan behavior:** if `type_check` fails, the just-pushed parent
/// expression remains in the arena as an orphan — the caller gets
/// `Err`, but the arena is not rolled back. Children pushed before the
/// failing type-check also remain. Orphans are harmless: downstream
/// emit walks only ids reachable from `ComputeOpKind`, so orphan exprs
/// are dead-stripped at emit time. The well-formed pass treats them as
/// non-errors (an orphan expr in the arena that no op references is
/// not a P10 / structural concern).
fn add(
    ctx: &mut LoweringCtx<'_>,
    expr: CgExpr,
    span: Span,
) -> Result<CgExprId, LoweringError> {
    let id = ctx
        .builder
        .add_expr(expr)
        .map_err(|e| LoweringError::BuilderRejected { error: e, span })?;
    typecheck_node(ctx, id, span)?;
    Ok(id)
}

/// Plan G G3f wire-up — locate the .sim's `view threats(...)` if any.
/// Returns the [`ViewId`] of a registered view named "threats" so the
/// `threats.*` Builtin lowering can route to a typed ViewCall against
/// it. Returns `None` when no such view exists in the .sim — the
/// Builtin lowering then falls through to the sentinel literal.
///
/// MVP: hardcoded name match against "threats". A future generalization
/// could let .sim authors annotate any view with `@implements(threats)`
/// to participate; the convention-over-configuration shape is
/// sufficient today.
fn find_threats_view_id(ctx: &LoweringCtx<'_>) -> Option<ViewId> {
    let interner = &ctx.builder.program().interner;
    ctx.view_ids
        .values()
        .copied()
        .find(|view_id| interner.get_view_name(*view_id) == Some("threats"))
}

/// Run [`type_check`] on the node at `id`, surfacing any failure as a
/// typed [`LoweringError::TypeCheckFailure`]. Defers view-signature
/// lookup to the in-context map (`ctx.view_signatures`).
pub(super) fn typecheck_node(
    ctx: &LoweringCtx<'_>,
    id: CgExprId,
    span: Span,
) -> Result<CgTy, LoweringError> {
    let prog = ctx.builder.program();
    let node = prog
        .exprs
        .get(id.0 as usize)
        .ok_or(LoweringError::TypeCheckFailure {
            error: TypeError::DanglingExprId {
                node: id,
                referenced: id,
            },
            span,
        })?;
    let resolver: &dyn Fn(ViewId) -> Option<(Vec<CgTy>, CgTy)> = &|view_id| {
        ctx.view_signatures
            .get(&view_id)
            .map(|(args, result)| (args.clone(), *result))
    };
    let tc_ctx = TypeCheckCtx::with_view_signature(prog, resolver);
    type_check(node, id, &tc_ctx).map_err(|e| LoweringError::TypeCheckFailure { error: e, span })
}

/// Lower `<base>.<field_name>`. Today the wired bases are `self` (any
/// dispatch shape) and `target` (only inside a pair-bound op — gated by
/// [`LoweringCtx::target_local`]).
///
/// # Limitations
///
/// - `target.<field>` only resolves when [`LoweringCtx::target_local`]
///   is `true`. The driver pass for pair-bound masks (today
///   [`crate::cg::lower::mask::lower_mask`] when the dispatch shape is
///   [`crate::cg::dispatch::DispatchShape::PerPair`]) sets the flag
///   before lowering the predicate and restores it after; outside
///   pair-bound contexts the same access surfaces as the typed
///   [`LoweringError::UnsupportedFieldBase`] deferral so a stray
///   `target` reference can't accidentally route through the per-pair
///   candidate buffer.
/// - Other bases (locals other than `self` / `target`, namespace
///   fields, builder-receiver chains) surface as the same
///   [`LoweringError::UnsupportedFieldBase`] typed deferral.
/// - **Let-bound `AgentId` locals.** Event-pattern binders (and any
///   other let-bound local whose CG type is `AgentId`) take precedence
///   over the bare-name `self` / `target` arms. The base lowers to a
///   `CgExprId` and the read routes through `AgentRef::Target(<that
///   id>)`, semantically identical to `agents.<field>(<that_local>)`.
///   This is the verb-cascade shape: the verb expander synthesises
///   `on ActionSelected { actor: <self>, … }` whose handler body's
///   `self.<field>` must address the actor's row, not the implicit
///   kernel-row identity. Without this arm a `Local(_, "self")` base
///   would be silently routed to `AgentRef::Self_` (the implicit
///   `gid` of the dispatching kernel), miscompiling the cascade.
fn lower_field(
    base: &IrExprNode,
    field_name: &str,
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    // Vec3 component access (Gap dungeon_stealth#1, 2026-05-12): when the
    // field name is `x` / `y` / `z` AND the base lowers to a `vec3<f32>`
    // typed expression, route to a `BuiltinId::Vec3X` / `Vec3Y` / `Vec3Z`
    // call. Lets the surface DSL author `self.pos.x` rather than
    // unpacking the vec into intermediate scalar fields. The base lowers
    // through the recursive `lower_expr` call so any vec3-typed
    // expression — `agents.pos(self)` reader, a let-bound vec3 local,
    // a `vec3(x,y,z)` literal — is acceptable.
    //
    // Sequencing: this MUST run before the agent-target resolution
    // below, because a `Field { base: <vec3 expr>, field_name: "x" }`
    // base shape (e.g. `self.pos.x`) would otherwise miss every
    // `Local(...)` arm and fall straight into the
    // `UnsupportedFieldBase` catch-all. Falls through (no early exit)
    // when the base isn't a vec3, so plain `self.<vec3_field>` (no
    // sub-component) keeps using the existing AgentField read path.
    if let Some(comp_id) = vec3_component_id(field_name) {
        if let Ok(base_id) = lower_expr(base, ctx) {
            if let Ok(base_ty) = typecheck_node(ctx, base_id, base.span) {
                if base_ty == CgTy::Vec3F32 {
                    return add(
                        ctx,
                        CgExpr::Builtin {
                            fn_id: comp_id,
                            args: vec![base_id],
                            ty: CgTy::F32,
                        },
                        span,
                    );
                }
            }
        }
    }

    // Resolve the agent reference implied by the base expression. Today
    // wired bases are `self` (every dispatch shape) and `target` inside
    // a pair-bound op. Anything else falls through as the typed
    // `UnsupportedFieldBase` deferral so a stray base reference can't
    // accidentally route through the per-pair candidate buffer.
    let target = match &base.kind {
        // Let-bound `AgentId` local taking precedence over the bare
        // structural-`self` arm. This is the verb-cascade shape: the
        // verb expander synthesises `on ActionSelected { actor: <self>,
        // action_id: …, target: <target> }` whose binders are
        // event-pattern `LocalRef`s registered in `ctx.local_ids`
        // (with `ctx.local_tys` carrying `CgTy::AgentId`) by
        // `synthesize_pattern_binding_lets`. Inside the handler body,
        // `self.pos` / `target.pos` are not the implicit kernel-row
        // identity — they're the actor / target id read out of the
        // event payload. A bare-name match against `"self"` /
        // `"target"` would silently route them to `AgentRef::Self_` /
        // `AgentRef::PerPairCandidate` and emit
        // `agent_pos[gid]` / `agent_pos[per_pair_candidate]`, neither
        // of which addresses the actor's row.
        //
        // Routing through the same `AgentRef::Target(<expr_id>)` shape
        // as `agents.<field>(<expr>)` (the `(NamespaceId::Agents, _)`
        // arm of `lower_namespace_call`) reuses the slice-1 stmt-prefix
        // hoisting + binding-scanner recursion: the WGSL emit
        // pre-binds `let target_expr_<N>: u32 = <local>;` and the body
        // reads `agent_<field>[target_expr_<N>]`. Semantically
        // identical to authoring `agents.<field>(<that_local>)` by
        // hand.
        //
        // **Fold-binder exclusion.** The fold-body lowering registers
        // its source-level binder (`other` in `sum(other in agents
        // : other.pos)`, or the body-iter binder in
        // `for other in agents { … }`) in BOTH `ctx.local_ids` AND
        // `ctx.fold_binder_name`. The desired semantic for that name
        // is `AgentRef::PerPairCandidate` (the per-pair / per-iter
        // loop variable), NOT a Target-let read of the binder's
        // value. The fold-binder arm below already handles the read;
        // skipping the let-bound arm here keeps that path intact.
        // (Without this guard, a fold-body's `other.pos` would route
        // through Target and the WGSL emit would hoist `let
        // target_expr_<N> = per_pair_candidate;` ahead of the
        // for-loop that binds `per_pair_candidate` — a use-before-def
        // scope error.)
        IrExpr::Local(local_ref, local_name)
            if ctx.local_ids.contains_key(local_ref)
                && ctx.fold_binder_name.as_deref() != Some(local_name.as_str()) =>
        {
            let base_id = lower_expr(base, ctx)?;
            let base_ty = typecheck_node(ctx, base_id, base.span)?;
            if base_ty != CgTy::AgentId {
                // Non-AgentId let-locals (`let dist: f32 = …; dist.foo`)
                // have no field-access semantics — surface the same
                // typed deferral as any other unbound base.
                return Err(LoweringError::UnsupportedFieldBase {
                    field_name: field_name.to_string(),
                    span,
                });
            }
            AgentRef::Target(base_id)
        }
        IrExpr::Local(_, local_name) if local_name == "self" => AgentRef::Self_,
        IrExpr::Local(_, local_name)
            if (local_name == "target" || local_name == "candidate") && ctx.target_local =>
        {
            // Pair-bound mask predicates (and, in 5.5b/c, scoring rows /
            // fold bodies) bind `target` to the per-pair candidate. The
            // emit layer (Task 4.x) resolves `AgentRef::PerPairCandidate`
            // to the candidate buffer + per-thread offset implied by the
            // dispatch shape's `PerPair { source }`; the IR layer just
            // tags the read.
            //
            // Phase 7 Task 5: spatial_query bodies bind their per-pair
            // neighbour as `candidate` (the v1 convention for the new
            // `spatial_query <name>(self, candidate, ...) = <filter>`
            // surface). When such a body is lowered via
            // `lower_filter_for_mask` (which sets `target_local = true`),
            // a `candidate.<field>` access must also resolve to
            // `PerPairCandidate`. Both names route here so existing
            // wolf-sim source (`target.<field>`) and new spatial_query
            // source (`candidate.<field>`) coexist without renaming
            // user-visible identifiers.
            AgentRef::PerPairCandidate
        }
        IrExpr::Local(_, local_name)
            if ctx.fold_binder_name.as_deref() == Some(local_name.as_str()) =>
        {
            // N²-fold body: the user-named binder (e.g. `other` in
            // `sum(other in agents where ... : other.pos)`) resolves
            // to the per-iteration loop variable, which the
            // `CgStmt::ForEachAgent` WGSL emit declares as
            // `per_pair_candidate`. Sharing AgentRef::PerPairCandidate
            // means `binder.<field>` reads route through the same
            // `agent_<field>[per_pair_candidate]` access shape the
            // pair-bound contexts already use.
            AgentRef::PerPairCandidate
        }
        _ => {
            return Err(LoweringError::UnsupportedFieldBase {
                field_name: field_name.to_string(),
                span,
            });
        }
    };

    // Virtual fields: names that don't map to an `AgentFieldId` but
    // synthesize a CG expression from real primitives. Today: `hp_pct`
    // ⇒ `hp / max_hp`. Future entries (mana_pct, cooldown_progress,
    // …) extend the dispatch below.
    if let Some(synth) = lookup_virtual_field(field_name) {
        return synth(target, span, ctx);
    }

    let field = AgentFieldId::from_snake(field_name).ok_or_else(|| {
        LoweringError::UnknownAgentField {
            field_name: field_name.to_string(),
            span,
        }
    })?;
    add(
        ctx,
        CgExpr::Read(DataHandle::AgentField { field, target }),
        span,
    )
}

/// Map a vec3 component field name (`"x"` / `"y"` / `"z"`) to the
/// corresponding [`BuiltinId`] for the postfix-component access. Returns
/// `None` for any other name — the caller (`lower_field`) then falls
/// through to the agent-target resolution path. Gap dungeon_stealth#1
/// (2026-05-12): unlocks `self.pos.x` / `.y` / `.z` accessors so authors
/// don't need to unpack vec3 fields through intermediate scalars.
fn vec3_component_id(field_name: &str) -> Option<BuiltinId> {
    match field_name {
        "x" => Some(BuiltinId::Vec3X),
        "y" => Some(BuiltinId::Vec3Y),
        "z" => Some(BuiltinId::Vec3Z),
        _ => None,
    }
}

/// Type alias for a virtual-field synthesizer. Each entry takes the
/// resolved [`AgentRef`] (whatever `self`-or-`target` the original
/// `IrExpr::Field` carried), the source [`Span`], and the lowering
/// context, and produces the synthesized [`CgExprId`].
type VirtualFieldSynth =
    fn(AgentRef, Span, &mut LoweringCtx<'_>) -> Result<CgExprId, LoweringError>;

/// Virtual fields synthesized from real `AgentField` primitives. Today
/// the only entry is `hp_pct = hp / max_hp`; new virtuals
/// (`mana_pct`, `cooldown_progress`, …) extend this table without
/// touching `lower_field`'s control flow.
const VIRTUAL_FIELDS: &[(&str, VirtualFieldSynth)] = &[("hp_pct", lower_hp_pct)];

/// Lookup helper for [`VIRTUAL_FIELDS`]. Returns the synthesizer for a
/// virtual field name, or `None` for real `AgentFieldId` names (which
/// fall through to `AgentFieldId::from_snake` in [`lower_field`]).
fn lookup_virtual_field(field_name: &str) -> Option<VirtualFieldSynth> {
    VIRTUAL_FIELDS
        .iter()
        .find_map(|(name, synth)| (*name == field_name).then_some(*synth))
}

/// Synthesize `<target>.hp / <target>.max_hp` for `<target>.hp_pct`.
/// Both reads carry the caller-supplied `target` so a per-pair
/// `target.hp_pct` lowers to per-pair-candidate reads, and `self.hp_pct`
/// lowers to self-reads.
fn lower_hp_pct(
    target: AgentRef,
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    let lhs = add(
        ctx,
        CgExpr::Read(DataHandle::AgentField {
            field: AgentFieldId::Hp,
            target: target.clone(),
        }),
        span,
    )?;
    let rhs = add(
        ctx,
        CgExpr::Read(DataHandle::AgentField {
            field: AgentFieldId::MaxHp,
            target,
        }),
        span,
    )?;
    add(
        ctx,
        CgExpr::Binary {
            op: BinaryOp::DivF32,
            lhs,
            rhs,
            ty: CgTy::F32,
        },
        span,
    )
}

/// Lower a bare `IrExpr::Local(local_ref, name)` (no `.field` access)
/// to a CG expression.
///
/// Resolution order:
///
/// 1. **Let-bound local.** If `ctx.local_ids` has an entry for
///    `local_ref`, the local was introduced by an enclosing
///    `IrStmt::Let` (lowered to `CgStmt::Let { local, value, ty }`).
///    The expression resolves to `CgExpr::ReadLocal { local, ty }`
///    where `ty` comes from `ctx.local_tys`. A missing
///    `local_tys` entry surfaces as
///    [`LoweringError::UnknownLocalType`].
/// 2. **Bare `self`.** Resolves to [`CgExpr::AgentSelfId`] (typed
///    `AgentId`). Used in surface DSL like `agents.alive(self)` and
///    `target != self`.
/// 3. **Bare `target` in a pair-bound context.** Resolves to
///    [`CgExpr::PerPairCandidateId`] (typed `AgentId`) when
///    `ctx.target_local` is `true`. Outside pair-bound contexts, falls
///    through to the default error.
/// 4. **Anything else** — surfaces as
///    [`LoweringError::UnsupportedLocalBinding`].
fn lower_bare_local(
    local_ref: LocalRef,
    name: &str,
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    // Step 0: fold-binder name takes precedence over any conflicting
    // let-bound local registration. The resolver may have given the
    // outer-let's LocalRef the same numeric index as the fold binder
    // (the AST scopes are independent — one numbers within the body,
    // the other within the fold), and `local_ids` indexes by that
    // numeric LocalRef. Without this guard a bare-binder read like
    // `other != self` inside `for other in agents` resolves to
    // `local_X` (the outer let) instead of `per_pair_candidate`,
    // producing WGSL referencing an undefined identifier. The
    // matching guard in `lower_field` already does this — see the
    // `IrExpr::Local(_, local_name) if fold_binder_name == local_name`
    // arm.
    if ctx.fold_binder_name.as_deref() == Some(name) {
        return add(ctx, CgExpr::PerPairCandidateId, span);
    }

    // Step 1: let-bound local.
    if let Some(&local_id) = ctx.local_ids.get(&local_ref) {
        let ty = ctx.local_tys.get(&local_id).copied().ok_or(
            LoweringError::UnknownLocalType {
                local: local_id,
                span,
            },
        )?;
        return add(ctx, CgExpr::ReadLocal { local: local_id, ty }, span);
    }

    // Step 2-3: structural locals.
    match name {
        "self" => add(ctx, CgExpr::AgentSelfId, span),
        // Phase 7 Task 5: accept both `target` (the action-head binder
        // name used by wolf-sim masks like `mask MoveToward(target) ...`)
        // and `candidate` (the spatial_query body binder name from the
        // new `spatial_query <name>(self, candidate, ...) = <filter>`
        // surface). Both resolve to the per-pair candidate id when the
        // pair-bound context is active. See the matching arm in
        // `lower_field` for the field-access path.
        "target" | "candidate" if ctx.target_local => {
            add(ctx, CgExpr::PerPairCandidateId, span)
        }
        // Plan G G3f follow-up — gap (b) from threats_struct_probe.sim.
        // `source_candidate` is the synthetic AgentId binding the AST
        // resolver injects into per_agent_event_scan view-fold bodies.
        // Lower as the per-pair candidate id (same kernel-local the
        // WGSL emit declares: `let source_candidate = gid.y;`).
        "source_candidate" if ctx.per_agent_event_scan_local => {
            add(ctx, CgExpr::PerPairCandidateId, span)
        }
        // N²-fold body bare-binder read (`other != self` etc.). The
        // user-named binder resolves to the per-iteration loop
        // variable, mirroring the field-access path in `lower_field`.
        n if ctx.fold_binder_name.as_deref() == Some(n) => {
            add(ctx, CgExpr::PerPairCandidateId, span)
        }
        // Wildcard `_` is short-circuited at the PerUnit lowering level
        // (see `IrExpr::PerUnit` arm in `lower_expr`). It should never
        // reach `lower_bare_local` directly — if it does, that's a
        // genuinely-unsupported context (e.g., bare wildcard outside a
        // PerUnit-modified view call) which surfaces as the standard
        // UnsupportedLocalBinding diagnostic. Future per-unit-fold
        // semantic resolves wildcards in the fold-iteration variable
        // binding instead.
        _ => Err(LoweringError::UnsupportedLocalBinding {
            name: name.to_string(),
            span,
        }),
    }
}

/// True if `node` is a bare wildcard `_` (an `IrExpr::Local` with
/// name `"_"`). Used by `lower_view_call` to short-circuit view calls
/// with wildcard args to a typed zero literal. Sibling helper to
/// [`expr_contains_wildcard`].
fn is_wildcard_local(node: &IrExprNode) -> bool {
    use dsl_ast::ir::IrExpr;
    matches!(&node.kind, IrExpr::Local(_, name) if name == "_")
}

/// True if `node` (or any sub-expression) is an `IrExpr::Local` with
/// name `"_"`. Used by the PerUnit lowering arm to short-circuit
/// wildcard-bearing expressions to a literal 0.0 rather than
/// attempting the (currently-broken) view-call-with-wildcard-arg path.
/// See the `IrExpr::PerUnit` arm in `lower_expr` for the rationale.
///
/// Cheap recursive walk: the wildcard appears at most a few sites per
/// PerUnit expression in practice, and the match is exhaustive over
/// `IrExpr` so adding a new variant forces an explicit decision.
fn expr_contains_wildcard(node: &IrExprNode) -> bool {
    use dsl_ast::ir::IrExpr;
    match &node.kind {
        IrExpr::Local(_, name) => name == "_",
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
        | IrExpr::AbilityHintLit { .. } => false,
        IrExpr::Unary(_, e) => expr_contains_wildcard(e),
        IrExpr::Binary(_, lhs, rhs)
        | IrExpr::In(lhs, rhs)
        | IrExpr::Contains(lhs, rhs)
        | IrExpr::Index(lhs, rhs) => {
            expr_contains_wildcard(lhs) || expr_contains_wildcard(rhs)
        }
        IrExpr::PerUnit { expr, delta } => {
            expr_contains_wildcard(expr) || expr_contains_wildcard(delta)
        }
        IrExpr::Field { base, .. } => expr_contains_wildcard(base),
        IrExpr::ViewCall(_, args)
        | IrExpr::VerbCall(_, args)
        | IrExpr::BuiltinCall(_, args)
        | IrExpr::UnresolvedCall(_, args)
        | IrExpr::NamespaceCall { args, .. } => {
            args.iter().any(|a| expr_contains_wildcard(&a.value))
        }
        IrExpr::If { cond, then_expr, else_expr } => {
            expr_contains_wildcard(cond)
                || expr_contains_wildcard(then_expr)
                || else_expr.as_ref().map_or(false, |e| expr_contains_wildcard(e))
        }
        IrExpr::Quantifier { iter, body, .. } => {
            expr_contains_wildcard(iter) || expr_contains_wildcard(body)
        }
        IrExpr::Fold { iter, body, .. } => {
            iter.as_ref().map_or(false, |i| expr_contains_wildcard(i))
                || expr_contains_wildcard(body)
        }
        IrExpr::Match { scrutinee, arms } => {
            expr_contains_wildcard(scrutinee)
                || arms.iter().any(|arm| expr_contains_wildcard(&arm.body))
        }
        IrExpr::List(items) | IrExpr::Tuple(items) => {
            items.iter().any(expr_contains_wildcard)
        }
        IrExpr::StructLit { fields, .. } => {
            fields.iter().any(|f| expr_contains_wildcard(&f.value))
        }
        IrExpr::Ctor { args, .. } => args.iter().any(expr_contains_wildcard),
        // Catch-all: any IrExpr variant not enumerated above is a leaf
        // shape with no IrExprNode sub-expressions (AbilityRange, Raw,
        // AbilityOnCooldown, etc.). They cannot contain a wildcard
        // syntactically. If a future variant adds children, the match
        // arm needs an explicit case — exhaustive checking will force
        // the update.
        _ => false,
    }
}

/// Lower a binary operator. Picks the typed [`BinaryOp`] variant based
/// on operand types — the AST's untyped `BinOp::Lt` becomes
/// `BinaryOp::LtF32` when both operands are `F32`, etc.
fn lower_binary(
    op: BinOp,
    lhs: &IrExprNode,
    rhs: &IrExprNode,
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    let lhs_id = lower_expr(lhs, ctx)?;
    let rhs_id = lower_expr(rhs, ctx)?;
    let lhs_ty = typecheck_node(ctx, lhs_id, lhs.span)?;
    let rhs_ty = typecheck_node(ctx, rhs_id, rhs.span)?;

    // Signed/unsigned integer literal coercion. A non-negative DSL
    // integer literal defaults to `LitValue::U32` at lowering time
    // (see `IrExpr::LitInt`). When the other operand is an `I32`-
    // typed non-literal (e.g., a signed event-field read like
    // `delta: i32`), the resulting `i32 != 0u32` shape would be
    // rejected as `BinaryOperandTyMismatch`. We coerce one side: if
    // exactly ONE operand is a `U32` literal and the OTHER operand
    // is `I32`-typed and non-literal, re-emit the literal as `I32`.
    // The asymmetric requirement (literal vs. non-literal) keeps a
    // genuine `i32_a != u32_b` mismatch (both non-literal) reported
    // as a real typing bug rather than silently coerced away.
    let (lhs_id, lhs_ty, rhs_id, rhs_ty) =
        coerce_int_literal_to_signed(ctx, lhs_id, lhs_ty, rhs_id, rhs_ty, span)?;

    // Asymmetric Vec3-by-scalar arithmetic: `vec3 * f32` /
    // `f32 * vec3` / `vec3 / f32`. WGSL handles these natively; we
    // pick the typed Mul/DivVec3ByF32 variant with the vec3 always
    // on the lhs (commute scalar*vec to vec*scalar at lowering
    // time). Falls through to the symmetric path below if neither
    // operand pair matches.
    if let Some(id) = try_lower_vec3_scalar(op, lhs_id, lhs_ty, rhs_id, rhs_ty, span, ctx)? {
        return Ok(id);
    }

    // Implicit `u32`/`i32` → `f32` promotion when the peer operand is
    // f32. Mirrors WGSL's lack of auto-promotion at the IR level by
    // wrapping the integer side in a `BuiltinId::AsF32(<src>)` cast,
    // so `1000.0 - hp_u32` lowers as `1000.0 - f32(hp_u32)`. Closes
    // Gap #2 of the pair_scoring probe (gap chain in
    // `docs/superpowers/notes/2026-05-04-pair_scoring_probe.md`).
    // Scope: only applies to numeric ops (arith + compare). Logical
    // `And`/`Or` reject earlier in `pick_binary_op` regardless. The
    // promotion is one-directional (int → f32), never the reverse —
    // demoting f32 to int is lossy and stays an explicit user-side
    // cast.
    let (lhs_id, lhs_ty, rhs_id, rhs_ty) =
        promote_int_to_f32(ctx, lhs_id, lhs_ty, rhs_id, rhs_ty, span)?;

    if lhs_ty != rhs_ty {
        return Err(LoweringError::BinaryOperandTyMismatch {
            op,
            lhs_ty,
            rhs_ty,
            span,
        });
    }

    let cg_op = pick_binary_op(op, lhs_ty, span)?;
    let result_ty = cg_op.result_ty();
    add(
        ctx,
        CgExpr::Binary {
            op: cg_op,
            lhs: lhs_id,
            rhs: rhs_id,
            ty: result_ty,
        },
        span,
    )
}

/// Try to lower a `vec3 * f32` / `f32 * vec3` / `vec3 / f32` binary
/// expression to its typed asymmetric variant
/// (`MulVec3ByF32` / `DivVec3ByF32`). Returns `Ok(Some(id))` when
/// the pattern matched and the typed binary node is now in the
/// arena; `Ok(None)` otherwise (the caller falls through to the
/// symmetric path). The `f32 * vec3` form commutes the operands so
/// vec3 is always on the lhs of the emitted `MulVec3ByF32`.
fn try_lower_vec3_scalar(
    op: BinOp,
    lhs_id: CgExprId,
    lhs_ty: CgTy,
    rhs_id: CgExprId,
    rhs_ty: CgTy,
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<Option<CgExprId>, LoweringError> {
    let cg_op = match (op, lhs_ty, rhs_ty) {
        (BinOp::Mul, CgTy::Vec3F32, CgTy::F32) | (BinOp::Mul, CgTy::F32, CgTy::Vec3F32) => {
            BinaryOp::MulVec3ByF32
        }
        (BinOp::Div, CgTy::Vec3F32, CgTy::F32) => BinaryOp::DivVec3ByF32,
        // Div the other way (`f32 / vec3`) is component-divide-into-
        // scalar, semantically distinct and not needed by the boids
        // fixture; skip until a real consumer arrives.
        _ => return Ok(None),
    };
    let (vec_id, scalar_id) = if lhs_ty == CgTy::Vec3F32 {
        (lhs_id, rhs_id)
    } else {
        (rhs_id, lhs_id)
    };
    let id = add(
        ctx,
        CgExpr::Binary {
            op: cg_op,
            lhs: vec_id,
            rhs: scalar_id,
            ty: CgTy::Vec3F32,
        },
        span,
    )?;
    Ok(Some(id))
}

/// Coerce a default-`U32` integer literal operand to `I32` when the
/// peer operand is a non-literal `I32`. Returns the (possibly updated)
/// `(lhs_id, lhs_ty, rhs_id, rhs_ty)` tuple.
///
/// Rationale: the DSL surface uses signed `i64` literal values; the
/// CG layer narrows to `U32` for non-negative literals (see
/// `IrExpr::LitInt`'s lowering). Patterns like `delta != 0` —
/// where `delta: i32` reads as a signed event-field — need the `0`
/// to lower as `I32` for the binary type-check to succeed. The
/// coercion is intentionally narrow:
///
/// - Only `U32` → `I32`, not the symmetric direction (no operand we
///   produce today defaults a literal to `I32` at lowering time).
/// - Only when EXACTLY ONE operand is a `Lit` and the OTHER is
///   non-`Lit`. Two non-literal `i32`/`u32` operands is a genuine
///   typing bug and stays an error.
/// - Only the literal value `0..=i32::MAX` survives the cast
///   without truncation. Higher-magnitude literals would need
///   explicit user-side typing; we leave them as `U32` so the
///   downstream mismatch error stays visible.
fn coerce_int_literal_to_signed(
    ctx: &mut LoweringCtx<'_>,
    lhs_id: CgExprId,
    lhs_ty: CgTy,
    rhs_id: CgExprId,
    rhs_ty: CgTy,
    span: Span,
) -> Result<(CgExprId, CgTy, CgExprId, CgTy), LoweringError> {
    // Only act on (I32, U32) or (U32, I32) operand-type pairs.
    let (lhs_lit, rhs_lit) = {
        let prog = ctx.builder.program();
        let lhs_lit = prog
            .exprs
            .get(lhs_id.0 as usize)
            .and_then(|e| match e {
                CgExpr::Lit(LitValue::U32(v)) => Some(*v),
                _ => None,
            });
        let rhs_lit = prog
            .exprs
            .get(rhs_id.0 as usize)
            .and_then(|e| match e {
                CgExpr::Lit(LitValue::U32(v)) => Some(*v),
                _ => None,
            });
        (lhs_lit, rhs_lit)
    };

    // Case A: lhs is non-literal I32, rhs is U32 literal — coerce rhs.
    if lhs_ty == CgTy::I32 && rhs_ty == CgTy::U32 && rhs_lit.is_some() && lhs_lit.is_none() {
        let v = rhs_lit.unwrap();
        if v <= i32::MAX as u32 {
            let new_rhs = add(ctx, CgExpr::Lit(LitValue::I32(v as i32)), span)?;
            return Ok((lhs_id, lhs_ty, new_rhs, CgTy::I32));
        }
    }
    // Case B: rhs is non-literal I32, lhs is U32 literal — coerce lhs.
    if rhs_ty == CgTy::I32 && lhs_ty == CgTy::U32 && lhs_lit.is_some() && rhs_lit.is_none() {
        let v = lhs_lit.unwrap();
        if v <= i32::MAX as u32 {
            let new_lhs = add(ctx, CgExpr::Lit(LitValue::I32(v as i32)), span)?;
            return Ok((new_lhs, CgTy::I32, rhs_id, rhs_ty));
        }
    }
    Ok((lhs_id, lhs_ty, rhs_id, rhs_ty))
}

/// Implicit `u32` / `i32` → `f32` promotion for mixed-type binary
/// arithmetic and comparison. When exactly one operand is `F32` and
/// the other is `U32` or `I32`, wrap the integer side in a
/// [`BuiltinId::AsF32`] cast and return the updated tuple. WGSL
/// itself doesn't auto-promote — the cast lowers to `f32(<arg>)` at
/// emit time. Falls through (returns the input tuple unchanged) for
/// any other type combination, including `Tick` / `AgentId` — those
/// stay an explicit-cast surface concern.
///
/// Asymmetric direction is intentional: f32 → int is lossy and would
/// hide truncation bugs; the user must opt into it explicitly. The
/// integer-side widening is loss-free for `i32` (representable
/// exactly up to `2^24`; larger magnitudes round to nearest f32) and
/// for `u32` under the same bound.
fn promote_int_to_f32(
    ctx: &mut LoweringCtx<'_>,
    lhs_id: CgExprId,
    lhs_ty: CgTy,
    rhs_id: CgExprId,
    rhs_ty: CgTy,
    span: Span,
) -> Result<(CgExprId, CgTy, CgExprId, CgTy), LoweringError> {
    fn int_src(ty: CgTy) -> Option<NumericTy> {
        match ty {
            CgTy::U32 => Some(NumericTy::U32),
            CgTy::I32 => Some(NumericTy::I32),
            _ => None,
        }
    }
    // lhs:f32, rhs:int — promote rhs.
    if lhs_ty == CgTy::F32 {
        if let Some(src) = int_src(rhs_ty) {
            let new_rhs = add(
                ctx,
                CgExpr::Builtin {
                    fn_id: BuiltinId::AsF32(src),
                    args: vec![rhs_id],
                    ty: CgTy::F32,
                },
                span,
            )?;
            return Ok((lhs_id, lhs_ty, new_rhs, CgTy::F32));
        }
    }
    // lhs:int, rhs:f32 — promote lhs.
    if rhs_ty == CgTy::F32 {
        if let Some(src) = int_src(lhs_ty) {
            let new_lhs = add(
                ctx,
                CgExpr::Builtin {
                    fn_id: BuiltinId::AsF32(src),
                    args: vec![lhs_id],
                    ty: CgTy::F32,
                },
                span,
            )?;
            return Ok((new_lhs, CgTy::F32, rhs_id, rhs_ty));
        }
    }
    Ok((lhs_id, lhs_ty, rhs_id, rhs_ty))
}

/// Pick the typed [`BinaryOp`] variant for a given AST op + operand
/// type. An unsupported combination (e.g., `agent.alive < 5`'s
/// `Lt<Bool>`) becomes [`LoweringError::IllTypedExpression`].
fn pick_binary_op(op: BinOp, ty: CgTy, span: Span) -> Result<BinaryOp, LoweringError> {
    match (op, ty) {
        // Logical — Bool only.
        (BinOp::And, CgTy::Bool) => Ok(BinaryOp::And),
        (BinOp::Or, CgTy::Bool) => Ok(BinaryOp::Or),
        (BinOp::And | BinOp::Or, _) => Err(LoweringError::IllTypedExpression {
            expected: CgTy::Bool,
            got: ty,
            span,
        }),

        // Equality — Bool, U32, I32, F32, AgentId. Tick comparisons go
        // through U32 (BinaryOp doc states this).
        (BinOp::Eq, CgTy::Bool) => Ok(BinaryOp::EqBool),
        (BinOp::Eq, CgTy::U32) | (BinOp::Eq, CgTy::Tick) => Ok(BinaryOp::EqU32),
        (BinOp::Eq, CgTy::I32) => Ok(BinaryOp::EqI32),
        (BinOp::Eq, CgTy::F32) => Ok(BinaryOp::EqF32),
        (BinOp::Eq, CgTy::AgentId) => Ok(BinaryOp::EqAgentId),
        (BinOp::Eq, CgTy::Vec3F32) | (BinOp::Eq, CgTy::ViewKey { .. }) => {
            Err(LoweringError::IllTypedExpression {
                expected: CgTy::F32,
                got: ty,
                span,
            })
        }
        (BinOp::NotEq, CgTy::Bool) => Ok(BinaryOp::NeBool),
        (BinOp::NotEq, CgTy::U32) | (BinOp::NotEq, CgTy::Tick) => Ok(BinaryOp::NeU32),
        (BinOp::NotEq, CgTy::I32) => Ok(BinaryOp::NeI32),
        (BinOp::NotEq, CgTy::F32) => Ok(BinaryOp::NeF32),
        (BinOp::NotEq, CgTy::AgentId) => Ok(BinaryOp::NeAgentId),
        (BinOp::NotEq, CgTy::Vec3F32) | (BinOp::NotEq, CgTy::ViewKey { .. }) => {
            Err(LoweringError::IllTypedExpression {
                expected: CgTy::F32,
                got: ty,
                span,
            })
        }

        // Ordered comparisons — F32, U32 (incl. Tick), I32 only.
        (BinOp::Lt, CgTy::F32) => Ok(BinaryOp::LtF32),
        (BinOp::Lt, CgTy::U32) | (BinOp::Lt, CgTy::Tick) => Ok(BinaryOp::LtU32),
        (BinOp::Lt, CgTy::I32) => Ok(BinaryOp::LtI32),
        (BinOp::LtEq, CgTy::F32) => Ok(BinaryOp::LeF32),
        (BinOp::LtEq, CgTy::U32) | (BinOp::LtEq, CgTy::Tick) => Ok(BinaryOp::LeU32),
        (BinOp::LtEq, CgTy::I32) => Ok(BinaryOp::LeI32),
        (BinOp::Gt, CgTy::F32) => Ok(BinaryOp::GtF32),
        (BinOp::Gt, CgTy::U32) | (BinOp::Gt, CgTy::Tick) => Ok(BinaryOp::GtU32),
        (BinOp::Gt, CgTy::I32) => Ok(BinaryOp::GtI32),
        (BinOp::GtEq, CgTy::F32) => Ok(BinaryOp::GeF32),
        (BinOp::GtEq, CgTy::U32) | (BinOp::GtEq, CgTy::Tick) => Ok(BinaryOp::GeU32),
        (BinOp::GtEq, CgTy::I32) => Ok(BinaryOp::GeI32),
        (BinOp::Lt | BinOp::LtEq | BinOp::Gt | BinOp::GtEq, _) => {
            Err(LoweringError::IllTypedExpression {
                expected: CgTy::F32,
                got: ty,
                span,
            })
        }

        // Arithmetic — F32, U32, I32, plus Vec3 (componentwise +/-).
        (BinOp::Add, CgTy::F32) => Ok(BinaryOp::AddF32),
        (BinOp::Add, CgTy::U32) => Ok(BinaryOp::AddU32),
        (BinOp::Add, CgTy::I32) => Ok(BinaryOp::AddI32),
        (BinOp::Add, CgTy::Vec3F32) => Ok(BinaryOp::AddVec3),
        (BinOp::Sub, CgTy::F32) => Ok(BinaryOp::SubF32),
        (BinOp::Sub, CgTy::U32) => Ok(BinaryOp::SubU32),
        (BinOp::Sub, CgTy::I32) => Ok(BinaryOp::SubI32),
        (BinOp::Sub, CgTy::Vec3F32) => Ok(BinaryOp::SubVec3),
        (BinOp::Mul, CgTy::F32) => Ok(BinaryOp::MulF32),
        (BinOp::Mul, CgTy::U32) => Ok(BinaryOp::MulU32),
        (BinOp::Mul, CgTy::I32) => Ok(BinaryOp::MulI32),
        (BinOp::Div, CgTy::F32) => Ok(BinaryOp::DivF32),
        (BinOp::Div, CgTy::U32) => Ok(BinaryOp::DivU32),
        (BinOp::Div, CgTy::I32) => Ok(BinaryOp::DivI32),
        // Vec3 mul/div not yet supported — boids steering uses only +/-
        // today. When weighted-sum forms (`alignment * weight + ...`)
        // arrive, add Vec3-by-scalar variants here.
        (BinOp::Add | BinOp::Sub | BinOp::Mul | BinOp::Div, _) => {
            Err(LoweringError::IllTypedExpression {
                expected: CgTy::F32,
                got: ty,
                span,
            })
        }

        // Mod — F32, U32, I32. `Tick` is treated as U32 for parity
        // with the comparison ops, so cooldown gates of the form
        // `tick % cooldown_ticks == 0u` lower cleanly. WGSL emits the
        // native `%` operator. See the abilities-probe discovery doc
        // (`docs/superpowers/notes/2026-05-04-abilities_probe.md`,
        // Gap #3).
        (BinOp::Mod, CgTy::F32) => Ok(BinaryOp::ModF32),
        (BinOp::Mod, CgTy::U32) | (BinOp::Mod, CgTy::Tick) => Ok(BinaryOp::ModU32),
        (BinOp::Mod, CgTy::I32) => Ok(BinaryOp::ModI32),
        (BinOp::Mod, _) => Err(LoweringError::IllTypedExpression {
            expected: CgTy::F32,
            got: ty,
            span,
        }),

        // #159: bitwise ops are u32-only at the CG layer (the
        // archetypal use case is per-agent skill / recipe bitsets,
        // which the SoA stores as u32). Adding I32/U64 variants is
        // straightforward when a fixture demands it. F32/Bool/Vec3
        // operands are rejected as ill-typed.
        (BinOp::BitOr, CgTy::U32)  => Ok(BinaryOp::BitOrU32),
        (BinOp::BitXor, CgTy::U32) => Ok(BinaryOp::BitXorU32),
        (BinOp::BitAnd, CgTy::U32) => Ok(BinaryOp::BitAndU32),
        (BinOp::BitOr | BinOp::BitXor | BinOp::BitAnd, _) => {
            Err(LoweringError::IllTypedExpression {
                expected: CgTy::U32,
                got: ty,
                span,
            })
        }
    }
}

/// Lower a unary operator. The CG-side variant is picked from operand
/// type (`Neg`/`Abs`/`Sqrt` go through `F32`/`I32`; `Not` is `Bool`-only).
fn lower_unary(
    op: UnOp,
    arg: &IrExprNode,
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    let arg_id = lower_expr(arg, ctx)?;
    let arg_ty = typecheck_node(ctx, arg_id, arg.span)?;
    let cg_op = pick_unary_op(op, arg_ty, span)?;
    let result_ty = cg_op.result_ty();
    add(
        ctx,
        CgExpr::Unary {
            op: cg_op,
            arg: arg_id,
            ty: result_ty,
        },
        span,
    )
}

fn pick_unary_op(op: UnOp, ty: CgTy, span: Span) -> Result<UnaryOp, LoweringError> {
    match (op, ty) {
        (UnOp::Not, CgTy::Bool) => Ok(UnaryOp::NotBool),
        (UnOp::Not, _) => Err(LoweringError::IllTypedExpression {
            expected: CgTy::Bool,
            got: ty,
            span,
        }),
        (UnOp::Neg, CgTy::F32) => Ok(UnaryOp::NegF32),
        (UnOp::Neg, CgTy::I32) => Ok(UnaryOp::NegI32),
        (UnOp::Neg, _) => Err(LoweringError::IllTypedExpression {
            expected: CgTy::F32,
            got: ty,
            span,
        }),
    }
}

/// Lower an `if cond then a else b` AST node into a [`CgExpr::Select`].
fn lower_select(
    cond: &IrExprNode,
    then_expr: &IrExprNode,
    else_expr: &IrExprNode,
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    let cond_id = lower_expr(cond, ctx)?;
    let then_id = lower_expr(then_expr, ctx)?;
    let else_id = lower_expr(else_expr, ctx)?;
    let cond_ty = typecheck_node(ctx, cond_id, cond.span)?;
    if cond_ty != CgTy::Bool {
        return Err(LoweringError::IllTypedExpression {
            expected: CgTy::Bool,
            got: cond_ty,
            span,
        });
    }
    let then_ty = typecheck_node(ctx, then_id, then_expr.span)?;
    let else_ty = typecheck_node(ctx, else_id, else_expr.span)?;
    if then_ty != else_ty {
        return Err(LoweringError::SelectArmMismatch {
            then_ty,
            else_ty,
            span,
        });
    }
    add(
        ctx,
        CgExpr::Select {
            cond: cond_id,
            then: then_id,
            else_: else_id,
            ty: then_ty,
        },
        span,
    )
}

/// Lower a [`Builtin`] call to a [`CgExpr::Builtin`]. The CG-side
/// `BuiltinId` variant is picked from the AST `Builtin` enum + (where
/// applicable) operand types.
fn lower_builtin_call(
    builtin: Builtin,
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    // Aggregations / quantifiers are AST-level dedicated nodes (Fold,
    // Quantifier) — they don't appear here as `BuiltinCall(Min, _)` in
    // their fold-shape, but the parser does produce `BuiltinCall(Min,
    // [a, b])` for the pairwise shape. Differentiate by arity.
    match builtin {
        Builtin::Forall | Builtin::Exists | Builtin::Count | Builtin::Sum => {
            return Err(LoweringError::UnsupportedBuiltin { builtin, span });
        }
        _ => {}
    }

    // Lower every argument first; then dispatch on the typed shape.
    let mut arg_ids = Vec::with_capacity(args.len());
    let mut arg_tys = Vec::with_capacity(args.len());
    for a in args {
        let id = lower_expr(&a.value, ctx)?;
        let ty = typecheck_node(ctx, id, a.value.span)?;
        arg_ids.push(id);
        arg_tys.push(ty);
    }

    match builtin {
        Builtin::Distance | Builtin::PlanarDistance | Builtin::ZSeparation => {
            expect_arity(builtin, 2, args.len(), span)?;
            let fn_id = match builtin {
                Builtin::Distance => BuiltinId::Distance,
                Builtin::PlanarDistance => BuiltinId::PlanarDistance,
                Builtin::ZSeparation => BuiltinId::ZSeparation,
                _ => unreachable!("outer match restricts to 3 distance variants"),
            };
            // Operand types must both be Vec3F32. Type checker enforces
            // it; we run that on the parent below.
            let result_ty = CgTy::F32;
            add(
                ctx,
                CgExpr::Builtin {
                    fn_id,
                    args: arg_ids,
                    ty: result_ty,
                },
                span,
            )
        }
        Builtin::Entity => {
            expect_arity(builtin, 1, args.len(), span)?;
            let result_ty = CgTy::AgentId;
            add(
                ctx,
                CgExpr::Builtin {
                    fn_id: BuiltinId::Entity,
                    args: arg_ids,
                    ty: result_ty,
                },
                span,
            )
        }
        Builtin::Floor | Builtin::Ceil | Builtin::Round
        | Builtin::Ln | Builtin::Log2 | Builtin::Log10 => {
            expect_arity(builtin, 1, args.len(), span)?;
            let fn_id = match builtin {
                Builtin::Floor => BuiltinId::Floor,
                Builtin::Ceil => BuiltinId::Ceil,
                Builtin::Round => BuiltinId::Round,
                Builtin::Ln => BuiltinId::Ln,
                Builtin::Log2 => BuiltinId::Log2,
                Builtin::Log10 => BuiltinId::Log10,
                _ => unreachable!("outer match restricts to 6 unary-f32 builtins"),
            };
            add(
                ctx,
                CgExpr::Builtin {
                    fn_id,
                    args: arg_ids,
                    ty: CgTy::F32,
                },
                span,
            )
        }
        Builtin::Sqrt => {
            // `sqrt` lowers to a `UnaryOp` (CG IR represents shape-pure
            // scalar functions there). Surface this rewrite explicitly.
            expect_arity(builtin, 1, args.len(), span)?;
            // Re-use the already-pushed arg id; build a Unary node.
            let arg_id = arg_ids[0];
            let arg_ty = arg_tys[0];
            if arg_ty != CgTy::F32 {
                return Err(LoweringError::IllTypedExpression {
                    expected: CgTy::F32,
                    got: arg_ty,
                    span,
                });
            }
            add(
                ctx,
                CgExpr::Unary {
                    op: UnaryOp::SqrtF32,
                    arg: arg_id,
                    ty: CgTy::F32,
                },
                span,
            )
        }
        Builtin::Normalize => {
            // `normalize(v)` — vec3 unit vector. Shape-pure (operand_ty
            // == result_ty == Vec3F32), so the lowering uses
            // `UnaryOp::NormalizeVec3F32` (mirrors `Builtin::Sqrt`'s
            // rewrite to `UnaryOp::SqrtF32`).
            expect_arity(builtin, 1, args.len(), span)?;
            let arg_id = arg_ids[0];
            let arg_ty = arg_tys[0];
            if arg_ty != CgTy::Vec3F32 {
                return Err(LoweringError::IllTypedExpression {
                    expected: CgTy::Vec3F32,
                    got: arg_ty,
                    span,
                });
            }
            add(
                ctx,
                CgExpr::Unary {
                    op: UnaryOp::NormalizeVec3F32,
                    arg: arg_id,
                    ty: CgTy::Vec3F32,
                },
                span,
            )
        }
        Builtin::Length => {
            // `length(v)` — Vec3F32 -> F32. Result type differs from
            // operand type, so it uses a `BuiltinId` variant rather
            // than `UnaryOp` (which is shape-pure by contract).
            expect_arity(builtin, 1, args.len(), span)?;
            let arg_ty = arg_tys[0];
            if arg_ty != CgTy::Vec3F32 {
                return Err(LoweringError::IllTypedExpression {
                    expected: CgTy::Vec3F32,
                    got: arg_ty,
                    span,
                });
            }
            add(
                ctx,
                CgExpr::Builtin {
                    fn_id: BuiltinId::LengthVec3F32,
                    args: arg_ids,
                    ty: CgTy::F32,
                },
                span,
            )
        }
        Builtin::Dot => {
            // `dot(a, b)` — (Vec3F32, Vec3F32) -> F32.
            expect_arity(builtin, 2, args.len(), span)?;
            for (idx, &t) in arg_tys.iter().enumerate() {
                if t != CgTy::Vec3F32 {
                    return Err(LoweringError::IllTypedExpression {
                        expected: CgTy::Vec3F32,
                        got: t,
                        span: args[idx].value.span,
                    });
                }
            }
            add(
                ctx,
                CgExpr::Builtin {
                    fn_id: BuiltinId::DotVec3F32,
                    args: arg_ids,
                    ty: CgTy::F32,
                },
                span,
            )
        }
        Builtin::Abs => {
            // Same UnaryOp rewrite as `sqrt`, but typed `F32` or `I32`.
            expect_arity(builtin, 1, args.len(), span)?;
            let arg_id = arg_ids[0];
            let arg_ty = arg_tys[0];
            let unary = match arg_ty {
                CgTy::F32 => UnaryOp::AbsF32,
                CgTy::I32 => UnaryOp::AbsI32,
                _ => {
                    return Err(LoweringError::NumericBuiltinNonNumericOperand {
                        builtin,
                        operand_index: 0,
                        got: arg_ty,
                        span,
                    });
                }
            };
            add(
                ctx,
                CgExpr::Unary {
                    op: unary,
                    arg: arg_id,
                    ty: arg_ty,
                },
                span,
            )
        }
        Builtin::Min => lower_pairwise_numeric(
            builtin,
            BuiltinIdCtor::Min,
            &arg_ids,
            &arg_tys,
            args,
            span,
            ctx,
        ),
        Builtin::Max => lower_pairwise_numeric(
            builtin,
            BuiltinIdCtor::Max,
            &arg_ids,
            &arg_tys,
            args,
            span,
            ctx,
        ),
        Builtin::Clamp => {
            expect_arity(builtin, 3, args.len(), span)?;
            let nty = numeric_ty_from(builtin, arg_tys[0], 0, span)?;
            // Validate the other two are the same numeric type.
            for (idx, &t) in arg_tys.iter().enumerate().skip(1) {
                let other = numeric_ty_from(builtin, t, idx as u8, span)?;
                if other != nty {
                    return Err(LoweringError::BuiltinOperandMismatch {
                        builtin,
                        lhs_ty: nty.cg_ty(),
                        rhs_ty: other.cg_ty(),
                        span,
                    });
                }
            }
            add(
                ctx,
                CgExpr::Builtin {
                    fn_id: BuiltinId::Clamp(nty),
                    args: arg_ids,
                    ty: nty.cg_ty(),
                },
                span,
            )
        }
        Builtin::SaturatingAdd => lower_pairwise_numeric(
            builtin,
            BuiltinIdCtor::SaturatingAdd,
            &arg_ids,
            &arg_tys,
            args,
            span,
            ctx,
        ),
        Builtin::Vec3 => {
            // `vec3(x, y, z)` — three F32 operands → Vec3F32 result.
            // BuiltinId::Vec3Ctor's signature() enforces the operand
            // types at type-check time; the lowering just records the
            // CgExpr::Builtin shape with the three arg ids.
            expect_arity(builtin, 3, args.len(), span)?;
            for (idx, arg_ty) in arg_tys.iter().enumerate() {
                if *arg_ty != CgTy::F32 {
                    return Err(LoweringError::Vec3RequiresF32 {
                        component_index: idx as u8,
                        got: *arg_ty,
                        span,
                    });
                }
            }
            add(
                ctx,
                CgExpr::Builtin {
                    fn_id: BuiltinId::Vec3Ctor,
                    args: arg_ids,
                    ty: CgTy::Vec3F32,
                },
                span,
            )
        }
        Builtin::F32Cast => lower_numeric_cast(
            builtin,
            CgTy::F32,
            BuiltinId::AsF32,
            &arg_ids,
            &arg_tys,
            args,
            span,
            ctx,
        ),
        Builtin::U32Cast => lower_numeric_cast(
            builtin,
            CgTy::U32,
            BuiltinId::AsU32,
            &arg_ids,
            &arg_tys,
            args,
            span,
            ctx,
        ),
        Builtin::I32Cast => lower_numeric_cast(
            builtin,
            CgTy::I32,
            BuiltinId::AsI32,
            &arg_ids,
            &arg_tys,
            args,
            span,
            ctx,
        ),
        // Plan G G3f (2026-05-09) — `threats.<method>(...)` scoring
        // primitives. Today's lowering emits sentinel literals; the
        // threats materialised view (G3g, future) wires the per-cell
        // walk that produces the real aggregates. The Builtin surface
        // is the load-bearing piece for this slice — the WGSL behaviour
        // is downstream (see `docs/plans/g3_threats_view_design.md`
        // "Estimated work breakdown" entry G3g).
        //
        // Arity / arg lowering already validated + executed above so
        // any type errors in the arg surface here, even though the
        // arg id itself is discarded (the stub doesn't consume it).
        // Plan G G3f wire-up — when the .sim defines a view named
        // "threats", route the Builtin to a ViewCall against it
        // (typed read of `view_storage_threats[self_id]`). When no
        // such view is defined, fall through to the sentinel literal
        // — graceful degradation so .sim files that don't use the
        // threats infrastructure still parse + lower without
        // declaring an unused view.
        //
        // The MVP read shape: arg 0 is taken as the agent slot index
        // (already lowered above into `arg_ids[0]` via the
        // expect_arity validation pass). For ThreatsIntensityAt the
        // arg is conceptually a `pos`, but today the threats view is
        // per-AGENT keyed (scalar f32 count per observer), so we
        // pass the caller's `self` slot through to the read. When
        // the threats view grows a position-keyed (struct payload +
        // per-cell distance) shape (G3 follow-up), the lowering
        // here updates to actually hash pos → ring slot.
        Builtin::ThreatsInZone => {
            expect_arity(builtin, 1, args.len(), span)?;
            match find_threats_view_id(ctx) {
                Some(view_id) => {
                    let arg_id = lower_expr(&args[0].value, ctx)?;
                    add(
                        ctx,
                        CgExpr::Builtin {
                            fn_id: BuiltinId::ViewCall { view: view_id },
                            args: vec![arg_id],
                            ty: CgTy::Bool,
                        },
                        span,
                    )
                }
                None => add(ctx, CgExpr::Lit(LitValue::Bool(false)), span),
            }
        }
        Builtin::ThreatsIntensityAt => {
            expect_arity(builtin, 1, args.len(), span)?;
            match find_threats_view_id(ctx) {
                Some(view_id) => {
                    let arg_id = lower_expr(&args[0].value, ctx)?;
                    add(
                        ctx,
                        CgExpr::Builtin {
                            fn_id: BuiltinId::ViewCall { view: view_id },
                            args: vec![arg_id],
                            ty: CgTy::F32,
                        },
                        span,
                    )
                }
                None => add(ctx, CgExpr::Lit(LitValue::F32(0.0)), span),
            }
        }
        Builtin::ThreatsNearest => {
            expect_arity(builtin, 1, args.len(), span)?;
            // Plan G G3f follow-up — the ring-walk argmin over struct
            // cells lands here. Lower to a typed
            // `BuiltinId::ThreatsNearest { view }` so the WGSL helper
            // (`compose_view_storage_prelude`) can emit a distinct
            // signature returning `u32` (AgentId). Falls back to the
            // sentinel if either (a) no threats view is declared, or
            // (b) the threats view doesn't have @per_entity_ring +
            // struct ViewLayout — the helper's body needs the per-cell
            // walk, which is undefined for scalar-payload views.
            match find_threats_view_id(ctx) {
                Some(view_id) => {
                    let arg_id = lower_expr(&args[0].value, ctx)?;
                    add(
                        ctx,
                        CgExpr::Builtin {
                            fn_id: BuiltinId::ThreatsNearest { view: view_id },
                            args: vec![arg_id],
                            ty: CgTy::AgentId,
                        },
                        span,
                    )
                }
                None => add(ctx, CgExpr::Lit(LitValue::AgentId(0)), span),
            }
        }
        Builtin::ThreatsDirAwayFromNearest => {
            expect_arity(builtin, 1, args.len(), span)?;
            // Plan G G3f follow-up — sibling of ThreatsNearest. Same
            // argmin pass over the struct-cell ring; returns the unit
            // vector pointing AWAY from the closest cell's center for
            // direct use as a flee velocity. Falls back to the
            // (0,0,0) sentinel when no threats view is declared so
            // fixtures without the surface stay no-op.
            match find_threats_view_id(ctx) {
                Some(view_id) => {
                    let arg_id = lower_expr(&args[0].value, ctx)?;
                    add(
                        ctx,
                        CgExpr::Builtin {
                            fn_id: BuiltinId::ThreatsDirAwayFromNearest { view: view_id },
                            args: vec![arg_id],
                            ty: CgTy::Vec3F32,
                        },
                        span,
                    )
                }
                None => add(
                    ctx,
                    CgExpr::Lit(LitValue::Vec3F32 { x: 0.0, y: 0.0, z: 0.0 }),
                    span,
                ),
            }
        }
        Builtin::NextWaypoint => {
            expect_arity(builtin, 1, args.len(), span)?;
            // Placeholder: returns a sentinel `vec3(0,0,0)` until a
            // real quest/landmark/waypoint runtime lands. The
            // `crowd_navigation.sim` design-target fixture uses this
            // in `physics PickNewGroupGoal` to stub out goal selection
            // for travel parties; lowering as a sentinel preserves
            // structural emit while leaving behavioural correctness
            // for a later pass.
            add(
                ctx,
                CgExpr::Lit(LitValue::Vec3F32 { x: 0.0, y: 0.0, z: 0.0 }),
                span,
            )
        }
        // Already filtered above.
        Builtin::Forall | Builtin::Exists | Builtin::Count | Builtin::Sum => {
            unreachable!("filtered earlier in lower_builtin_call")
        }
    }
}

/// Lower an explicit numeric cast (`f32(x)` / `u32(x)` / `i32(x)`).
///
/// All three share the same shape: arity 1, source must be a different
/// numeric type than the target (no-op casts are rejected so authors
/// don't accidentally mask a type-inference mistake), result type is
/// the target. Lowers to `CgExpr::Builtin { fn_id: AsF32 | AsU32 |
/// AsI32 }` per the `id_ctor` callback.
#[allow(clippy::too_many_arguments)]
fn lower_numeric_cast(
    builtin: Builtin,
    target: CgTy,
    id_ctor: fn(NumericTy) -> BuiltinId,
    arg_ids: &[CgExprId],
    arg_tys: &[CgTy],
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    expect_arity(builtin, 1, args.len(), span)?;
    let src_ty = arg_tys[0];
    let src = match src_ty {
        CgTy::F32 => NumericTy::F32,
        CgTy::U32 => NumericTy::U32,
        CgTy::I32 => NumericTy::I32,
        _ => {
            return Err(LoweringError::CastNonNumericOperand {
                target,
                got: src_ty,
                span,
            });
        }
    };
    if src.cg_ty() == target {
        return Err(LoweringError::CastNoOp { target, span });
    }
    add(
        ctx,
        CgExpr::Builtin {
            fn_id: id_ctor(src),
            args: arg_ids.to_vec(),
            ty: target,
        },
        span,
    )
}

/// Tag distinguishing the three pairwise-numeric AST builtins that
/// share the same lowering shape. Only used inside
/// `lower_pairwise_numeric`.
enum BuiltinIdCtor {
    Min,
    Max,
    SaturatingAdd,
}

impl BuiltinIdCtor {
    fn build(&self, t: NumericTy) -> BuiltinId {
        match self {
            BuiltinIdCtor::Min => BuiltinId::Min(t),
            BuiltinIdCtor::Max => BuiltinId::Max(t),
            BuiltinIdCtor::SaturatingAdd => BuiltinId::SaturatingAdd(t),
        }
    }
}

fn lower_pairwise_numeric(
    builtin: Builtin,
    ctor: BuiltinIdCtor,
    arg_ids: &[CgExprId],
    arg_tys: &[CgTy],
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    expect_arity(builtin, 2, args.len(), span)?;
    let nty_lhs = numeric_ty_from(builtin, arg_tys[0], 0, span)?;
    let nty_rhs = numeric_ty_from(builtin, arg_tys[1], 1, span)?;
    if nty_lhs != nty_rhs {
        return Err(LoweringError::BuiltinOperandMismatch {
            builtin,
            lhs_ty: nty_lhs.cg_ty(),
            rhs_ty: nty_rhs.cg_ty(),
            span,
        });
    }
    let fn_id = ctor.build(nty_lhs);
    add(
        ctx,
        CgExpr::Builtin {
            fn_id,
            args: arg_ids.to_vec(),
            ty: nty_lhs.cg_ty(),
        },
        span,
    )
}

fn numeric_ty_from(
    builtin: Builtin,
    ty: CgTy,
    operand_index: u8,
    span: Span,
) -> Result<NumericTy, LoweringError> {
    match ty {
        CgTy::F32 => Ok(NumericTy::F32),
        CgTy::U32 => Ok(NumericTy::U32),
        CgTy::I32 => Ok(NumericTy::I32),
        _ => Err(LoweringError::NumericBuiltinNonNumericOperand {
            builtin,
            operand_index,
            got: ty,
            span,
        }),
    }
}

fn expect_arity(
    builtin: Builtin,
    expected: u8,
    got: usize,
    span: Span,
) -> Result<(), LoweringError> {
    if got as u8 == expected {
        Ok(())
    } else {
        Err(LoweringError::BuiltinArityMismatch {
            builtin,
            expected,
            got: got as u8,
            span,
        })
    }
}

/// Lower a `view::<name>(args)` call into a `CgExpr::Builtin { fn_id:
/// ViewCall { view }, .. }`. Result type is fetched from
/// `ctx.view_signatures` if registered; otherwise falls back to
/// `ViewKey { view }` (Phase 1's chosen phantom) and the type checker
/// surfaces an unresolved-signature error if a downstream consumer
/// requires the concrete shape.
/// `<ring_view_name>.<field_name>(key, index)` — the read side of
/// `@per_entity_ring` struct-payload storage. Requires:
///   - the view resolves and its storage hint is `PerEntityRing { k }`
///     (checked against `ctx.view_storage_hints`, populated by the
///     driver for every view before ANY physics/verb body lowers —
///     `lower_all_views` runs before `lower_all_physics`, so this is
///     always present by the time a consumer reaches here);
///   - the view has a registered struct-cell `ViewLayout` (populated by
///     THAT SAME view's own `self.append(...)` lowering, which — same
///     ordering guarantee — has already run);
///   - `field` names one of that layout's fields;
///   - exactly 2 args (`key`, `index`).
/// Lowers to `BuiltinId::RingFieldRead`, which resolves the exact
/// storage index (`key * k + (index % k)) * field_count + field_offset`)
/// at WGSL-emit time — mirroring the write side's own
/// `self.append(...)` indexing (`fold_recent_damage_records.wgsl`)
/// exactly, so a read and a write of the same cell never disagree
/// about layout.
fn lower_ring_field_read(
    ast_ref: AstViewRef,
    field: &str,
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    let view_id = *ctx
        .view_ids
        .get(&ast_ref)
        .ok_or(LoweringError::UnknownView { ast_ref, span })?;

    let k = match ctx.view_storage_hints.get(&view_id) {
        Some(crate::cg::program::CgStorageHint::PerEntityRing { k }) => *k,
        Some(crate::cg::program::CgStorageHint::PairMap) => {
            return Err(LoweringError::RingFieldReadRequiresPerEntityRing {
                view: view_id,
                hint_label: "pair_map",
                span,
            });
        }
        Some(crate::cg::program::CgStorageHint::SingleKey) | None => {
            return Err(LoweringError::RingFieldReadRequiresPerEntityRing {
                view: view_id,
                hint_label: "single_key (per_entity_topk / symmetric_pair_topk / lazy_cached)",
                span,
            });
        }
    };

    let layout = ctx.builder.view_layout(view_id).ok_or(LoweringError::RingFieldReadOnScalarRing {
        view: view_id,
        span,
    })?;
    let field_count = layout.fields.len();
    let (field_offset, field_ty) = layout
        .fields
        .iter()
        .position(|f| f.name == field)
        .map(|pos| (pos, layout.fields[pos].ty))
        .ok_or_else(|| LoweringError::RingFieldReadUnknownField {
            view: view_id,
            field: field.to_string(),
            known_fields: layout.fields.iter().map(|f| f.name.clone()).collect(),
            span,
        })?;

    if args.len() != 2 {
        return Err(LoweringError::RingFieldReadArityMismatch {
            view: view_id,
            field: field.to_string(),
            got: args.len(),
            span,
        });
    }
    let key_id = lower_expr(&args[0].value, ctx)?;
    let index_id = lower_expr(&args[1].value, ctx)?;

    add(
        ctx,
        CgExpr::Builtin {
            fn_id: BuiltinId::RingFieldRead {
                view: view_id,
                field_offset: field_offset as u16,
                field_count: field_count as u16,
                k,
                result_ty: field_ty,
            },
            args: vec![key_id, index_id],
            ty: field_ty,
        },
        span,
    )
}

fn lower_view_call(
    ast_ref: AstViewRef,
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    let view_id = *ctx
        .view_ids
        .get(&ast_ref)
        .ok_or(LoweringError::UnknownView { ast_ref, span })?;

    // Lazy-view inlining (Task 5.5c). When the driver registered a
    // body snapshot for this view_id, substitute the body directly
    // at the call site instead of emitting a `BuiltinId::ViewCall`.
    // This sidesteps the `BuiltinSignature::ViewCall` type-check
    // path for lazy views entirely — `view_signatures` only needs
    // entries for materialized views (which still lower as
    // `BuiltinId::ViewCall`).
    if let Some(snapshot) = ctx.lazy_view_bodies.get(&view_id).cloned() {
        if snapshot.param_locals.len() != args.len() {
            return Err(LoweringError::ViewCallArityMismatch {
                view: view_id,
                expected: snapshot.param_locals.len(),
                got: args.len(),
                span,
            });
        }
        // Build the binder map: i-th param's LocalRef → i-th arg's IrExprNode.
        let mut binder_map: HashMap<LocalRef, IrExprNode> = HashMap::new();
        for (param_local, call_arg) in snapshot.param_locals.iter().zip(args.iter()) {
            binder_map.insert(*param_local, call_arg.value.clone());
        }
        // Substitute and lower the result.
        let substituted = substitute_locals(&snapshot.body, &binder_map);
        return lower_expr(&substituted, ctx);
    }

    // Wildcard short-circuit (Phase 6 Task 2.5): if any arg is a bare
    // wildcard `_`, the call is a per-unit-fold-over-all-candidates
    // shape that the current IR doesn't represent. Rather than thread
    // the wildcard through (which the type-checker rejects because the
    // wildcard's typed-default substitution doesn't match the view's
    // declared signature), short-circuit the whole view-call to a
    // type-appropriate zero literal. Same B1 semantic as the
    // PerUnit-with-wildcard short-circuit: empty view storage produces
    // 0; the call's result is 0.
    if args.iter().any(|a| is_wildcard_local(&a.value)) {
        let result_ty = ctx
            .view_signatures
            .get(&view_id)
            .map(|(_, r)| *r)
            .unwrap_or(CgTy::F32);
        let zero = match result_ty {
            CgTy::F32 => CgExpr::Lit(LitValue::F32(0.0)),
            CgTy::U32 => CgExpr::Lit(LitValue::U32(0)),
            CgTy::AgentId => CgExpr::Lit(LitValue::AgentId(0)),
            // Other typed defaults — fall through to F32(0) since views
            // historically return numeric scalars. ViewKey shouldn't
            // appear here (the registered-signature path returns a
            // concrete type).
            _ => CgExpr::Lit(LitValue::F32(0.0)),
        };
        return add(ctx, zero, span);
    }

    // Materialized-view path: lower as a typed `BuiltinId::ViewCall`.
    let mut arg_ids = Vec::with_capacity(args.len());
    for a in args {
        let id = lower_expr(&a.value, ctx)?;
        arg_ids.push(id);
    }
    // Result type — pulled from the context's signature registry, or
    // defaulted to `ViewKey { view }` when unregistered (matches the
    // Phase 1 phantom shape).
    let result_ty = ctx
        .view_signatures
        .get(&view_id)
        .map(|(_, r)| *r)
        .unwrap_or(CgTy::ViewKey { view: view_id });
    add(
        ctx,
        CgExpr::Builtin {
            fn_id: BuiltinId::ViewCall { view: view_id },
            args: arg_ids,
            ty: result_ty,
        },
        span,
    )
}

/// Walk `expr` and return a new `IrExprNode` where every
/// `IrExpr::Local(local_ref, _)` whose ref appears in `binders`
/// is replaced by `binders[&local_ref]`. Other shapes are walked
/// recursively (children re-built with their substituted forms).
/// Span is preserved from the original node at every level.
///
/// Used only by lazy-view inlining (Task 5.5c). The walk is
/// exhaustive over `IrExpr`; literal / tag / ability / belief
/// shapes that have no binder children are returned via clone
/// without descent.
fn substitute_locals(
    expr: &IrExprNode,
    binders: &HashMap<LocalRef, IrExprNode>,
) -> IrExprNode {
    let span = expr.span;
    let kind = match &expr.kind {
        IrExpr::Local(local_ref, _name) if binders.contains_key(local_ref) => {
            // Substituted node carries the *callsite arg's* span,
            // not the param-binder's span — that's deliberate: the
            // diagnostic span for "operand is wrong type" should
            // point at the call site's argument, not the view
            // parameter declaration.
            return binders[local_ref].clone();
        }
        IrExpr::Local(_, _) => expr.kind.clone(), // unbound local — pass through
        IrExpr::Field { base, field_name, field } => IrExpr::Field {
            base: Box::new(substitute_locals(base, binders)),
            field_name: field_name.clone(),
            field: *field,
        },
        IrExpr::Binary(op, l, r) => IrExpr::Binary(
            *op,
            Box::new(substitute_locals(l, binders)),
            Box::new(substitute_locals(r, binders)),
        ),
        IrExpr::Unary(op, a) => IrExpr::Unary(*op, Box::new(substitute_locals(a, binders))),
        IrExpr::If { cond, then_expr, else_expr } => IrExpr::If {
            cond: Box::new(substitute_locals(cond, binders)),
            then_expr: Box::new(substitute_locals(then_expr, binders)),
            else_expr: else_expr
                .as_ref()
                .map(|e| Box::new(substitute_locals(e, binders))),
        },
        IrExpr::BuiltinCall(b, args) => IrExpr::BuiltinCall(
            *b,
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: substitute_locals(&a.value, binders),
                    span: a.span,
                })
                .collect(),
        ),
        IrExpr::ViewCall(vr, args) => IrExpr::ViewCall(
            *vr,
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: substitute_locals(&a.value, binders),
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
                    value: substitute_locals(&a.value, binders),
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
                    value: substitute_locals(&a.value, binders),
                    span: a.span,
                })
                .collect(),
        },
        // Pass-through for shapes that carry no `IrExprNode` children
        // we need to descend through.
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
        | IrExpr::AbilityHint
        | IrExpr::AbilityHintLit(_)
        | IrExpr::AbilityRange
        | IrExpr::AbilityTag { .. }
        | IrExpr::Raw(_) => expr.kind.clone(),
        IrExpr::AbilityOnCooldown(inner) => {
            IrExpr::AbilityOnCooldown(Box::new(substitute_locals(inner, binders)))
        }
        IrExpr::BeliefsAccessor { observer, target, field } => IrExpr::BeliefsAccessor {
            observer: Box::new(substitute_locals(observer, binders)),
            target: Box::new(substitute_locals(target, binders)),
            field: field.clone(),
        },
        IrExpr::BeliefsConfidence { observer, target } => IrExpr::BeliefsConfidence {
            observer: Box::new(substitute_locals(observer, binders)),
            target: Box::new(substitute_locals(target, binders)),
        },
        IrExpr::BeliefsView { observer, view_name } => IrExpr::BeliefsView {
            observer: Box::new(substitute_locals(observer, binders)),
            view_name: view_name.clone(),
        },
        // Forms that *could* carry locals; descend into children.
        IrExpr::Index(base, idx) => IrExpr::Index(
            Box::new(substitute_locals(base, binders)),
            Box::new(substitute_locals(idx, binders)),
        ),
        IrExpr::VerbCall(vr, args) => IrExpr::VerbCall(
            *vr,
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: substitute_locals(&a.value, binders),
                    span: a.span,
                })
                .collect(),
        ),
        IrExpr::UnresolvedCall(name, args) => IrExpr::UnresolvedCall(
            name.clone(),
            args.iter()
                .map(|a| IrCallArg {
                    name: a.name.clone(),
                    value: substitute_locals(&a.value, binders),
                    span: a.span,
                })
                .collect(),
        ),
        IrExpr::In(l, r) => IrExpr::In(
            Box::new(substitute_locals(l, binders)),
            Box::new(substitute_locals(r, binders)),
        ),
        IrExpr::Contains(l, r) => IrExpr::Contains(
            Box::new(substitute_locals(l, binders)),
            Box::new(substitute_locals(r, binders)),
        ),
        IrExpr::List(items) => IrExpr::List(
            items.iter().map(|i| substitute_locals(i, binders)).collect(),
        ),
        IrExpr::Tuple(items) => IrExpr::Tuple(
            items.iter().map(|i| substitute_locals(i, binders)).collect(),
        ),
        // Quantifier / Fold / Match / StructLit / Ctor / PerUnit:
        // these introduce new binders that may shadow our map.
        // Real lazy view bodies don't exercise these today (the
        // canonical lazy views — is_hostile, is_stunned,
        // slow_factor — use only Field, BuiltinCall,
        // NamespaceCall, Binary, If, Lit). If a future lazy view
        // does, the substituter must extend `binders` with a
        // shadow-aware walk; until then, return the unchanged
        // form so a stray reference to an outer local is
        // visible to the failure path rather than silently
        // miscompiled. Documented as a known limitation.
        IrExpr::Quantifier { .. }
        | IrExpr::Fold { .. }
        | IrExpr::Match { .. }
        | IrExpr::StructLit { .. }
        | IrExpr::Ctor { .. }
        | IrExpr::PerUnit { .. } => expr.kind.clone(),
    };
    IrExprNode { kind, span }
}

/// Map a `dsl_ast::ir::IrType` to its `CgTy` representation. Used
/// by view-signature population (Task 5.5c). Falls back to
/// `CgTy::U32` for shapes the current CG IR doesn't surface; if
/// such a view's signature is consulted, the type checker will
/// surface a mismatch downstream rather than the registration
/// itself panicking.
pub(super) fn ir_type_to_cg_ty(ty: &dsl_ast::ir::IrType) -> CgTy {
    use dsl_ast::ir::IrType as T;
    match ty {
        T::Bool => CgTy::Bool,
        T::U8 | T::U16 | T::U32 => CgTy::U32,
        T::I8 | T::I16 | T::I32 => CgTy::I32,
        T::F32 => CgTy::F32,
        T::Vec3 => CgTy::Vec3F32,
        T::AgentId => CgTy::AgentId,
        // Entity references in the DSL surface as `Agent`, `Item`, etc.
        // — they're typed AgentId-equivalents at the IR layer (the
        // resolver maps the entity reference to its primary id type).
        // Without this arm, view signatures like `(a: Agent, b: Agent)`
        // would register as `(u32, u32)` via the fallthrough, then the
        // type-checker rejects calls like `view::X(self, target)`
        // because `self`/`target` lower to typed `AgentId`. (Phase 6
        // Task 2.5: surfaced when wildcard short-circuit unblocked the
        // type-check from running on real view-call sites.)
        T::EntityRef(_) => CgTy::AgentId,
        // Tick-typed fields go through CgTy::Tick at the read
        // layer; views don't return Tick today, but reserve the
        // mapping for symmetry.
        T::U64 | T::I64 | T::F64 => CgTy::U32, // narrowed (DSL surface is 32-bit)
        // Falls through for unsupported shapes — the type checker
        // will surface a mismatch when the registered signature
        // is consulted; the registration itself shouldn't panic.
        _ => CgTy::U32,
    }
}

/// Lower an `IrExpr::NamespaceCall`. Most stdlib namespace calls don't
/// produce a single `CgExpr` — they lower to op-level constructs
/// (`SpatialQuery`, `EventRing`, etc.). The two cases that do are:
///
/// * `rng.<purpose>()` — pure expression, becomes `CgExpr::Rng`.
/// * `agents.<field>(<expr>)` — read of an agent field whose target is
///   given by a sub-expression. The sub-expression must already lower
///   to an `AgentId`-typed `CgExpr`.
///
/// Lower a `count(<binder> in agents where <pred>)` or
/// `sum(<binder> in agents where <projection>)` fold to a
/// [`CgStmt::ForEachAgent`] (pushed onto `pending_pre_stmts`) plus a
/// [`CgExpr::ReadLocal`] reading the populated accumulator.
///
/// # Why this is N²
///
/// Today the loop walks every agent slot (`for i in 0..agent_cap`).
/// No spatial index, no early-out — each fold over `agents` runs in
/// O(N) per fold-evaluating thread, so a per-agent rule that contains
/// k folds runs in O(k · N) per agent and O(k · N²) per tick. Fine
/// for the boids fixture at thousand-scale agent counts; the
/// declared `spatial_query nearby_other` in `boids.sim` is the
/// future surface that will let this same DSL form lower to a
/// bounded walk over a spatial hash instead.
///
/// # Type rules
///
/// - **Sum**: the `body` is the projection. Its computed CG type is
///   the accumulator type; init is the type's zero literal. Today
///   I32 / F32 / Vec3F32 are supported (matching the `+` operator
///   coverage in `lower_binary`).
/// - **Count**: the `body` is the predicate (Bool-typed). The
///   accumulator is I32; the per-iteration projection is
///   `select(0i, 1i, body)` so the loop sums 1 for each true case.
///
/// # Source-level binder
///
/// `binder_name` is captured from `IrExpr::Fold::binder_name` (the
/// surface identifier) and pushed onto `ctx.fold_binder_name` for the
/// duration of the body lowering, so reads of `<binder>.<field>`
/// inside the body resolve via [`AgentRef::PerPairCandidate`].
/// Restored on return.
fn lower_fold_over_agents(
    kind: dsl_ast::ast::FoldKind,
    binder_name: Option<&str>,
    iter: Option<&IrExprNode>,
    body: &IrExprNode,
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    use dsl_ast::ast::FoldKind;

    let binder = binder_name.ok_or(LoweringError::UnsupportedAstNode {
        ast_label: "Fold (no binder)",
        span,
    })?;

    // Two recognised iter shapes:
    //
    // - `agents` — the unbounded N²-walk path lowered to
    //   `CgStmt::ForEachAgent`. Visits every alive agent slot.
    // - `spatial.<method>(self, ...)` — the bounded spatial-grid walk
    //   path lowered to `CgStmt::ForEachNeighbor`. Visits only the
    //   3³=27 cells surrounding the calling agent's cell. Today the
    //   `<method>` name is informational (any registered
    //   spatial_query is accepted); the cell-radius is hard-coded to
    //   1 because the runtime sizes its CELL_SIZE constant equal to
    //   the per-fixture perception radius. A future surface will
    //   thread the radius from the call args.
    //
    // Slice 2a (stdlib-into-CG-IR plan): the spatial-iter recognition
    // is delegated to `super::spatial::try_recognise_spatial_iter`
    // so mask / fold / future per-pair body-iter consumers all walk
    // the same shape table. The fold path uses just the `is this a
    // spatial iter?` boolean; the returned `SpatialIterShape`'s
    // radius_cells is consumed when the helper grows beyond the
    // hard-coded `1` (a future surface threads the radius from a
    // call arg).
    let spatial_iter_shape = match iter {
        None => None,
        Some(node) => match &node.kind {
            IrExpr::Namespace(NamespaceId::Agents) => None,
            IrExpr::NamespaceCall { ns: NamespaceId::Spatial, .. }
            | IrExpr::NamespaceCall { ns: NamespaceId::Query, .. } => {
                super::spatial::try_recognise_spatial_iter(node, ctx)?
            }
            _ => {
                return Err(LoweringError::UnsupportedAstNode {
                    ast_label: "Fold (iter is not `agents` or `spatial.<query>`)",
                    span,
                });
            }
        },
    };

    // Gap dungeon_horde#1: when the iter is a spatial namespace call,
    // lower its first arg as the origin agent expression so the WGSL
    // emit can substitute `agent_pos[<lowered>]` into the cell-window
    // centre + auto-injected distance gate instead of hard-coding
    // `agent_pos[agent_id]`. The lowering happens BEFORE pushing the
    // binder onto the fold-binder slot below so the origin expression
    // (which references the caller's scope, not the per-pair binder)
    // resolves correctly — `spatial.<...>(self)` becomes `AgentSelfId`
    // (WGSL `agent_id`); `spatial.<...>(s)` where `s` is event-bound
    // becomes a `ReadLocal` for that binding's lowered local.
    let spatial_origin_id = match (iter, &spatial_iter_shape) {
        (Some(node), Some(_)) => {
            if let IrExpr::NamespaceCall { args, .. } = &node.kind {
                if args.is_empty() {
                    return Err(LoweringError::UnsupportedAstNode {
                        ast_label: "Fold/spatial.<...>() — missing origin arg",
                        span,
                    });
                }
                Some(lower_expr(&args[0].value, ctx)?)
            } else {
                None
            }
        }
        _ => None,
    };

    // Push the binder onto the fold-binder slot so body reads of
    // `<binder>` / `<binder>.<field>` resolve to per-pair candidate.
    let prev_binder = ctx.fold_binder_name.replace(binder.to_string());

    // Lower the body. For Count, body is a Bool predicate; for Sum,
    // body is the projection (any numeric / vec type).
    let body_id = lower_expr(body, ctx)?;
    let body_ty = typecheck_node(ctx, body_id, span)?;

    // Build the (acc_ty, init, projection) triple per fold kind.
    let (acc_ty, init_id, projection_id) = match kind {
        FoldKind::Count => {
            // Count expects a Bool predicate. Reject otherwise.
            if body_ty != CgTy::Bool {
                ctx.fold_binder_name = prev_binder;
                return Err(LoweringError::TypeCheckFailure {
                    error: TypeError::ClaimedResultMismatch {
                        node: body_id,
                        expected: CgTy::Bool,
                        got: body_ty,
                    },
                    span,
                });
            }
            let zero = add(ctx, CgExpr::Lit(LitValue::I32(0)), span)?;
            let one = add(ctx, CgExpr::Lit(LitValue::I32(1)), span)?;
            let proj = add(
                ctx,
                CgExpr::Select {
                    cond: body_id,
                    then: one,
                    else_: zero,
                    ty: CgTy::I32,
                },
                span,
            )?;
            let init = add(ctx, CgExpr::Lit(LitValue::I32(0)), span)?;
            (CgTy::I32, init, proj)
        }
        FoldKind::Sum => {
            // Gap dungeon_stealth#2 (closed): Sum body inferred from the
            // arm types; `sum(... { 1u } else { 0u })` lowers to a u32
            // accumulator via `LitValue::U32(0)` init. The WGSL ForEachAgent
            // emit's `local_N = local_N + projection` works uniformly across
            // U32/I32/F32/Vec3F32 since `cg_ty_to_wgsl(U32)` returns `u32`
            // and `+` is the same WGSL operator at all four types.
            let init = match body_ty {
                CgTy::U32 => add(ctx, CgExpr::Lit(LitValue::U32(0)), span)?,
                CgTy::I32 => add(ctx, CgExpr::Lit(LitValue::I32(0)), span)?,
                CgTy::F32 => add(ctx, CgExpr::Lit(LitValue::F32(0.0)), span)?,
                CgTy::Vec3F32 => add(
                    ctx,
                    CgExpr::Lit(LitValue::Vec3F32 {
                        x: 0.0,
                        y: 0.0,
                        z: 0.0,
                    }),
                    span,
                )?,
                other => {
                    ctx.fold_binder_name = prev_binder;
                    return Err(LoweringError::TypeCheckFailure {
                        error: TypeError::ClaimedResultMismatch {
                            node: body_id,
                            expected: CgTy::F32,
                            got: other,
                        },
                        span,
                    });
                }
            };
            (body_ty, init, body_id)
        }
        FoldKind::Min | FoldKind::Max | FoldKind::Mean => {
            // Filtered out by the caller; defensive.
            ctx.fold_binder_name = prev_binder;
            return Err(LoweringError::UnsupportedAstNode {
                ast_label: "Fold (Min/Max/Mean)",
                span,
            });
        }
    };

    // Restore prior fold binder before exiting.
    ctx.fold_binder_name = prev_binder;

    // Allocate a fresh accumulator local. Pick max-existing + 1 over
    // both the AST-bound locals (`local_ids`) and the typed-local map
    // (`local_tys`) so the id is disjoint from both registries.
    let next_id = ctx
        .local_ids
        .values()
        .map(|id| id.0)
        .chain(ctx.local_tys.keys().map(|id| id.0))
        .max()
        .map(|m| m + 1)
        .unwrap_or(0);
    let acc_local = LocalId(next_id);
    ctx.record_local_ty(acc_local, acc_ty);

    // Push the fold loop onto pending pre-stmts so the surrounding
    // stmt-list driver injects it before the consumer of this fold's
    // result. Variant choice: spatial-iter folds become
    // ForEachNeighbor (bounded 27-cell walk); plain-`agents` folds
    // become ForEachAgent (unbounded N² walk).
    let stmt = if let Some(shape) = spatial_iter_shape {
        // `spatial_origin_id` is `Some` because the spatial-iter branch
        // above populates it whenever it returns `Some(shape)`. The
        // defensive `unwrap_or` here is unreachable in well-formed
        // input but lower-impact than a `.expect` panic — surfaces as
        // a structural assertion that the two branches stay in sync.
        let origin = spatial_origin_id.ok_or(LoweringError::UnsupportedAstNode {
            ast_label: "Fold/spatial.<...> — origin lowering desynced from shape",
            span,
        })?;
        CgStmt::ForEachNeighbor {
            acc_local,
            acc_ty,
            init: init_id,
            projection: projection_id,
            // Cell radius comes from the helper-recognised shape.
            // Today every shape returns 1 (CELL_SIZE matches each
            // fixture's perception radius, so a 3³ neighbourhood
            // covers it); when the helper threads call-arg radii
            // through, this picks up the new value automatically.
            radius_cells: shape.radius_cells,
            origin,
        }
    } else {
        CgStmt::ForEachAgent {
            acc_local,
            acc_ty,
            init: init_id,
            projection: projection_id,
        }
    };
    let stmt_id = ctx
        .builder
        .add_stmt(stmt)
        .map_err(|e| LoweringError::BuilderRejected { error: e, span })?;
    ctx.pending_pre_stmts.push(stmt_id);

    // Return a read of the accumulator. Consumers (Let, Assign,
    // Binary, …) pick this up as a normal CgExpr.
    add(
        ctx,
        CgExpr::ReadLocal {
            local: acc_local,
            ty: acc_ty,
        },
        span,
    )
}

/// Lower a `rng.<method>(...)` call to its CG IR shape.
///
/// Two surface flavours are recognised:
///
/// 1. **Internal nullary purposes** (`action`, `sample`, `shuffle`,
///    `conception`) — each lowers directly to a single
///    `CgExpr::Rng { purpose, ty: U32 }` node. These are the
///    lower-level surface used by the engine's per-stream
///    derivation; arity is enforced as 0.
///
/// 2. **Spec-named typed surfaces** (`uniform`, `gauss`, `coin`,
///    `uniform_int`) — match `docs/spec/dsl.md` §rng. Each addresses
///    a distinct deterministic stream (its own
///    [`RngPurpose`] variant, hashed from a unique purpose-byte tag
///    via `per_agent_u32`), so adding the typed surface does not
///    perturb existing fixtures that draw via the internal
///    purposes.
///
///    The IR shapes:
///    - `rng.coin()` → `CgExpr::Rng { Coin, Bool }` (nullary).
///    - `rng.uniform(lo, hi)` → `lo + draw * (hi - lo)` where
///      `draw = CgExpr::Rng { Uniform, F32 }` is a unit-interval
///      sample. WGSL emit converts the underlying `u32` draw to
///      `f32 / U32_MAX`.
///    - `rng.gauss(mu, sigma)` → `mu + draw * sigma` where
///      `draw = CgExpr::Rng { Gauss, F32 }` is a standard-normal
///      sample. WGSL emit performs the Box-Muller (or equivalent)
///      transform.
///    - `rng.uniform_int(lo, hi)` → `lo + draw % (hi - lo)` where
///      `draw = CgExpr::Rng { UniformInt, U32 }` is the raw u32
///      `per_agent_u32` draw. The signature is `(u32, u32) -> u32`
///      (Gap #C close, 2026-05-04 — the prior `(i32, i32) -> i32`
///      surface was unreachable from any `.sim` because the parser
///      has no i32 source). The result is in `[lo, hi)` modulo the
///      well-known modulo-bias.
///
/// Arity + arg-type errors surface as
/// [`LoweringError::NamespaceCallArityMismatch`] and
/// [`LoweringError::IllTypedExpression`] respectively, using the
/// same shape the surrounding namespace dispatch uses.
/// Look up the per-rule rng-call count for `purpose`, return it as the
/// `extra` value for the call's `CgExpr::Rng` node, and bump the
/// counter. First call of each purpose in a rule returns 0 (which
/// the WGSL emit renders as the bare `per_agent_u32(...)` form,
/// preserving every existing fixture's stream). Subsequent calls
/// return distinct values that route through `per_agent_u32_with_extra`.
fn bump_rng_extra(ctx: &mut LoweringCtx<'_>, purpose: RngPurpose) -> u32 {
    let n = ctx.rng_purpose_count.entry(purpose).or_insert(0);
    let extra = *n;
    *n += 1;
    extra
}

fn lower_rng_call(
    method: &str,
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    // Internal purposes — nullary, returning u32.
    let internal_purpose = match method {
        "action" => Some(RngPurpose::Action),
        "sample" => Some(RngPurpose::Sample),
        "shuffle" => Some(RngPurpose::Shuffle),
        "conception" => Some(RngPurpose::Conception),
        _ => None,
    };
    if let Some(purpose) = internal_purpose {
        if !args.is_empty() {
            return Err(LoweringError::NamespaceCallArityMismatch {
                ns: NamespaceId::Rng,
                method: method.to_string(),
                expected: 0,
                got: args.len(),
                span,
            });
        }
        let extra = bump_rng_extra(ctx, purpose);
        return add(
            ctx,
            CgExpr::Rng {
                purpose,
                extra,
                ty: CgTy::U32,
            },
            span,
        );
    }

    // Spec-named purposes — each is shape-specific.
    match method {
        // `rng.coin()` — nullary; returns bool. The IR node carries
        // the typed `Bool` result; the WGSL emitter is responsible
        // for the `(per_agent_u32(...) & 1u) == 0u` shape.
        "coin" => {
            if !args.is_empty() {
                return Err(LoweringError::NamespaceCallArityMismatch {
                    ns: NamespaceId::Rng,
                    method: method.to_string(),
                    expected: 0,
                    got: args.len(),
                    span,
                });
            }
            let extra = bump_rng_extra(ctx, RngPurpose::Coin);
            add(
                ctx,
                CgExpr::Rng {
                    purpose: RngPurpose::Coin,
                    extra,
                    ty: CgTy::Bool,
                },
                span,
            )
        }
        // `rng.uniform(lo, hi)` — `(f32, f32) -> f32`.
        // Lowered to `lo + draw * (hi - lo)` where `draw` is a
        // unit-interval sample on the `Uniform` stream.
        "uniform" => lower_rng_scaled_f32(
            method,
            args,
            span,
            ctx,
            RngPurpose::Uniform,
            ScaleShape::AffineLoHi,
        ),
        // `rng.gauss(mu, sigma)` — `(f32, f32) -> f32`. Lowered to
        // `mu + draw * sigma` where `draw` is a standard-normal
        // sample on the `Gauss` stream.
        "gauss" => lower_rng_scaled_f32(
            method,
            args,
            span,
            ctx,
            RngPurpose::Gauss,
            ScaleShape::MeanStddev,
        ),
        // `rng.uniform_int(lo, hi)` — `(u32, u32) -> u32`. Lowered
        // to `lo + draw % (hi - lo)` where `draw` is the raw
        // `per_agent_u32` u32 on the `UniformInt` stream. The u32
        // signature was picked at the Gap #C close (stdlib_math_probe,
        // 2026-05-04) because the DSL has no i32 source surface
        // (no literal suffix, no cast); positive bare integer
        // literals lower to `LitValue::U32` so `rng.uniform_int(0, 4)`
        // typechecks straight through.
        "uniform_int" => lower_rng_uniform_int(method, args, span, ctx),
        _ => Err(LoweringError::UnsupportedNamespaceCall {
            ns: NamespaceId::Rng,
            method: method.to_string(),
            span,
        }),
    }
}

/// Variants of the `lo + draw * scale(lo, hi)` shape used by
/// `rng.uniform` (`scale = hi - lo`) and `rng.gauss`
/// (`scale = sigma`, `lo = mu`). Encoded as an enum so the shared
/// helper picks one closed-form per call.
enum ScaleShape {
    /// `rng.uniform(lo, hi)`: result = `lo + draw * (hi - lo)`.
    AffineLoHi,
    /// `rng.gauss(mu, sigma)`: result = `mu + draw * sigma`.
    MeanStddev,
}

/// Shared lowering for `rng.uniform(lo, hi)` and `rng.gauss(mu,
/// sigma)`. Both surfaces take 2 `f32` args and produce `f32`; the
/// difference is the inner expression that scales the unit-stream
/// draw. The `ScaleShape` discriminator selects:
///
///   - `AffineLoHi` — `lo + draw * (hi - lo)` (uniform).
///   - `MeanStddev` — `mu + draw * sigma` (gauss).
fn lower_rng_scaled_f32(
    method: &str,
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
    purpose: RngPurpose,
    shape: ScaleShape,
) -> Result<CgExprId, LoweringError> {
    if args.len() != 2 {
        return Err(LoweringError::NamespaceCallArityMismatch {
            ns: NamespaceId::Rng,
            method: method.to_string(),
            expected: 2,
            got: args.len(),
            span,
        });
    }
    let lhs_id = lower_expr(&args[0].value, ctx)?;
    let rhs_id = lower_expr(&args[1].value, ctx)?;
    // Both args must be f32. AgentId / U32 reject; the user can
    // explicitly cast at the surface (no implicit coercion in the IR).
    for (id, arg) in [(lhs_id, &args[0]), (rhs_id, &args[1])] {
        let ty = typecheck_node(ctx, id, arg.span)?;
        if ty != CgTy::F32 {
            return Err(LoweringError::IllTypedExpression {
                expected: CgTy::F32,
                got: ty,
                span: arg.span,
            });
        }
    }
    // Build `draw = CgExpr::Rng { purpose, F32 }`.
    let extra = bump_rng_extra(ctx, purpose);
    let draw_id = add(
        ctx,
        CgExpr::Rng {
            purpose,
            extra,
            ty: CgTy::F32,
        },
        span,
    )?;
    // Inner scale factor depends on the shape:
    //   AffineLoHi → hi - lo
    //   MeanStddev → sigma   (`rhs_id` directly)
    let scale_id = match shape {
        ScaleShape::AffineLoHi => add(
            ctx,
            CgExpr::Binary {
                op: BinaryOp::SubF32,
                lhs: rhs_id,
                rhs: lhs_id,
                ty: CgTy::F32,
            },
            span,
        )?,
        ScaleShape::MeanStddev => rhs_id,
    };
    // `draw * scale`.
    let scaled_id = add(
        ctx,
        CgExpr::Binary {
            op: BinaryOp::MulF32,
            lhs: draw_id,
            rhs: scale_id,
            ty: CgTy::F32,
        },
        span,
    )?;
    // `lo + draw * scale` (or `mu + draw * sigma`).
    add(
        ctx,
        CgExpr::Binary {
            op: BinaryOp::AddF32,
            lhs: lhs_id,
            rhs: scaled_id,
            ty: CgTy::F32,
        },
        span,
    )
}

/// Lower `rng.uniform_int(lo, hi)`. Surface signature is
/// `(u32, u32) -> u32` (Gap #C close, 2026-05-04). The IR shape is
/// `lo + draw % (hi - lo)` where `draw` is the raw `per_agent_u32`
/// u32 (encoded by `RngPurpose::UniformInt` carrying `CgTy::U32`).
/// The result is in `[lo, hi)` with the standard modulo-bias for
/// ranges that don't divide `2^32` evenly; this is documented
/// behavior. The u32 signature was picked over the previous
/// `(i32, i32) -> i32` because the DSL has no i32 source surface —
/// see the gap report at
/// `docs/superpowers/notes/2026-05-04-stdlib_math_probe.md` §Gap #C.
fn lower_rng_uniform_int(
    method: &str,
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    if args.len() != 2 {
        return Err(LoweringError::NamespaceCallArityMismatch {
            ns: NamespaceId::Rng,
            method: method.to_string(),
            expected: 2,
            got: args.len(),
            span,
        });
    }
    let lo_id = lower_expr(&args[0].value, ctx)?;
    let hi_id = lower_expr(&args[1].value, ctx)?;
    for (id, arg) in [(lo_id, &args[0]), (hi_id, &args[1])] {
        let ty = typecheck_node(ctx, id, arg.span)?;
        if ty != CgTy::U32 {
            return Err(LoweringError::IllTypedExpression {
                expected: CgTy::U32,
                got: ty,
                span: arg.span,
            });
        }
    }
    // `draw = CgExpr::Rng { UniformInt, U32 }`.
    let extra = bump_rng_extra(ctx, RngPurpose::UniformInt);
    let draw_id = add(
        ctx,
        CgExpr::Rng {
            purpose: RngPurpose::UniformInt,
            extra,
            ty: CgTy::U32,
        },
        span,
    )?;
    // `hi - lo`.
    let range_id = add(
        ctx,
        CgExpr::Binary {
            op: BinaryOp::SubU32,
            lhs: hi_id,
            rhs: lo_id,
            ty: CgTy::U32,
        },
        span,
    )?;
    // `draw % (hi - lo)`.
    let mod_id = add(
        ctx,
        CgExpr::Binary {
            op: BinaryOp::ModU32,
            lhs: draw_id,
            rhs: range_id,
            ty: CgTy::U32,
        },
        span,
    )?;
    // `lo + draw % (hi - lo)`.
    add(
        ctx,
        CgExpr::Binary {
            op: BinaryOp::AddU32,
            lhs: lo_id,
            rhs: mod_id,
            ty: CgTy::U32,
        },
        span,
    )
}

/// All other namespace/method pairs surface as
/// [`LoweringError::UnsupportedNamespaceCall`] for now.
fn lower_namespace_call(
    ns: NamespaceId,
    method: &str,
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
) -> Result<CgExprId, LoweringError> {
    match (ns, method) {
        (NamespaceId::Rng, m) => lower_rng_call(m, args, span, ctx),
        (NamespaceId::Tables, m) => {
            // `tables.<name>(<idx_expr>)` — read a static lookup
            // table. Resolver registered the table in `ctx.tables`
            // (name → bounds-checked u32 values). Bake the values
            // into the CG node so the kernel emit can prepend a
            // `const <name>: array<u32, N> = …;` declaration without
            // a side-channel lookup.
            if args.len() != 1 {
                return Err(LoweringError::NamespaceCallArityMismatch {
                    ns,
                    method: m.to_string(),
                    expected: 1,
                    got: args.len(),
                    span,
                });
            }
            let values = match ctx.tables.get(m) {
                Some(v) => v.clone(),
                None => {
                    return Err(LoweringError::UnsupportedNamespaceCall {
                        ns,
                        method: m.to_string(),
                        span,
                    });
                }
            };
            let idx_expr = &args[0].value;
            let idx_id = lower_expr(idx_expr, ctx)?;
            let idx_ty = typecheck_node(ctx, idx_id, idx_expr.span)?;
            if !matches!(idx_ty, CgTy::U32 | CgTy::AgentId) {
                return Err(LoweringError::IllTypedExpression {
                    expected: CgTy::U32,
                    got: idx_ty,
                    span,
                });
            }
            add(
                ctx,
                CgExpr::TableLookup {
                    name: m.to_string(),
                    values,
                    index: idx_id,
                    ty: CgTy::U32,
                },
                span,
            )
        }
        // Plan H slice 3 — abilities.telegraph_kind(id) /
        // abilities.telegraph_param_0(id). Mirrors the AgentField
        // single-arg shape: lower the index expression, type-check it
        // as u32-or-AgentId (ability ids are u32 NonZero in the
        // registry), then emit a typed Builtin call. The WGSL helper
        // `ability_registry_telegraph_kind_at(id)` is auto-emitted by
        // `compose_view_storage_prelude` when the substring is
        // detected; the BGL composer body-scan in `cg/emit/kernel.rs`
        // adds the matching `ability_registry_telegraph_*` binding.
        (NamespaceId::Abilities, m) if args.len() == 1 && (m == "telegraph_kind" || m == "telegraph_param_0") => {
            let target_expr = &args[0].value;
            let target_id = lower_expr(target_expr, ctx)?;
            let target_ty = typecheck_node(ctx, target_id, target_expr.span)?;
            if !matches!(target_ty, CgTy::U32 | CgTy::AgentId) {
                return Err(LoweringError::IllTypedExpression {
                    expected: CgTy::U32,
                    got: target_ty,
                    span,
                });
            }
            let (fn_id, ty) = match m {
                "telegraph_kind" => (BuiltinId::AbilityTelegraphKind, CgTy::U32),
                "telegraph_param_0" => (BuiltinId::AbilityTelegraphParam0, CgTy::F32),
                _ => unreachable!("guard above narrowed to these two methods"),
            };
            add(
                ctx,
                CgExpr::Builtin {
                    fn_id,
                    args: vec![target_id],
                    ty,
                },
                span,
            )
        }
        (NamespaceId::Items, field) if args.len() == 1 => {
            // `items.<field>(<expr>)` — typed Item-field read where the
            // target slot is computed by `<expr>`. Resolves `<field>`
            // against the per-fixture entity-field catalog: each Item
            // declaration's field list is recorded by name + type, and
            // the lookup returns the (entity ref, slot, primitive type)
            // triple that fills the typed [`crate::cg::data_handle::ItemFieldId`].
            //
            // Currently each `<field>` name must be unique across all
            // Item entities in the program (one Item entity per field
            // name). The first match wins; a future ambiguity would
            // surface as a typed error here.
            let target_expr = &args[0].value;
            let target_id = lower_expr(target_expr, ctx)?;
            let target_ty = typecheck_node(ctx, target_id, target_expr.span)?;
            // Accept U32 / AgentId / ItemId — all are u32 at the IR
            // level. The catalog index is the literal value passed in.
            if !matches!(target_ty, CgTy::U32 | CgTy::AgentId) {
                return Err(LoweringError::IllTypedExpression {
                    expected: CgTy::U32,
                    got: target_ty,
                    span,
                });
            }
            let (entity_ref, slot, ty) = ctx
                .entity_field_catalog
                .resolve_item_by_name(field)
                .ok_or_else(|| LoweringError::UnsupportedNamespaceCall {
                    ns,
                    method: field.to_string(),
                    span,
                })?;
            let item_field_id = crate::cg::data_handle::ItemFieldId {
                entity: entity_ref,
                slot,
                ty,
            };
            let handle = DataHandle::ItemField {
                field: item_field_id,
                target: target_id,
            };
            let _ty = data_handle_ty(&handle);
            add(ctx, CgExpr::Read(handle), span)
        }
        (NamespaceId::Groups, field) if args.len() == 1 => {
            // `groups.<field>(<expr>)` — same shape as `items.<field>`
            // but resolves against the Group half of the catalog.
            let target_expr = &args[0].value;
            let target_id = lower_expr(target_expr, ctx)?;
            let target_ty = typecheck_node(ctx, target_id, target_expr.span)?;
            if !matches!(target_ty, CgTy::U32 | CgTy::AgentId) {
                return Err(LoweringError::IllTypedExpression {
                    expected: CgTy::U32,
                    got: target_ty,
                    span,
                });
            }
            let (entity_ref, slot, ty) = ctx
                .entity_field_catalog
                .resolve_group_by_name(field)
                .ok_or_else(|| LoweringError::UnsupportedNamespaceCall {
                    ns,
                    method: field.to_string(),
                    span,
                })?;
            let group_field_id = crate::cg::data_handle::GroupFieldId {
                entity: entity_ref,
                slot,
                ty,
            };
            let handle = DataHandle::GroupField {
                field: group_field_id,
                target: target_id,
            };
            let _ty = data_handle_ty(&handle);
            add(ctx, CgExpr::Read(handle), span)
        }
        (NamespaceId::Agents, field) if args.len() == 1 => {
            // `agents.<field>(<expr>)` — typed agent-field read where
            // the target slot is computed by `<expr>`. The DSL surfaces
            // this for cross-agent reads (`agents.hp(target)` etc.).
            //
            // **Registry-first dispatch**: if `(Agents, field)` is in
            // the namespace registry (e.g.
            // `agents.is_hostile_to(target)` registered as a
            // single-arg method returning bool), the registry path
            // wins. The agent-field read is the fallback for
            // unregistered method names that match an `AgentFieldId`.
            // This ordering means the registry is the source of truth
            // for the symbol surface; falling back to agent-field
            // resolution stays compatible with the DSL's existing
            // `agents.hp(target)` shape.
            if let Some(def) = ctx
                .namespace_registry
                .namespaces
                .get(&ns)
                .and_then(|nd| nd.methods.get(field))
            {
                return lower_registered_namespace_call(ns, field, args, span, ctx, def.clone());
            }
            let target_expr = &args[0].value;
            let target_id = lower_expr(target_expr, ctx)?;
            let target_ty = typecheck_node(ctx, target_id, target_expr.span)?;
            if target_ty != CgTy::AgentId {
                return Err(LoweringError::IllTypedExpression {
                    expected: CgTy::AgentId,
                    got: target_ty,
                    span,
                });
            }
            let field_id = AgentFieldId::from_snake(field).ok_or_else(|| {
                LoweringError::UnknownAgentField {
                    field_name: field.to_string(),
                    span,
                }
            })?;
            // Structural-folding optimisation: if `target_id` resolves
            // to a structural agent identifier (`PerPairCandidateId` /
            // `AgentSelfId`), collapse the `AgentRef::Target(<expr>)`
            // indirection to the matching structural variant directly.
            // The downstream WGSL emitter renders structural variants
            // with kernel-bound identifiers (`per_pair_candidate`,
            // `agent_id`) — no `target_expr_<N>` hoist needed. Without
            // this fold the scoring kernel emits a `target_expr_<N>`
            // identifier inside its row body that is never declared (the
            // hoist relies on a stmt wrapper the scoring emit doesn't
            // run), producing invalid WGSL — see Gap A in
            // `docs/superpowers/notes/2026-05-04-pair_scoring_probe.md`.
            let target_ref = match crate::cg::expr::ExprArena::get(
                ctx.builder.program(),
                target_id,
            ) {
                Some(CgExpr::PerPairCandidateId) => AgentRef::PerPairCandidate,
                Some(CgExpr::AgentSelfId) => AgentRef::Self_,
                _ => AgentRef::Target(target_id),
            };
            let handle = DataHandle::AgentField {
                field: field_id,
                target: target_ref,
            };
            // Sanity: the field's primitive type must round-trip
            // through `data_handle_ty` — otherwise `Read` wouldn't
            // produce a meaningful CgExpr.
            let _ty = data_handle_ty(&handle);
            add(ctx, CgExpr::Read(handle), span)
        }
        _ => {
            // Registry fallback: any `(ns, method)` pair registered in
            // `namespace_registry` lowers to `CgExpr::NamespaceCall` —
            // covers `agents.is_hostile_to`, `agents.engaged_with_or`,
            // `query.nearest_hostile_to_or`, and any future namespace
            // method whose schema is recorded in the registry.
            if let Some(def) = ctx
                .namespace_registry
                .namespaces
                .get(&ns)
                .and_then(|nd| nd.methods.get(method))
            {
                return lower_registered_namespace_call(ns, method, args, span, ctx, def.clone());
            }
            Err(LoweringError::UnsupportedNamespaceCall {
                ns,
                method: method.to_string(),
                span,
            })
        }
    }
}

/// Lower a registered namespace-method call to a typed
/// [`CgExpr::NamespaceCall`]. Validates arity against the registry
/// schema; arg types are not enforced here (the type checker already
/// validated each argument's claimed type). Used by both the
/// `(Agents, _)` and the catch-all arms of
/// [`lower_namespace_call`].
fn lower_registered_namespace_call(
    ns: NamespaceId,
    method: &str,
    args: &[IrCallArg],
    span: Span,
    ctx: &mut LoweringCtx<'_>,
    def: super::super::program::MethodDef,
) -> Result<CgExprId, LoweringError> {
    if args.len() != def.arg_tys.len() {
        return Err(LoweringError::NamespaceCallArityMismatch {
            ns,
            method: method.to_string(),
            expected: def.arg_tys.len(),
            got: args.len(),
            span,
        });
    }
    let mut arg_ids = Vec::with_capacity(args.len());
    for a in args {
        arg_ids.push(lower_expr(&a.value, ctx)?);
    }
    add(
        ctx,
        CgExpr::NamespaceCall {
            ns,
            method: method.to_string(),
            args: arg_ids,
            ty: def.return_ty,
        },
        span,
    )
}

/// Confirm `AgentFieldTy` doesn't have a closed-set match arm gap. The
/// primitive-type set is referenced indirectly via [`data_handle_ty`];
/// this helper isn't called from production code, but documents the
/// invariant the lowering depends on (every `AgentFieldTy` has a
/// non-`ViewKey` `CgTy` representation).
#[allow(dead_code)]
fn _agent_field_ty_invariant(t: AgentFieldTy) -> CgTy {
    match t {
        AgentFieldTy::F32 => CgTy::F32,
        AgentFieldTy::U32 => CgTy::U32,
        AgentFieldTy::I16 => CgTy::I32,
        AgentFieldTy::Bool => CgTy::Bool,
        AgentFieldTy::Vec3 => CgTy::Vec3F32,
        AgentFieldTy::EnumU8 => CgTy::U32,
        AgentFieldTy::OptAgentId => CgTy::AgentId,
        AgentFieldTy::OptEnumU32 => CgTy::U32,
    }
}

// ---------------------------------------------------------------------------
// Tests
// ---------------------------------------------------------------------------

#[cfg(test)]
mod tests {
    use super::*;
    use crate::cg::expr::pretty;
    use dsl_ast::ast::Span as AstSpan;
    use dsl_ast::ir::LocalRef;

    // ---- helpers ----

    fn span(start: usize, end: usize) -> AstSpan {
        AstSpan::new(start, end)
    }

    fn node(kind: IrExpr) -> IrExprNode {
        IrExprNode {
            kind,
            span: span(0, 0),
        }
    }

    fn arg(value: IrExprNode) -> IrCallArg {
        let s = value.span;
        IrCallArg {
            name: None,
            value,
            span: s,
        }
    }

    fn local_self() -> IrExprNode {
        node(IrExpr::Local(LocalRef(0), "self".to_string()))
    }

    fn field_self(name: &str) -> IrExprNode {
        node(IrExpr::Field {
            base: Box::new(local_self()),
            field_name: name.to_string(),
            field: None,
        })
    }

    fn lower_to_string(ast: &IrExprNode) -> Result<String, LoweringError> {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let id = lower_expr(ast, &mut ctx)?;
        let prog = builder.finish();
        let node = &prog.exprs[id.0 as usize];
        Ok(pretty(node, &prog.exprs))
    }

    // ---- Literals ----

    #[test]
    fn literal_bool_lowers() {
        let ast = node(IrExpr::LitBool(true));
        assert_eq!(lower_to_string(&ast).unwrap(), "(lit true)");
    }

    #[test]
    fn literal_int_positive_picks_u32() {
        let ast = node(IrExpr::LitInt(5));
        assert_eq!(lower_to_string(&ast).unwrap(), "(lit 5u32)");
    }

    #[test]
    fn literal_int_negative_picks_i32() {
        let ast = node(IrExpr::LitInt(-3));
        assert_eq!(lower_to_string(&ast).unwrap(), "(lit -3i32)");
    }

    #[test]
    fn literal_float_lowers_f32() {
        let ast = node(IrExpr::LitFloat(1.5));
        assert_eq!(lower_to_string(&ast).unwrap(), "(lit 1.5f32)");
    }

    #[test]
    fn literal_int_overflow_u32_rejected() {
        let v = (u32::MAX as i64) + 1;
        let ast = node(IrExpr::LitInt(v));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::LiteralOutOfRange { value, target, .. } => {
                assert_eq!(value, v);
                assert_eq!(target, CgTy::U32);
            }
            other => panic!("unexpected error: {other:?}"),
        }
    }

    #[test]
    fn literal_int_overflow_i32_rejected() {
        let v = (i32::MIN as i64) - 1;
        let ast = node(IrExpr::LitInt(v));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::LiteralOutOfRange { value, target, .. } => {
                assert_eq!(value, v);
                assert_eq!(target, CgTy::I32);
            }
            other => panic!("unexpected error: {other:?}"),
        }
    }

    // ---- Field access (the plan's `agent.hp` example) ----

    #[test]
    fn self_hp_lowers_to_read_agent_field() {
        let ast = field_self("hp");
        assert_eq!(lower_to_string(&ast).unwrap(), "(read agent.self.hp)");
    }

    #[test]
    fn self_pos_lowers_to_read_vec3_field() {
        let ast = field_self("pos");
        assert_eq!(lower_to_string(&ast).unwrap(), "(read agent.self.pos)");
    }

    #[test]
    fn self_alive_lowers_to_read_bool_field() {
        let ast = field_self("alive");
        assert_eq!(lower_to_string(&ast).unwrap(), "(read agent.self.alive)");
    }

    #[test]
    fn unknown_self_field_rejected() {
        // `nonexistent_field` is neither a real `AgentFieldId` nor a
        // virtual field synthesizer — must surface as
        // `UnknownAgentField`. (Historically this used `hp_pct`; that
        // name is now a virtual field synthesized to `hp / max_hp`,
        // covered by `self_hp_pct_synthesizes_hp_div_max_hp`.)
        let ast = field_self("nonexistent_field");
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::UnknownAgentField { field_name, .. } => {
                assert_eq!(field_name, "nonexistent_field");
            }
            other => panic!("unexpected: {other:?}"),
        }
    }

    // ---- Virtual fields (Task 8 of the cg-lowering gap-closure plan) ----

    #[test]
    fn self_hp_pct_synthesizes_hp_div_max_hp() {
        // `self.hp_pct` is a virtual field — no `AgentFieldId::HpPct`
        // exists. The lowering synthesizes `Read(Hp) / Read(MaxHp)`,
        // both targeting `AgentRef::Self_`.
        let ast = field_self("hp_pct");
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let id = lower_expr(&ast, &mut ctx).expect("hp_pct synthesizes");
        let prog = builder.finish();
        let root = &prog.exprs[id.0 as usize];
        // Pretty-printed canonical form: div.f32 of two agent-self reads.
        assert_eq!(
            pretty(root, &prog.exprs),
            "(div.f32 (read agent.self.hp) (read agent.self.max_hp))"
        );
        // And the typed shape — both reads must target Self_, not the
        // per-pair candidate.
        match root {
            CgExpr::Binary { op, lhs, rhs, ty } => {
                assert_eq!(*op, BinaryOp::DivF32);
                assert_eq!(*ty, CgTy::F32);
                match &prog.exprs[lhs.0 as usize] {
                    CgExpr::Read(DataHandle::AgentField { field, target }) => {
                        assert_eq!(*field, AgentFieldId::Hp);
                        assert_eq!(*target, AgentRef::Self_);
                    }
                    other => panic!("unexpected lhs: {other:?}"),
                }
                match &prog.exprs[rhs.0 as usize] {
                    CgExpr::Read(DataHandle::AgentField { field, target }) => {
                        assert_eq!(*field, AgentFieldId::MaxHp);
                        assert_eq!(*target, AgentRef::Self_);
                    }
                    other => panic!("unexpected rhs: {other:?}"),
                }
            }
            other => panic!("expected Binary, got {other:?}"),
        }
    }

    #[test]
    fn target_hp_pct_synthesizes_per_pair_hp_div_max_hp() {
        // Symmetry: in a pair-bound context, `target.hp_pct`
        // synthesizes the same Div, both reads tagged
        // `AgentRef::PerPairCandidate`.
        let ast = field_target("hp_pct");
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        ctx.target_local = true;
        let id = lower_expr(&ast, &mut ctx).expect("target.hp_pct synthesizes");
        let prog = builder.finish();
        let root = &prog.exprs[id.0 as usize];
        match root {
            CgExpr::Binary { op, lhs, rhs, ty } => {
                assert_eq!(*op, BinaryOp::DivF32);
                assert_eq!(*ty, CgTy::F32);
                match &prog.exprs[lhs.0 as usize] {
                    CgExpr::Read(DataHandle::AgentField { field, target }) => {
                        assert_eq!(*field, AgentFieldId::Hp);
                        assert_eq!(*target, AgentRef::PerPairCandidate);
                    }
                    other => panic!("unexpected lhs: {other:?}"),
                }
                match &prog.exprs[rhs.0 as usize] {
                    CgExpr::Read(DataHandle::AgentField { field, target }) => {
                        assert_eq!(*field, AgentFieldId::MaxHp);
                        assert_eq!(*target, AgentRef::PerPairCandidate);
                    }
                    other => panic!("unexpected rhs: {other:?}"),
                }
            }
            other => panic!("expected Binary, got {other:?}"),
        }
    }

    #[test]
    fn field_on_non_self_local_rejected() {
        let ast = node(IrExpr::Field {
            base: Box::new(node(IrExpr::Local(LocalRef(1), "target".to_string()))),
            field_name: "hp".to_string(),
            field: None,
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::UnsupportedFieldBase { .. }));
    }

    // ---- target.<field> binding (Task 5.5a) ----

    fn field_target(name: &str) -> IrExprNode {
        node(IrExpr::Field {
            base: Box::new(node(IrExpr::Local(LocalRef(1), "target".to_string()))),
            field_name: name.to_string(),
            field: None,
        })
    }

    #[test]
    fn target_field_with_target_local_lowers_to_per_pair_candidate_read() {
        // target.alive in a context where ctx.target_local is true
        // resolves to `Read(AgentField { target: PerPairCandidate, .. })`.
        let ast = field_target("alive");
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        ctx.target_local = true;
        let id = lower_expr(&ast, &mut ctx).expect("lowers");
        let prog = builder.finish();
        let node_at = &prog.exprs[id.0 as usize];
        // Expect: (read agent.per_pair_candidate.alive) under the
        // `pretty` pretty-printer.
        assert_eq!(
            pretty(node_at, &prog.exprs),
            "(read agent.per_pair_candidate.alive)"
        );
        // Confirm the typed handle shape exactly — Display goes through
        // the `agent.per_pair_candidate.<field>` form.
        match node_at {
            CgExpr::Read(DataHandle::AgentField { field, target }) => {
                assert_eq!(*field, AgentFieldId::Alive);
                assert_eq!(*target, AgentRef::PerPairCandidate);
            }
            other => panic!("unexpected lowered expr: {other:?}"),
        }
    }

    #[test]
    fn target_field_without_target_local_rejects_with_unsupported_field_base() {
        // Regression: outside a pair-bound context (`target_local =
        // false`, the default), `target.<field>` must NOT route through
        // `PerPairCandidate`. The lowering surfaces the same typed
        // deferral as any other unbound receiver.
        let ast = field_target("alive");
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        // ctx.target_local left false (the default).
        let err = lower_expr(&ast, &mut ctx).expect_err("must reject");
        match err {
            LoweringError::UnsupportedFieldBase { field_name, .. } => {
                assert_eq!(field_name, "alive");
            }
            other => panic!("expected UnsupportedFieldBase, got {other:?}"),
        }
    }

    #[test]
    fn target_field_unknown_name_under_target_local_rejects_with_unknown_agent_field() {
        // target.<bogus> in a target-bound context: the receiver is
        // now recognised, but the field name is neither a real
        // `AgentFieldId` nor a virtual field. The lowering surfaces
        // the same `UnknownAgentField` defect as the self-side case —
        // keeps the error surface symmetric. (Historically this used
        // `hp_pct`; that name is now a virtual field — see
        // `target_hp_pct_synthesizes_per_pair_hp_div_max_hp`.)
        let ast = field_target("nonexistent_field");
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        ctx.target_local = true;
        let err = lower_expr(&ast, &mut ctx).expect_err("must reject");
        match err {
            LoweringError::UnknownAgentField { field_name, .. } => {
                assert_eq!(field_name, "nonexistent_field");
            }
            other => panic!("expected UnknownAgentField, got {other:?}"),
        }
    }

    // ---- Let-bound AgentId local as field-access base ----
    //
    // Verb-cascade follow-up (Phase 7 / 2026-05-03): the verb expander
    // synthesises `physics verb_chronicle_<name> { on ActionSelected
    // { actor: <self_local>, action_id: …, target: <target_local> } {
    // emit Killed { … pos: self.pos } } }`. The handler body's
    // `self.pos` reference must address the actor's row, NOT the
    // implicit kernel-row identity. The fix routes a let-bound
    // `AgentId` local base through `AgentRef::Target(<expr>)` —
    // semantically identical to authoring `agents.<field>(<that_local>)`.

    /// Test helper: register `local_ref` as a let-bound local of type
    /// `AgentId`. Mirrors what `synthesize_pattern_binding_lets` does
    /// for an event-pattern binder.
    fn register_let_bound_agent_id_local(ctx: &mut LoweringCtx<'_>, local_ref: LocalRef) -> LocalId {
        let local_id = ctx.allocate_local(local_ref);
        ctx.record_local_ty(local_id, CgTy::AgentId);
        local_id
    }

    #[test]
    fn field_on_let_bound_agent_id_local_lowers_to_target_read() {
        // Verb cascade: `self` is a let-bound LocalRef from the event
        // binder (NOT the implicit `Self_` of the surrounding rule).
        // `self.pos` must lower to `Read(AgentField { field: Pos,
        // target: AgentRef::Target(<read_local>) })`.
        let self_ref = LocalRef(7);
        let ast = node(IrExpr::Field {
            base: Box::new(node(IrExpr::Local(self_ref, "self".to_string()))),
            field_name: "pos".to_string(),
            field: None,
        });
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let self_local_id = register_let_bound_agent_id_local(&mut ctx, self_ref);

        let id = lower_expr(&ast, &mut ctx).expect("self.pos lowers under let-bound binder");
        let prog = builder.finish();
        let root = &prog.exprs[id.0 as usize];
        match root {
            CgExpr::Read(DataHandle::AgentField { field, target }) => {
                assert_eq!(*field, AgentFieldId::Pos);
                match target {
                    AgentRef::Target(expr_id) => {
                        // The Target's expr_id must point at the
                        // ReadLocal of the let-bound binder — NOT a
                        // bare `AgentSelfId`.
                        match &prog.exprs[expr_id.0 as usize] {
                            CgExpr::ReadLocal { local, ty } => {
                                assert_eq!(*local, self_local_id);
                                assert_eq!(*ty, CgTy::AgentId);
                            }
                            other => panic!(
                                "AgentRef::Target inner expr expected ReadLocal, got {other:?}"
                            ),
                        }
                    }
                    other => panic!("expected AgentRef::Target, got {other:?}"),
                }
            }
            other => panic!("expected Read(AgentField), got {other:?}"),
        }
    }

    #[test]
    fn field_on_let_bound_target_local_lowers_to_target_read() {
        // Symmetry: a let-bound `target` AgentId local (also
        // synthesised by the verb expander's `target: <target_local>`
        // binder) routes the same way. This is independent of
        // `ctx.target_local` (the pair-bound flag) — the let-bound
        // arm fires first.
        let target_ref = LocalRef(11);
        let ast = node(IrExpr::Field {
            base: Box::new(node(IrExpr::Local(target_ref, "target".to_string()))),
            field_name: "hp".to_string(),
            field: None,
        });
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        // `ctx.target_local` left false — the let-bound arm wins
        // regardless of the pair-bound flag.
        register_let_bound_agent_id_local(&mut ctx, target_ref);

        let id = lower_expr(&ast, &mut ctx).expect("target.hp lowers under let-bound binder");
        let prog = builder.finish();
        let root = &prog.exprs[id.0 as usize];
        match root {
            CgExpr::Read(DataHandle::AgentField { field, target }) => {
                assert_eq!(*field, AgentFieldId::Hp);
                assert!(
                    matches!(target, AgentRef::Target(_)),
                    "expected AgentRef::Target, got {target:?}"
                );
            }
            other => panic!("expected Read(AgentField), got {other:?}"),
        }
    }

    #[test]
    fn field_on_let_bound_non_agent_id_local_rejected() {
        // A let-bound non-AgentId local (`let dist: f32 = …; dist.foo`)
        // has no field-access semantics — surface the same typed
        // deferral as any other unbound base.
        let dist_ref = LocalRef(3);
        let ast = node(IrExpr::Field {
            base: Box::new(node(IrExpr::Local(dist_ref, "dist".to_string()))),
            field_name: "anything".to_string(),
            field: None,
        });
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let dist_local_id = ctx.allocate_local(dist_ref);
        ctx.record_local_ty(dist_local_id, CgTy::F32);

        let err = lower_expr(&ast, &mut ctx).expect_err("non-AgentId local field-access rejects");
        assert!(
            matches!(err, LoweringError::UnsupportedFieldBase { .. }),
            "expected UnsupportedFieldBase, got {err:?}"
        );
    }

    #[test]
    fn field_on_let_bound_agent_id_local_virtual_field_synthesizes() {
        // Virtual field (`hp_pct`) on a let-bound AgentId local: the
        // synthesizer takes the resolved `AgentRef::Target(<expr>)` and
        // produces `<read>.hp / <read>.max_hp`, both reads tagged with
        // the same target.
        let actor_ref = LocalRef(5);
        let ast = node(IrExpr::Field {
            base: Box::new(node(IrExpr::Local(actor_ref, "self".to_string()))),
            field_name: "hp_pct".to_string(),
            field: None,
        });
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        register_let_bound_agent_id_local(&mut ctx, actor_ref);

        let id = lower_expr(&ast, &mut ctx).expect("self.hp_pct synthesizes under let-bound binder");
        let prog = builder.finish();
        let root = &prog.exprs[id.0 as usize];
        match root {
            CgExpr::Binary { op, lhs, rhs, ty } => {
                assert_eq!(*op, BinaryOp::DivF32);
                assert_eq!(*ty, CgTy::F32);
                // Both operands must be Reads tagged with the same
                // AgentRef::Target(<expr_id>) — i.e., they share the
                // actor's id, not the implicit Self_.
                let lhs_target = match &prog.exprs[lhs.0 as usize] {
                    CgExpr::Read(DataHandle::AgentField { field, target }) => {
                        assert_eq!(*field, AgentFieldId::Hp);
                        target.clone()
                    }
                    other => panic!("unexpected lhs: {other:?}"),
                };
                let rhs_target = match &prog.exprs[rhs.0 as usize] {
                    CgExpr::Read(DataHandle::AgentField { field, target }) => {
                        assert_eq!(*field, AgentFieldId::MaxHp);
                        target.clone()
                    }
                    other => panic!("unexpected rhs: {other:?}"),
                };
                assert_eq!(lhs_target, rhs_target);
                assert!(
                    matches!(lhs_target, AgentRef::Target(_)),
                    "expected AgentRef::Target on virtual-field operand, got {lhs_target:?}"
                );
            }
            other => panic!("expected Binary, got {other:?}"),
        }
    }

    #[test]
    fn field_on_fold_binder_local_skips_target_let_arm() {
        // Fold-binder exclusion: in a fold body, the source-level
        // binder (`other`) is registered in BOTH `ctx.local_ids` AND
        // `ctx.fold_binder_name`. The desired semantic is
        // `AgentRef::PerPairCandidate` (the per-pair loop variable),
        // not a Target-let read of the binder's value. Without the
        // exclusion, the WGSL emit would hoist `let target_expr_<N> =
        // per_pair_candidate;` ahead of the for-loop that binds
        // `per_pair_candidate` (use-before-def). This test asserts
        // the existing fold-binder arm wins for that name.
        let other_ref = LocalRef(13);
        let ast = node(IrExpr::Field {
            base: Box::new(node(IrExpr::Local(other_ref, "other".to_string()))),
            field_name: "pos".to_string(),
            field: None,
        });
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        // Mirror the fold-body lowering: register `other` in
        // `local_ids` AND set the fold-binder slot to its name.
        register_let_bound_agent_id_local(&mut ctx, other_ref);
        ctx.fold_binder_name = Some("other".to_string());

        let id = lower_expr(&ast, &mut ctx).expect("other.pos lowers under fold binder");
        let prog = builder.finish();
        let root = &prog.exprs[id.0 as usize];
        match root {
            CgExpr::Read(DataHandle::AgentField { field, target }) => {
                assert_eq!(*field, AgentFieldId::Pos);
                assert_eq!(*target, AgentRef::PerPairCandidate);
            }
            other => panic!("expected Read(AgentField, PerPairCandidate), got {other:?}"),
        }
    }

    #[test]
    fn field_on_bare_self_without_let_binding_still_routes_to_self_ref() {
        // Regression: in the absence of a let-binding for the local,
        // `self.<field>` continues to resolve to `AgentRef::Self_` —
        // the existing self-side fast path is untouched. Only the
        // verb-cascade case (let-bound `self`) takes the new arm.
        let ast = node(IrExpr::Field {
            base: Box::new(local_self()),
            field_name: "pos".to_string(),
            field: None,
        });
        let s = lower_to_string(&ast).expect("self.pos lowers without let-binding");
        assert_eq!(s, "(read agent.self.pos)");
    }

    // ---- The plan's specific rejection — `agent.alive < 5` ----

    #[test]
    fn agent_alive_lt_5_rejects_with_typed_error() {
        // agent.alive : Bool
        // 5            : U32
        // → mismatched binary operand types
        let ast = node(IrExpr::Binary(
            BinOp::Lt,
            Box::new(field_self("alive")),
            Box::new(node(IrExpr::LitInt(5))),
        ));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::BinaryOperandTyMismatch {
                op,
                lhs_ty,
                rhs_ty,
                ..
            } => {
                assert_eq!(op, BinOp::Lt);
                assert_eq!(lhs_ty, CgTy::Bool);
                assert_eq!(rhs_ty, CgTy::U32);
            }
            other => panic!("expected BinaryOperandTyMismatch, got {other:?}"),
        }
    }

    // ---- Signed/unsigned integer literal coercion ----

    /// `delta != 0` where `delta: i32` (event-field shape) and `0`
    /// defaults to `LitValue::U32` at lowering. The coercion in
    /// `lower_binary` should re-emit the literal as `I32` so the
    /// binary type-check accepts the shape.
    #[test]
    fn binary_i32_field_neq_u32_literal_coerces_literal_to_i32() {
        // self.slow_factor_q8 (i16 -> CgTy::I32) != 0
        let ast = node(IrExpr::Binary(
            BinOp::NotEq,
            Box::new(field_self("slow_factor_q8")),
            Box::new(node(IrExpr::LitInt(0))),
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s, "(ne.i32 (read agent.self.slow_factor_q8) (lit 0i32))",
            "expected i32-typed binary with literal coerced to I32, got {s:?}"
        );
    }

    /// Symmetric: literal on lhs, i32 read on rhs.
    #[test]
    fn binary_u32_literal_gt_i32_field_coerces_literal_to_i32() {
        // 0 > self.slow_factor_q8
        let ast = node(IrExpr::Binary(
            BinOp::Gt,
            Box::new(node(IrExpr::LitInt(0))),
            Box::new(field_self("slow_factor_q8")),
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s, "(gt.i32 (lit 0i32) (read agent.self.slow_factor_q8))",
            "expected i32-typed binary with lhs literal coerced to I32, got {s:?}"
        );
    }

    /// `delta > 0` (strict) — same i32-vs-u32 shape as the inequality
    /// case; verifies the `Gt` branch that surfaced in the
    /// post-Task-1 diagnostics.
    #[test]
    fn binary_i32_field_gt_u32_literal_coerces_literal_to_i32() {
        let ast = node(IrExpr::Binary(
            BinOp::Gt,
            Box::new(field_self("slow_factor_q8")),
            Box::new(node(IrExpr::LitInt(0))),
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s, "(gt.i32 (read agent.self.slow_factor_q8) (lit 0i32))"
        );
    }

    /// Two non-literal i32/u32 operands stay rejected — the
    /// coercion intentionally fires only when one side is a
    /// literal, so genuine field-vs-field mismatches surface as
    /// typing bugs.
    #[test]
    fn binary_i32_field_neq_u32_field_still_rejected_when_neither_is_literal() {
        // self.slow_factor_q8 (I32) != self.level (U32)
        let ast = node(IrExpr::Binary(
            BinOp::NotEq,
            Box::new(field_self("slow_factor_q8")),
            Box::new(field_self("level")),
        ));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::BinaryOperandTyMismatch {
                lhs_ty, rhs_ty, ..
            } => {
                assert_eq!(lhs_ty, CgTy::I32);
                assert_eq!(rhs_ty, CgTy::U32);
            }
            other => panic!("expected BinaryOperandTyMismatch, got {other:?}"),
        }
    }

    // ---- Implicit u32/i32 → f32 promotion (Gap #2 of pair_scoring probe) ----

    /// `1000.0 - self.level` (f32 lhs, u32 rhs) lowers to
    /// `1000.0 - f32(self.level)` — the rhs is wrapped in
    /// `BuiltinId::AsF32(U32)`, then the SubF32 op is picked.
    #[test]
    fn binary_f32_minus_u32_promotes_rhs_to_f32() {
        let ast = node(IrExpr::Binary(
            BinOp::Sub,
            Box::new(node(IrExpr::LitFloat(1000.0))),
            Box::new(field_self("level")),
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s,
            "(sub.f32 (lit 1000.0f32) (builtin.as_f32.u32 (read agent.self.level)))",
            "expected u32→f32 cast on rhs, got {s:?}"
        );
    }

    /// Symmetric: `self.level * 2.0` (u32 lhs, f32 rhs) — lhs wraps.
    #[test]
    fn binary_u32_times_f32_promotes_lhs_to_f32() {
        let ast = node(IrExpr::Binary(
            BinOp::Mul,
            Box::new(field_self("level")),
            Box::new(node(IrExpr::LitFloat(2.0))),
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s,
            "(mul.f32 (builtin.as_f32.u32 (read agent.self.level)) (lit 2.0f32))",
            "expected u32→f32 cast on lhs, got {s:?}"
        );
    }

    /// I32-source promotion: `self.slow_factor_q8 < 0.5` (i32 lhs,
    /// f32 rhs). Verifies the NumericTy::I32 arm of the cast.
    #[test]
    fn binary_i32_lt_f32_promotes_lhs_to_f32() {
        let ast = node(IrExpr::Binary(
            BinOp::Lt,
            Box::new(field_self("slow_factor_q8")),
            Box::new(node(IrExpr::LitFloat(0.5))),
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s,
            "(lt.f32 (builtin.as_f32.i32 (read agent.self.slow_factor_q8)) (lit 0.5f32))",
            "expected i32→f32 cast on lhs, got {s:?}"
        );
    }

    /// Promotion is one-directional. `self.level - self.engaged_with`
    /// (u32 - agent_id) is NOT a numeric mixed-type case, so the
    /// existing `BinaryOperandTyMismatch` still fires.
    #[test]
    fn binary_u32_minus_agent_id_still_rejected() {
        let ast = node(IrExpr::Binary(
            BinOp::Sub,
            Box::new(field_self("level")),
            Box::new(field_self("engaged_with")),
        ));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::BinaryOperandTyMismatch {
                lhs_ty, rhs_ty, ..
            } => {
                assert_eq!(lhs_ty, CgTy::U32);
                assert_eq!(rhs_ty, CgTy::AgentId);
            }
            other => panic!("expected BinaryOperandTyMismatch, got {other:?}"),
        }
    }

    // ---- BinaryOp coverage ----

    #[test]
    fn binary_arithmetic_f32() {
        let ast = node(IrExpr::Binary(
            BinOp::Add,
            Box::new(field_self("hp")),
            Box::new(field_self("max_hp")),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(add.f32 (read agent.self.hp) (read agent.self.max_hp))"
        );
    }

    #[test]
    fn binary_arithmetic_u32() {
        let ast = node(IrExpr::Binary(
            BinOp::Sub,
            Box::new(field_self("level")),
            Box::new(node(IrExpr::LitInt(1))),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(sub.u32 (read agent.self.level) (lit 1u32))"
        );
    }

    #[test]
    fn binary_comparison_f32_lt() {
        // self.hp < self.max_hp
        let ast = node(IrExpr::Binary(
            BinOp::Lt,
            Box::new(field_self("hp")),
            Box::new(field_self("max_hp")),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(lt.f32 (read agent.self.hp) (read agent.self.max_hp))"
        );
    }

    #[test]
    fn binary_comparison_u32_le() {
        // self.level <= 5
        let ast = node(IrExpr::Binary(
            BinOp::LtEq,
            Box::new(field_self("level")),
            Box::new(node(IrExpr::LitInt(5))),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(le.u32 (read agent.self.level) (lit 5u32))"
        );
    }

    #[test]
    fn binary_equality_bool() {
        // self.alive == self.alive
        let ast = node(IrExpr::Binary(
            BinOp::Eq,
            Box::new(field_self("alive")),
            Box::new(field_self("alive")),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(eq.bool (read agent.self.alive) (read agent.self.alive))"
        );
    }

    #[test]
    fn binary_equality_agent_id() {
        // self.engaged_with == self.engaged_with
        let ast = node(IrExpr::Binary(
            BinOp::Eq,
            Box::new(field_self("engaged_with")),
            Box::new(field_self("engaged_with")),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(eq.agent_id (read agent.self.engaged_with) (read agent.self.engaged_with))"
        );
    }

    #[test]
    fn binary_logical_and() {
        let ast = node(IrExpr::Binary(
            BinOp::And,
            Box::new(field_self("alive")),
            Box::new(field_self("alive")),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(and (read agent.self.alive) (read agent.self.alive))"
        );
    }

    #[test]
    fn binary_logical_or() {
        let ast = node(IrExpr::Binary(
            BinOp::Or,
            Box::new(node(IrExpr::LitBool(true))),
            Box::new(node(IrExpr::LitBool(false))),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(or (lit true) (lit false))"
        );
    }

    /// `BinOp::Mod` lowers to `BinaryOp::ModU32` for u32 operands. The
    /// pretty-print exercises both the `mod.u32` label and the WGSL `%`
    /// operator path. Closes Gap #3 from
    /// `docs/superpowers/notes/2026-05-04-abilities_probe.md`.
    #[test]
    fn binary_mod_u32() {
        let ast = node(IrExpr::Binary(
            BinOp::Mod,
            Box::new(node(IrExpr::LitInt(7))),
            Box::new(node(IrExpr::LitInt(3))),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(mod.u32 (lit 7u32) (lit 3u32))"
        );
    }

    /// `BinOp::Mod` lowers to `BinaryOp::ModI32` when both operands are
    /// i32-typed. `slow_factor_q8` is i16 widened to i32 in CG IR (see
    /// `unary_neg_i32`'s comment for the same i32-source pattern).
    #[test]
    fn binary_mod_i32() {
        let ast = node(IrExpr::Binary(
            BinOp::Mod,
            Box::new(field_self("slow_factor_q8")),
            Box::new(field_self("slow_factor_q8")),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(mod.i32 (read agent.self.slow_factor_q8) (read agent.self.slow_factor_q8))"
        );
    }

    /// `BinOp::Mod` lowers to `BinaryOp::ModF32` for f32 operands —
    /// matching WGSL's native `%` overload for floats.
    #[test]
    fn binary_mod_f32() {
        let ast = node(IrExpr::Binary(
            BinOp::Mod,
            Box::new(node(IrExpr::LitFloat(7.5))),
            Box::new(node(IrExpr::LitFloat(2.0))),
        ));
        let s = lower_to_string(&ast).unwrap();
        assert!(s.starts_with("(mod.f32 "), "expected mod.f32, got {s}");
    }

    #[test]
    fn binary_logical_and_on_non_bool_rejected() {
        let ast = node(IrExpr::Binary(
            BinOp::And,
            Box::new(node(IrExpr::LitInt(1))),
            Box::new(node(IrExpr::LitInt(2))),
        ));
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::IllTypedExpression { .. }));
    }

    // ---- PerUnit (Phase 6 Task 1) ----

    /// `<expr> per_unit <delta>` lowers as `expr * delta` per the AST
    /// docstring's outside-scoring semantic. Inside scoring contexts
    /// the iterate-over-view-storage semantic differs, but for empty
    /// view storage the result is identical (0 * delta = 0). This
    /// test verifies the rejection (`UnsupportedAstNode { ast_label:
    /// "PerUnit" }`) is gone and the lowering produces the expected
    /// `mul.f32` shape.
    #[test]
    fn per_unit_lowers_as_multiplication() {
        let ast = node(IrExpr::PerUnit {
            expr: Box::new(node(IrExpr::LitFloat(2.0))),
            delta: Box::new(node(IrExpr::LitFloat(0.01))),
        });
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s, "(mul.f32 (lit 2.0f32) (lit 0.01f32))",
            "expected per_unit to lower as mul.f32, got {s:?}"
        );
    }

    // ---- UnaryOp coverage ----

    #[test]
    fn unary_not_bool() {
        let ast = node(IrExpr::Unary(UnOp::Not, Box::new(field_self("alive"))));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(not.bool (read agent.self.alive))"
        );
    }

    #[test]
    fn unary_neg_f32() {
        let ast = node(IrExpr::Unary(UnOp::Neg, Box::new(field_self("hp"))));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(neg.f32 (read agent.self.hp))"
        );
    }

    #[test]
    fn unary_neg_i32() {
        // self.slow_factor_q8 is i16 widened to i32 in CG IR.
        let ast = node(IrExpr::Unary(
            UnOp::Neg,
            Box::new(field_self("slow_factor_q8")),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(neg.i32 (read agent.self.slow_factor_q8))"
        );
    }

    #[test]
    fn unary_not_on_u32_rejected() {
        let ast = node(IrExpr::Unary(UnOp::Not, Box::new(field_self("level"))));
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::IllTypedExpression { .. }));
    }

    #[test]
    fn unary_neg_on_bool_rejected() {
        let ast = node(IrExpr::Unary(UnOp::Neg, Box::new(field_self("alive"))));
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::IllTypedExpression { .. }));
    }

    // ---- Builtins ----

    #[test]
    fn distance_builtin_lowers() {
        // distance(self.pos, self.pos)  — DSL spec example.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Distance,
            vec![arg(field_self("pos")), arg(field_self("pos"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.distance (read agent.self.pos) (read agent.self.pos))"
        );
    }

    #[test]
    fn planar_distance_builtin_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::PlanarDistance,
            vec![arg(field_self("pos")), arg(field_self("pos"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.planar_distance (read agent.self.pos) (read agent.self.pos))"
        );
    }

    #[test]
    fn z_separation_builtin_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::ZSeparation,
            vec![arg(field_self("pos")), arg(field_self("pos"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.z_separation (read agent.self.pos) (read agent.self.pos))"
        );
    }

    #[test]
    fn distance_arity_mismatch_rejected() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Distance,
            vec![arg(field_self("pos"))],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::BuiltinArityMismatch {
                builtin: Builtin::Distance,
                expected,
                got,
                ..
            } => {
                assert_eq!(expected, 2);
                assert_eq!(got, 1);
            }
            other => panic!("unexpected: {other:?}"),
        }
    }

    #[test]
    fn distance_with_non_vec3_args_fails_typecheck() {
        // distance(self.hp, self.hp) — operands must be Vec3, not F32.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Distance,
            vec![arg(field_self("hp")), arg(field_self("hp"))],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::TypeCheckFailure { .. }));
    }

    #[test]
    fn min_f32_pairwise_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Min,
            vec![arg(field_self("hp")), arg(field_self("max_hp"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.min.f32 (read agent.self.hp) (read agent.self.max_hp))"
        );
    }

    #[test]
    fn max_u32_pairwise_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Max,
            vec![
                arg(field_self("level")),
                arg(node(IrExpr::LitInt(7))),
            ],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.max.u32 (read agent.self.level) (lit 7u32))"
        );
    }

    #[test]
    fn clamp_f32_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Clamp,
            vec![
                arg(field_self("hp")),
                arg(node(IrExpr::LitFloat(0.0))),
                arg(field_self("max_hp")),
            ],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.clamp.f32 (read agent.self.hp) (lit 0.0f32) (read agent.self.max_hp))"
        );
    }

    #[test]
    fn saturating_add_u32_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::SaturatingAdd,
            vec![
                arg(field_self("level")),
                arg(node(IrExpr::LitInt(1))),
            ],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.saturating_add.u32 (read agent.self.level) (lit 1u32))"
        );
    }

    #[test]
    fn entity_builtin_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Entity,
            vec![arg(field_self("engaged_with"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.entity (read agent.self.engaged_with))"
        );
    }

    #[test]
    fn floor_builtin_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Floor,
            vec![arg(field_self("hp"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(builtin.floor (read agent.self.hp))"
        );
    }

    #[test]
    fn ceil_ln_log2_log10_round_lower() {
        // Quick smoke test that all five additional unary-f32 builtins
        // share the same path.
        for (b, label) in [
            (Builtin::Ceil, "ceil"),
            (Builtin::Round, "round"),
            (Builtin::Ln, "ln"),
            (Builtin::Log2, "log2"),
            (Builtin::Log10, "log10"),
        ] {
            let ast = node(IrExpr::BuiltinCall(b, vec![arg(field_self("hp"))]));
            let s = lower_to_string(&ast).unwrap();
            assert_eq!(
                s,
                format!("(builtin.{label} (read agent.self.hp))"),
                "builtin {label}"
            );
        }
    }

    #[test]
    fn sqrt_builtin_rewrites_to_unary() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Sqrt,
            vec![arg(field_self("hp"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(sqrt.f32 (read agent.self.hp))"
        );
    }

    #[test]
    fn abs_f32_rewrites_to_unary() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Abs,
            vec![arg(field_self("hp"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(abs.f32 (read agent.self.hp))"
        );
    }

    #[test]
    fn abs_i32_rewrites_to_unary() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Abs,
            vec![arg(field_self("slow_factor_q8"))],
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(abs.i32 (read agent.self.slow_factor_q8))"
        );
    }

    #[test]
    fn abs_on_bool_rejected() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Abs,
            vec![arg(field_self("alive"))],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::NumericBuiltinNonNumericOperand { .. }
        ));
    }

    #[test]
    fn min_on_bool_rejected() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Min,
            vec![
                arg(field_self("alive")),
                arg(field_self("alive")),
            ],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::NumericBuiltinNonNumericOperand { .. }
        ));
    }

    #[test]
    fn min_with_mixed_numeric_types_rejected() {
        // min(self.hp, self.level) — F32 vs U32.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Min,
            vec![arg(field_self("hp")), arg(field_self("level"))],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        // The two operand lowerings succeed independently; the
        // pairwise-numeric helper rejects the mix.
        match err {
            LoweringError::BuiltinOperandMismatch {
                builtin: Builtin::Min,
                lhs_ty,
                rhs_ty,
                ..
            } => {
                assert_eq!(lhs_ty, CgTy::F32);
                assert_eq!(rhs_ty, CgTy::U32);
            }
            other => panic!("expected BuiltinOperandMismatch(Min), got {other:?}"),
        }
    }

    #[test]
    fn clamp_with_mixed_numeric_types_rejected() {
        // clamp(self.hp, 0u32, self.max_hp) — first/last are F32,
        // middle slot is U32. The clamp lowering picks `nty` from the
        // first operand, then rejects the second when it doesn't match.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Clamp,
            vec![
                arg(field_self("hp")),
                arg(node(IrExpr::LitInt(0))),
                arg(field_self("max_hp")),
            ],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::BuiltinOperandMismatch {
                builtin: Builtin::Clamp,
                lhs_ty,
                rhs_ty,
                ..
            } => {
                assert_eq!(lhs_ty, CgTy::F32);
                assert_eq!(rhs_ty, CgTy::U32);
            }
            other => panic!("expected BuiltinOperandMismatch(Clamp), got {other:?}"),
        }
    }

    #[test]
    fn quantifier_builtins_unsupported() {
        for b in [Builtin::Forall, Builtin::Exists, Builtin::Count, Builtin::Sum] {
            let ast = node(IrExpr::BuiltinCall(b, vec![]));
            let err = lower_to_string(&ast).unwrap_err();
            assert!(
                matches!(err, LoweringError::UnsupportedBuiltin { .. }),
                "expected UnsupportedBuiltin for {b:?}, got {err:?}"
            );
        }
    }

    // ---- Conditional (Select) ----

    #[test]
    fn if_then_else_lowers_to_select() {
        // if self.alive then 1.0 else 0.0
        let ast = node(IrExpr::If {
            cond: Box::new(field_self("alive")),
            then_expr: Box::new(node(IrExpr::LitFloat(1.0))),
            else_expr: Some(Box::new(node(IrExpr::LitFloat(0.0)))),
        });
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(select (read agent.self.alive) (lit 1.0f32) (lit 0.0f32))"
        );
    }

    #[test]
    fn if_with_non_bool_cond_rejected() {
        // if self.hp then 1.0 else 0.0 — `cond` is f32, not bool.
        let ast = node(IrExpr::If {
            cond: Box::new(field_self("hp")),
            then_expr: Box::new(node(IrExpr::LitFloat(1.0))),
            else_expr: Some(Box::new(node(IrExpr::LitFloat(0.0)))),
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::IllTypedExpression { .. }));
    }

    #[test]
    fn if_with_arms_mismatch_rejected() {
        // if self.alive then 1.0 else 1u32
        let ast = node(IrExpr::If {
            cond: Box::new(field_self("alive")),
            then_expr: Box::new(node(IrExpr::LitFloat(1.0))),
            else_expr: Some(Box::new(node(IrExpr::LitInt(1)))),
        });
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::SelectArmMismatch { then_ty, else_ty, .. } => {
                assert_eq!(then_ty, CgTy::F32);
                assert_eq!(else_ty, CgTy::U32);
            }
            other => panic!("expected SelectArmMismatch, got {other:?}"),
        }
    }

    #[test]
    fn if_without_else_rejected() {
        let ast = node(IrExpr::If {
            cond: Box::new(field_self("alive")),
            then_expr: Box::new(node(IrExpr::LitFloat(1.0))),
            else_expr: None,
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedAstNode {
                ast_label: "If(without-else)",
                ..
            }
        ));
    }

    // ---- RNG / namespace calls ----

    #[test]
    fn rng_action_lowers_to_rng_node() {
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "action".to_string(),
            args: vec![],
        });
        assert_eq!(lower_to_string(&ast).unwrap(), "(rng action)");
    }

    #[test]
    fn rng_sample_lowers() {
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "sample".to_string(),
            args: vec![],
        });
        assert_eq!(lower_to_string(&ast).unwrap(), "(rng sample)");
    }

    #[test]
    fn rng_truly_unknown_purpose_rejected() {
        // `rng.bogus()` is neither an internal purpose
        // (`action`/`sample`/`shuffle`/`conception`) nor a spec-named
        // surface (`uniform`/`gauss`/`coin`/`uniform_int`); must
        // surface as `UnsupportedNamespaceCall`.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "bogus".to_string(),
            args: vec![],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedNamespaceCall { .. }
        ));
    }

    // ---- Spec-named typed RNG surfaces (Gap #4 — stochastic_probe) ----
    //
    // Each test below pins the IR shape produced by lowering a
    // `rng.<method>(...)` call from `docs/spec/dsl.md` §rng. The
    // shapes match the contract documented on `lower_rng_call`.

    #[test]
    fn rng_coin_lowers_to_typed_bool_rng_node() {
        // `rng.coin()` → `CgExpr::Rng { Coin, Bool }` (nullary).
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "coin".to_string(),
            args: vec![],
        });
        assert_eq!(lower_to_string(&ast).unwrap(), "(rng coin)");
    }

    #[test]
    fn rng_coin_with_extra_args_rejected() {
        // `rng.coin(0)` — coin is nullary; extra args surface the
        // same arity-mismatch error as `rng.action(<extra>)`.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "coin".to_string(),
            args: vec![arg(node(IrExpr::LitInt(0)))],
        });
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::NamespaceCallArityMismatch {
                ns,
                method,
                expected,
                got,
                ..
            } => {
                assert_eq!(ns, NamespaceId::Rng);
                assert_eq!(method, "coin");
                assert_eq!(expected, 0);
                assert_eq!(got, 1);
            }
            other => panic!("expected NamespaceCallArityMismatch, got {other:?}"),
        }
    }

    #[test]
    fn rng_uniform_lowers_to_lo_plus_draw_times_range() {
        // `rng.uniform(0.0, 1.0)` → `0.0 + draw * (1.0 - 0.0)`.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "uniform".to_string(),
            args: vec![arg(node(IrExpr::LitFloat(0.0))), arg(node(IrExpr::LitFloat(1.0)))],
        });
        // Affine shape: outermost AddF32, RHS is MulF32(draw, SubF32(hi, lo)).
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(add.f32 (lit 0.0f32) (mul.f32 (rng uniform) (sub.f32 (lit 1.0f32) (lit 0.0f32))))"
        );
    }

    #[test]
    fn rng_uniform_arity_mismatch_rejected() {
        // `rng.uniform()` (zero args) — spec says (f32, f32); arity
        // mismatch surfaces the typed `NamespaceCallArityMismatch`.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "uniform".to_string(),
            args: vec![],
        });
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::NamespaceCallArityMismatch {
                ns,
                method,
                expected,
                got,
                ..
            } => {
                assert_eq!(ns, NamespaceId::Rng);
                assert_eq!(method, "uniform");
                assert_eq!(expected, 2);
                assert_eq!(got, 0);
            }
            other => panic!("expected NamespaceCallArityMismatch, got {other:?}"),
        }
    }

    #[test]
    fn rng_uniform_with_non_f32_args_rejected() {
        // `rng.uniform(0u32, 1u32)` — args must be f32.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "uniform".to_string(),
            args: vec![arg(node(IrExpr::LitInt(0))), arg(node(IrExpr::LitInt(1)))],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::IllTypedExpression { .. }));
    }

    #[test]
    fn rng_gauss_lowers_to_mu_plus_draw_times_sigma() {
        // `rng.gauss(0.0, 2.5)` → `0.0 + draw * 2.5`.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "gauss".to_string(),
            args: vec![arg(node(IrExpr::LitFloat(0.0))), arg(node(IrExpr::LitFloat(2.5)))],
        });
        // MeanStddev shape: outermost AddF32, RHS is MulF32(draw, sigma)
        // with sigma threaded directly (no Sub wrapping).
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(add.f32 (lit 0.0f32) (mul.f32 (rng gauss) (lit 2.5f32)))"
        );
    }

    #[test]
    fn rng_gauss_arity_mismatch_rejected() {
        // Single arg — spec is `(mu, sigma)`.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "gauss".to_string(),
            args: vec![arg(node(IrExpr::LitFloat(0.0)))],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::NamespaceCallArityMismatch {
                expected: 2,
                got: 1,
                ..
            }
        ));
    }

    #[test]
    fn rng_uniform_int_lowers_to_lo_plus_draw_mod_range() {
        // Gap #C close (stdlib_math_probe, 2026-05-04): the surface is
        // now `(u32, u32) -> u32`. `rng.uniform_int(0, 4)` → `0 +
        // (draw % (4 - 0))`. Outermost AddU32; RHS is ModU32(draw,
        // SubU32(hi, lo)). Positive `IrExpr::LitInt` picks `u32`
        // (see `literal_int_positive_picks_u32`), so a bare-literal
        // pair just types straight through — which is the whole
        // point of the surface change.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "uniform_int".to_string(),
            args: vec![arg(node(IrExpr::LitInt(0))), arg(node(IrExpr::LitInt(4)))],
        });
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(add.u32 (lit 0u32) (mod.u32 (rng uniform_int) (sub.u32 (lit 4u32) (lit 0u32))))"
        );
    }

    #[test]
    fn rng_uniform_int_arity_mismatch_rejected() {
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "uniform_int".to_string(),
            args: vec![],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::NamespaceCallArityMismatch {
                expected: 2,
                got: 0,
                ..
            }
        ));
    }

    #[test]
    fn rng_uniform_int_with_non_u32_args_rejected() {
        // Float args reject — surface is `(u32, u32)` post Gap #C.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "uniform_int".to_string(),
            args: vec![arg(node(IrExpr::LitFloat(0.0))), arg(node(IrExpr::LitFloat(1.0)))],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::IllTypedExpression { .. }));
    }

    #[test]
    fn rng_uniform_int_with_negative_literal_rejected_as_i32() {
        // Negative `LitInt` lowers to I32, which now mismatches the
        // U32 signature — surfaces as IllTypedExpression. Authors who
        // want signed-style ranges can express them as bare u32
        // ranges (the bias is the same).
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "uniform_int".to_string(),
            args: vec![arg(node(IrExpr::LitInt(-1))), arg(node(IrExpr::LitInt(-2)))],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::IllTypedExpression { expected: CgTy::U32, got: CgTy::I32, .. }
        ));
    }

    #[test]
    fn rng_purposes_use_distinct_streams() {
        // Each spec-named purpose must map to its own `RngPurpose`
        // variant so the underlying `per_agent_u32(seed, agent_id,
        // tick, purpose)` call uses a distinct purpose-byte tag —
        // i.e. drawing `rng.uniform()` and `rng.action()` in the same
        // tick produces uncorrelated samples (P5 per-stream
        // determinism). The pretty-printer surfaces the snake-case
        // purpose name; check each spec-surface includes its own.
        let cases = [
            ("coin", "coin"),
            // `uniform` / `gauss` / `uniform_int` are wrapped in
            // arithmetic, so we just check the inner `(rng <name>)`
            // token appears.
            ("uniform", "uniform"),
            ("gauss", "gauss"),
            ("uniform_int", "uniform_int"),
        ];
        for (method, snake) in cases {
            let args = match method {
                "coin" => vec![],
                // Gap #C close: uniform_int now takes `(u32, u32)`; bare
                // positive literals lower to U32 directly.
                "uniform_int" => vec![arg(node(IrExpr::LitInt(0))), arg(node(IrExpr::LitInt(4)))],
                _ => vec![arg(node(IrExpr::LitFloat(0.0))), arg(node(IrExpr::LitFloat(1.0)))],
            };
            let ast = node(IrExpr::NamespaceCall {
                ns: NamespaceId::Rng,
                method: method.to_string(),
                args,
            });
            let s = lower_to_string(&ast).unwrap();
            let token = format!("(rng {})", snake);
            assert!(
                s.contains(&token),
                "rng.{}() lowering missing `{}` token: {}",
                method,
                token,
                s,
            );
        }
    }

    #[test]
    fn rng_with_extra_args_rejected_with_namespace_arity() {
        // `rng.action(<extra>)` — RNG draws are nullary at the
        // expression layer; passing args surfaces the typed
        // namespace-call arity mismatch rather than the builtin one.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Rng,
            method: "action".to_string(),
            args: vec![arg(node(IrExpr::LitInt(0)))],
        });
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::NamespaceCallArityMismatch {
                ns,
                method,
                expected,
                got,
                ..
            } => {
                assert_eq!(ns, NamespaceId::Rng);
                assert_eq!(method, "action");
                assert_eq!(expected, 0);
                assert_eq!(got, 1);
            }
            other => panic!("expected NamespaceCallArityMismatch, got {other:?}"),
        }
    }

    #[test]
    fn agents_pos_with_target_expr_lowers_to_target_read() {
        // agents.pos(self.engaged_with) — engaged_with is AgentId, so
        // the resulting Read uses AgentRef::Target(child_id).
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Agents,
            method: "pos".to_string(),
            args: vec![arg(field_self("engaged_with"))],
        });
        let s = lower_to_string(&ast).unwrap();
        // The target-id varies based on arena ordering, but the prefix
        // is stable.
        assert!(
            s.starts_with("(read agent.target(#"),
            "unexpected lowering: {s}"
        );
        assert!(s.ends_with(").pos)"));
    }

    #[test]
    fn agents_field_with_non_agent_id_arg_rejected() {
        // agents.hp(self.hp) — arg is f32, not AgentId.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Agents,
            method: "hp".to_string(),
            args: vec![arg(field_self("hp"))],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::IllTypedExpression { .. }));
    }

    #[test]
    fn unsupported_namespace_call_typed_error() {
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Cascade,
            method: "iterations".to_string(),
            args: vec![],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedNamespaceCall { .. }
        ));
    }

    #[test]
    fn unsupported_non_config_namespace_field_typed_error() {
        let ast = node(IrExpr::NamespaceField {
            ns: NamespaceId::World,
            field: "tick".to_string(),
            ty: dsl_ast::ir::IrType::U64,
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedNamespaceField { .. }
        ));
    }

    // ---- Registry-driven namespace lowering (Task 4 of CG lowering gap closure) ----

    /// Build a `LoweringCtx` whose namespace registry has the
    /// `agents.is_hostile_to(a, b)` method registered. Mirrors the
    /// driver's `populate_namespace_registry`. Used by the registry-
    /// path tests below.
    fn ctx_with_agents_is_hostile_to_registered<'a>(
        builder: &'a mut CgProgramBuilder,
    ) -> LoweringCtx<'a> {
        use crate::cg::program::{MethodDef, NamespaceDef};
        let mut ctx = LoweringCtx::new(builder);
        let mut agents = NamespaceDef {
            name: "agents".to_string(),
            ..NamespaceDef::default()
        };
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
        ctx.namespace_registry
            .namespaces
            .insert(NamespaceId::Agents, agents);
        ctx
    }

    #[test]
    fn agents_is_hostile_to_registry_lowers_to_namespace_call() {
        // `agents.is_hostile_to(self, self)` with the registry entry
        // present → CgExpr::NamespaceCall { ns: Agents, method:
        // "is_hostile_to", args: [self, self], ty: Bool }.
        let mut builder = CgProgramBuilder::new();
        let mut ctx = ctx_with_agents_is_hostile_to_registered(&mut builder);

        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Agents,
            method: "is_hostile_to".to_string(),
            args: vec![arg(local_self()), arg(local_self())],
        });
        let id = lower_expr(&ast, &mut ctx).expect("lowers");
        let prog = builder.finish();
        let lowered = &prog.exprs[id.0 as usize];
        match lowered {
            CgExpr::NamespaceCall {
                ns, method, args, ty,
            } => {
                assert_eq!(*ns, NamespaceId::Agents);
                assert_eq!(method, "is_hostile_to");
                assert_eq!(args.len(), 2);
                assert_eq!(*ty, CgTy::Bool);
            }
            other => panic!("expected NamespaceCall, got {other:?}"),
        }
    }

    /// Build a `LoweringCtx` whose namespace registry has the
    /// `auctions.place_bid(bidder, good, amount)` method registered.
    /// Mirrors the driver's `populate_namespace_registry`. Used by
    /// the registry-path test below to confirm the catch-all arm of
    /// `lower_namespace_call` (line ~2566) handles auctions through
    /// the registry-fallback path with no special-case needed.
    fn ctx_with_auctions_place_bid_registered<'a>(
        builder: &'a mut CgProgramBuilder,
    ) -> LoweringCtx<'a> {
        use crate::cg::program::{MethodDef, NamespaceDef};
        let mut ctx = LoweringCtx::new(builder);
        let mut auctions = NamespaceDef {
            name: "auctions".to_string(),
            ..NamespaceDef::default()
        };
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
        ctx.namespace_registry
            .namespaces
            .insert(NamespaceId::Auctions, auctions);
        ctx
    }

    #[test]
    fn auctions_place_bid_registry_lowers_to_namespace_call() {
        // `auctions.place_bid(self, self, 10.0)` with the registry
        // entry present → `CgExpr::NamespaceCall { ns: Auctions,
        // method: "place_bid", args: [self, self, 10.0], ty: Bool }`.
        // Confirms the registry-fallback arm of
        // `lower_namespace_call` handles `(NamespaceId::Auctions, _)`
        // without a dedicated dispatch arm — the `auctions` namespace
        // is end-to-end lowerable via registry alone.
        let mut builder = CgProgramBuilder::new();
        let mut ctx = ctx_with_auctions_place_bid_registered(&mut builder);

        let amount_arg = arg(node(IrExpr::LitFloat(10.0)));
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Auctions,
            method: "place_bid".to_string(),
            args: vec![arg(local_self()), arg(local_self()), amount_arg],
        });
        let id = lower_expr(&ast, &mut ctx).expect("lowers");
        let prog = builder.finish();
        let lowered = &prog.exprs[id.0 as usize];
        match lowered {
            CgExpr::NamespaceCall {
                ns, method, args, ty,
            } => {
                assert_eq!(*ns, NamespaceId::Auctions);
                assert_eq!(method, "place_bid");
                assert_eq!(args.len(), 3);
                assert_eq!(*ty, CgTy::Bool);
            }
            other => panic!("expected NamespaceCall, got {other:?}"),
        }
    }

    #[test]
    fn world_tick_registry_lowers_to_namespace_field() {
        // `world.tick` with a `World.tick` field registered → typed
        // `CgExpr::NamespaceField { ns: World, field: "tick", ty: U32 }`.
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        use crate::cg::program::{FieldDef, NamespaceDef, WgslAccessForm};
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
        ctx.namespace_registry
            .namespaces
            .insert(NamespaceId::World, world);

        let ast = node(IrExpr::NamespaceField {
            ns: NamespaceId::World,
            field: "tick".to_string(),
            ty: dsl_ast::ir::IrType::U32,
        });
        let id = lower_expr(&ast, &mut ctx).expect("lowers");
        let prog = builder.finish();
        let lowered = &prog.exprs[id.0 as usize];
        match lowered {
            CgExpr::NamespaceField { ns, field, ty } => {
                assert_eq!(*ns, NamespaceId::World);
                assert_eq!(field, "tick");
                assert_eq!(*ty, CgTy::U32);
            }
            other => panic!("expected NamespaceField, got {other:?}"),
        }
    }

    #[test]
    fn registered_namespace_call_arity_mismatch_typed_error() {
        // `agents.is_hostile_to(self)` with a 2-arg registry entry →
        // typed NamespaceCallArityMismatch.
        let mut builder = CgProgramBuilder::new();
        let mut ctx = ctx_with_agents_is_hostile_to_registered(&mut builder);

        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Agents,
            method: "is_hostile_to".to_string(),
            args: vec![arg(local_self())],
        });
        let err = lower_expr(&ast, &mut ctx).expect_err("must reject");
        match err {
            LoweringError::NamespaceCallArityMismatch {
                ns,
                method,
                expected,
                got,
                ..
            } => {
                assert_eq!(ns, NamespaceId::Agents);
                assert_eq!(method, "is_hostile_to");
                assert_eq!(expected, 2);
                assert_eq!(got, 1);
            }
            other => panic!("expected NamespaceCallArityMismatch, got {other:?}"),
        }
    }

    #[test]
    fn unregistered_query_call_falls_through_to_unsupported() {
        // `query.nearest_hostile_to_or` with no registry entry →
        // typed UnsupportedNamespaceCall (the catch-all arm).
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Query,
            method: "nearest_hostile_to_or".to_string(),
            args: vec![],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedNamespaceCall { .. }
        ));
    }

    // ---- Config NamespaceField → ConfigConst (Task 5.5c, Patch 1) ----

    #[test]
    fn lowers_namespace_field_to_config_const() {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        ctx.register_config_const(
            NamespaceId::Config,
            "combat.attack_range".to_string(),
            ConfigConstId(0),
        );

        let ast = node(IrExpr::NamespaceField {
            ns: NamespaceId::Config,
            field: "combat.attack_range".to_string(),
            ty: dsl_ast::ir::IrType::F32,
        });
        let id = lower_expr(&ast, &mut ctx).unwrap();
        let prog = builder.finish();
        let node = &prog.exprs[id.0 as usize];
        let s = pretty(node, &prog.exprs);
        assert!(s.starts_with("(read config"), "got pretty: {s}");
    }

    #[test]
    fn unknown_namespace_field_returns_typed_error() {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        // No registry entries.
        let ast = node(IrExpr::NamespaceField {
            ns: NamespaceId::Config,
            field: "combat.attack_range".to_string(),
            ty: dsl_ast::ir::IrType::F32,
        });
        let err = lower_expr(&ast, &mut ctx).expect_err("must be typed error");
        match err {
            LoweringError::UnknownConfigField { ns, field, .. } => {
                assert_eq!(ns, NamespaceId::Config);
                assert_eq!(field, "combat.attack_range");
            }
            other => panic!("expected UnknownConfigField, got {other:?}"),
        }
    }

    // ---- Lazy view inlining (Task 5.5c, Patch 2) ----

    #[test]
    fn inlines_lazy_view_at_call_site() {
        // Lazy view body: just `LocalRef(0)` (the view's first param).
        // Calling with `LitBool(true)` should inline the literal,
        // bypassing `BuiltinId::ViewCall`.
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let ast_ref = AstViewRef(0);
        let view_id = ViewId(0);
        ctx.register_view(ast_ref, view_id);
        let snapshot = LazyViewSnapshot {
            param_locals: vec![LocalRef(0)],
            body: node(IrExpr::Local(LocalRef(0), "a".to_string())),
        };
        ctx.register_lazy_view_body(view_id, snapshot);

        let ast = node(IrExpr::ViewCall(
            ast_ref,
            vec![arg(node(IrExpr::LitBool(true)))],
        ));
        let id = lower_expr(&ast, &mut ctx).unwrap();
        let prog = builder.finish();
        let node = &prog.exprs[id.0 as usize];
        // Should be the literal, not a builtin.view_call.
        assert_eq!(pretty(node, &prog.exprs), "(lit true)");
    }

    #[test]
    fn materialized_view_call_uses_builtin_view_call() {
        // No lazy body registered → call falls through to the
        // materialized BuiltinId::ViewCall path.
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let ast_ref = AstViewRef(0);
        let view_id = ViewId(0);
        ctx.register_view(ast_ref, view_id);
        ctx.register_view_signature(view_id, vec![CgTy::AgentId], CgTy::F32);

        let ast = node(IrExpr::ViewCall(
            ast_ref,
            vec![arg(field_self("engaged_with"))],
        ));
        let id = lower_expr(&ast, &mut ctx).unwrap();
        let prog = builder.finish();
        let node = &prog.exprs[id.0 as usize];
        let s = pretty(node, &prog.exprs);
        assert!(s.starts_with("(builtin.view_call."), "got: {s}");
    }

    #[test]
    fn lazy_view_arity_mismatch_returns_typed_error() {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let ast_ref = AstViewRef(0);
        let view_id = ViewId(0);
        ctx.register_view(ast_ref, view_id);
        // 2-param body, called with 1 arg.
        let snapshot = LazyViewSnapshot {
            param_locals: vec![LocalRef(0), LocalRef(1)],
            body: node(IrExpr::Local(LocalRef(0), "a".to_string())),
        };
        ctx.register_lazy_view_body(view_id, snapshot);

        let ast = node(IrExpr::ViewCall(
            ast_ref,
            vec![arg(node(IrExpr::LitBool(true)))],
        ));
        let err = lower_expr(&ast, &mut ctx).expect_err("arity mismatch");
        match err {
            LoweringError::ViewCallArityMismatch {
                view, expected, got, ..
            } => {
                assert_eq!(view, view_id);
                assert_eq!(expected, 2);
                assert_eq!(got, 1);
            }
            other => panic!("expected ViewCallArityMismatch, got {other:?}"),
        }
    }

    // ---- ViewCall ----

    #[test]
    fn view_call_with_registered_signature_lowers() {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let ast_ref = AstViewRef(0);
        let view_id = ViewId(0);
        ctx.register_view(ast_ref, view_id);
        ctx.register_view_signature(view_id, vec![CgTy::AgentId], CgTy::Bool);

        // view::is_hostile(self.engaged_with)
        let ast = node(IrExpr::ViewCall(
            ast_ref,
            vec![arg(field_self("engaged_with"))],
        ));
        let id = lower_expr(&ast, &mut ctx).unwrap();
        let prog = builder.finish();
        let node = &prog.exprs[id.0 as usize];
        assert_eq!(
            pretty(node, &prog.exprs),
            "(builtin.view_call.#0 (read agent.self.engaged_with))"
        );
    }

    #[test]
    fn view_call_unknown_ref_rejected() {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let ast = node(IrExpr::ViewCall(AstViewRef(99), vec![]));
        let err = lower_expr(&ast, &mut ctx).unwrap_err();
        assert!(matches!(err, LoweringError::UnknownView { .. }));
    }

    // ---- Local references ----

    #[test]
    fn bare_local_self_lowers_to_agent_self_id() {
        // Task 5.5d: bare `self` resolves to `CgExpr::AgentSelfId`.
        let ast = local_self();
        assert_eq!(lower_to_string(&ast).unwrap(), "(agent self_id)");
    }

    #[test]
    fn bare_target_in_pair_bound_lowers_to_per_pair_candidate_id() {
        let ast = node(IrExpr::Local(LocalRef(1), "target".to_string()));
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        ctx.target_local = true;
        let id = lower_expr(&ast, &mut ctx).expect("lowers");
        let prog = builder.finish();
        let node_at = &prog.exprs[id.0 as usize];
        assert_eq!(pretty(node_at, &prog.exprs), "(agent per_pair_candidate_id)");
    }

    #[test]
    fn bare_target_outside_pair_bound_rejected() {
        let ast = node(IrExpr::Local(LocalRef(1), "target".to_string()));
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        // ctx.target_local left false.
        let err = lower_expr(&ast, &mut ctx).expect_err("must reject");
        match err {
            LoweringError::UnsupportedLocalBinding { name, .. } => {
                assert_eq!(name, "target");
            }
            other => panic!("expected UnsupportedLocalBinding, got {other:?}"),
        }
    }

    #[test]
    fn bare_unknown_local_rejected() {
        let ast = node(IrExpr::Local(LocalRef(2), "foo".to_string()));
        let err = lower_to_string(&ast).expect_err("must reject");
        match err {
            LoweringError::UnsupportedLocalBinding { name, .. } => {
                assert_eq!(name, "foo");
            }
            other => panic!("expected UnsupportedLocalBinding, got {other:?}"),
        }
    }

    #[test]
    fn target_neq_self_lowers_in_pair_bound() {
        // (target != self) under target_local = true.
        let ast = node(IrExpr::Binary(
            BinOp::NotEq,
            Box::new(node(IrExpr::Local(LocalRef(1), "target".to_string()))),
            Box::new(node(IrExpr::Local(LocalRef(0), "self".to_string()))),
        ));
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        ctx.target_local = true;
        let id = lower_expr(&ast, &mut ctx).expect("lowers");
        let prog = builder.finish();
        let node_at = &prog.exprs[id.0 as usize];
        assert_eq!(
            pretty(node_at, &prog.exprs),
            "(ne.agent_id (agent per_pair_candidate_id) (agent self_id))"
        );
    }

    #[test]
    fn let_bound_local_read_lowers_to_read_local() {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        ctx.register_local(LocalRef(7), LocalId(3));
        ctx.record_local_ty(LocalId(3), CgTy::F32);

        let ast = node(IrExpr::Local(LocalRef(7), "x".to_string()));
        let id = lower_expr(&ast, &mut ctx).expect("lowers");
        let prog = builder.finish();
        let node_at = &prog.exprs[id.0 as usize];
        assert_eq!(pretty(node_at, &prog.exprs), "(read_local local#3 f32)");
    }

    #[test]
    fn let_bound_local_without_recorded_ty_rejected() {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        ctx.register_local(LocalRef(7), LocalId(3));
        // Note: no ty recorded.

        let ast = node(IrExpr::Local(LocalRef(7), "x".to_string()));
        let err = lower_expr(&ast, &mut ctx).expect_err("must reject");
        match err {
            LoweringError::UnknownLocalType { local, .. } => {
                assert_eq!(local, LocalId(3));
            }
            other => panic!("expected UnknownLocalType, got {other:?}"),
        }
    }

    // ---- Unsupported AST shapes — typed deferral ----

    #[test]
    fn lit_string_unsupported() {
        let ast = node(IrExpr::LitString("foo".to_string()));
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedAstNode {
                ast_label: "LitString",
                ..
            }
        ));
    }

    /// `FoldKind::Min` / `Max` still surface as
    /// `UnsupportedAstNode` deferrals — Sum + Count are wired through
    /// the N²-fold `CgStmt::ForEachAgent` path; Min/Max would need
    /// distinct accumulator init (NEG_INFINITY / INFINITY) and a
    /// per-iteration reduction op different from `+`. No fixture
    /// asks for them yet.
    #[test]
    fn fold_min_max_unsupported() {
        for kind in [dsl_ast::ast::FoldKind::Min, dsl_ast::ast::FoldKind::Max] {
            let ast = node(IrExpr::Fold {
                kind,
                binder: Some(LocalRef(0)),
                binder_name: Some("x".to_string()),
                iter: Some(Box::new(node(IrExpr::Namespace(NamespaceId::Agents)))),
                body: Box::new(node(IrExpr::LitFloat(1.0))),
            });
            let err = lower_to_string(&ast).unwrap_err();
            assert!(
                matches!(err, LoweringError::UnsupportedAstNode { ast_label, .. } if ast_label.starts_with("Fold")),
                "Min/Max should defer; got: {err:?}"
            );
        }
    }

    /// `FoldKind::Count` over `agents` lowers to a `CgStmt::ForEachAgent`
    /// (pushed to `pending_pre_stmts`) plus a `CgExpr::ReadLocal`
    /// reading the populated accumulator. The expression's pretty-
    /// printed form is just the read; the loop is one stmt-arena entry
    /// over.
    #[test]
    fn fold_count_lowers_to_for_each_agent() {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = LoweringCtx::new(&mut builder);
        let ast = node(IrExpr::Fold {
            kind: dsl_ast::ast::FoldKind::Count,
            binder: Some(LocalRef(0)),
            binder_name: Some("x".to_string()),
            iter: Some(Box::new(node(IrExpr::Namespace(NamespaceId::Agents)))),
            body: Box::new(node(IrExpr::LitBool(true))),
        });
        let id = lower_expr(&ast, &mut ctx).expect("Count fold lowers");
        // The ForEachAgent stmt was pushed onto pending_pre_stmts.
        assert_eq!(
            ctx.pending_pre_stmts.len(),
            1,
            "ForEachAgent stmt must land on pending_pre_stmts"
        );
        let prog = builder.finish();
        let read = &prog.exprs[id.0 as usize];
        // The fold expression evaluates to a ReadLocal of the
        // accumulator local (typed I32).
        assert!(
            matches!(read, CgExpr::ReadLocal { ty: CgTy::I32, .. }),
            "Count fold expr must read i32 accumulator; got: {read:?}"
        );
    }

    #[test]
    fn struct_lit_unsupported() {
        let ast = node(IrExpr::StructLit {
            name: "X".to_string(),
            ctor: None,
            fields: vec![],
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedAstNode {
                ast_label: "StructLit",
                ..
            }
        ));
    }

    #[test]
    fn ability_tag_unsupported() {
        let ast = node(IrExpr::AbilityTag {
            tag: dsl_ast::ir::AbilityTag::Physical,
        });
        let err = lower_to_string(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedAstNode { ast_label: "AbilityTag", .. }
        ));
    }

    // ---- Span propagation ----

    #[test]
    fn lowering_error_carries_node_span() {
        // Span propagation through `UnknownAgentField`. Use a name
        // that's neither a real `AgentFieldId` nor a virtual field —
        // `hp_pct` was the historical choice but is now synthesized.
        let mut bad = field_self("nonexistent_field");
        bad.span = span(11, 22);
        let err = lower_to_string(&bad).unwrap_err();
        match err {
            LoweringError::UnknownAgentField { span: s, .. } => {
                assert_eq!(s.start, 11);
                assert_eq!(s.end, 22);
            }
            other => panic!("unexpected: {other:?}"),
        }
    }

    // ---- Plan/spec example: `mask Attack` predicate fragment ----

    #[test]
    fn distance_lt_attack_range_full_predicate() {
        // (distance(self.pos, self.pos) < self.attack_range)
        // — analogue of `distance(self, t) < AGGRO_RANGE` in the spec
        // example, with `t` substituted by `self` so we don't need a
        // target binding (Task 2.1 doesn't yet wire those).
        let ast = node(IrExpr::Binary(
            BinOp::Lt,
            Box::new(node(IrExpr::BuiltinCall(
                Builtin::Distance,
                vec![arg(field_self("pos")), arg(field_self("pos"))],
            ))),
            Box::new(field_self("attack_range")),
        ));
        assert_eq!(
            lower_to_string(&ast).unwrap(),
            "(lt.f32 (builtin.distance (read agent.self.pos) (read agent.self.pos)) (read agent.self.attack_range))"
        );
    }

    // ---- LoweringError Display sanity ----

    #[test]
    fn lowering_error_display_includes_span_and_reason() {
        let e = LoweringError::UnknownAgentField {
            field_name: "hp_pct".to_string(),
            span: span(3, 9),
        };
        let s = format!("{}", e);
        assert!(s.contains("hp_pct"));
        assert!(s.contains("3..9"));
    }

    #[test]
    fn lowering_error_display_unsupported_ast_node() {
        let e = LoweringError::UnsupportedAstNode {
            ast_label: "Fold",
            span: span(0, 5),
        };
        let s = format!("{}", e);
        assert!(s.contains("Fold"));
    }

    // ---- Items / Groups namespace lowering ----------------------------

    /// Build a `LoweringCtx` with a one-Item / one-Group entity-field
    /// catalog populated, so `items.weight(0)` and `groups.size(0)`
    /// resolve to typed handles. Mirrors what
    /// `populate_entity_field_catalog` does for a real `Compilation`.
    fn ctx_with_entity_catalog<'a>(
        builder: &'a mut CgProgramBuilder,
    ) -> LoweringCtx<'a> {
        use crate::cg::data_handle::AgentFieldTy;
        use crate::cg::program::{EntityFieldCatalog, EntityFieldEntry, EntityFieldRecord};
        let mut ctx = LoweringCtx::new(builder);
        let mut catalog = EntityFieldCatalog::default();
        catalog.items.insert(
            5,
            EntityFieldRecord {
                entity_name: "Coin".to_string(),
                fields: vec![EntityFieldEntry {
                    name: "weight".to_string(),
                    ty: AgentFieldTy::F32,
                }],
            },
        );
        catalog.groups.insert(
            7,
            EntityFieldRecord {
                entity_name: "Caravan".to_string(),
                fields: vec![EntityFieldEntry {
                    name: "size".to_string(),
                    ty: AgentFieldTy::F32,
                }],
            },
        );
        ctx.entity_field_catalog = catalog;
        ctx
    }

    fn lower_with_catalog(ast: &IrExprNode) -> Result<String, LoweringError> {
        let mut builder = CgProgramBuilder::new();
        let mut ctx = ctx_with_entity_catalog(&mut builder);
        let id = lower_expr(ast, &mut ctx)?;
        let prog = builder.finish();
        let node = &prog.exprs[id.0 as usize];
        Ok(crate::cg::expr::pretty(node, &prog.exprs))
    }

    #[test]
    fn items_weight_lowers_to_item_field_read() {
        // `items.weight(0u32)` resolves against the catalog's Coin /
        // weight entry → `Read(ItemField { entity: 5, slot: 0, ty:
        // F32 })`. The target expression (the literal `0u32`) is the
        // catalog index.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Items,
            method: "weight".to_string(),
            args: vec![arg(node(IrExpr::LitInt(0)))],
        });
        let s = lower_with_catalog(&ast).unwrap();
        assert!(
            s.starts_with("(read item[#5.0]"),
            "unexpected lowering: {s}"
        );
    }

    #[test]
    fn groups_size_lowers_to_group_field_read() {
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Groups,
            method: "size".to_string(),
            args: vec![arg(node(IrExpr::LitInt(0)))],
        });
        let s = lower_with_catalog(&ast).unwrap();
        assert!(
            s.starts_with("(read group[#7.0]"),
            "unexpected lowering: {s}"
        );
    }

    #[test]
    fn items_unknown_field_surfaces_typed_error() {
        // `items.bogus(0)` — no Coin field by that name.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Items,
            method: "bogus".to_string(),
            args: vec![arg(node(IrExpr::LitInt(0)))],
        });
        let err = lower_with_catalog(&ast).unwrap_err();
        assert!(matches!(
            err,
            LoweringError::UnsupportedNamespaceCall { .. }
        ));
    }

    #[test]
    fn items_with_non_id_arg_rejected() {
        // `items.weight(self.hp)` — arg is f32, not an id.
        let ast = node(IrExpr::NamespaceCall {
            ns: NamespaceId::Items,
            method: "weight".to_string(),
            args: vec![arg(field_self("hp"))],
        });
        let err = lower_with_catalog(&ast).unwrap_err();
        assert!(matches!(err, LoweringError::IllTypedExpression { .. }));
    }

    // ---- Vec3 strict-f32 typing ----

    #[test]
    fn vec3_with_three_f32_literals_lowers() {
        // vec3(1.0, 2.0, 3.0) — strict-f32 form, parses + lowers cleanly.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Vec3,
            vec![
                arg(node(IrExpr::LitFloat(1.0))),
                arg(node(IrExpr::LitFloat(2.0))),
                arg(node(IrExpr::LitFloat(3.0))),
            ],
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s,
            "(builtin.vec3 (lit 1.0f32) (lit 2.0f32) (lit 3.0f32))",
            "expected vec3(...) to lower as builtin.vec3, got {s:?}"
        );
    }

    #[test]
    fn vec3_with_int_literals_errors_with_helpful_message() {
        // Int literals widen to U32 in CG IR; the strict Vec3 typing
        // rule rejects the first non-f32 component with a helpful
        // Vec3RequiresF32 diagnostic.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Vec3,
            vec![
                arg(node(IrExpr::LitInt(1))),
                arg(node(IrExpr::LitInt(2))),
                arg(node(IrExpr::LitInt(3))),
            ],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::Vec3RequiresF32 {
                component_index,
                got,
                ..
            } => {
                assert_eq!(component_index, 0, "first non-f32 component is index 0");
                assert_eq!(got, CgTy::U32);
            }
            other => panic!("unexpected error: {other:?}"),
        }
    }

    #[test]
    fn vec3_diagnostic_renders_with_f32_hint() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Vec3,
            vec![
                arg(node(IrExpr::LitFloat(1.0))),
                arg(node(IrExpr::LitInt(2))),
                arg(node(IrExpr::LitFloat(3.0))),
            ],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        let msg = format!("{err}");
        assert!(
            msg.contains("vec3"),
            "diagnostic should name vec3, got: {msg}"
        );
        assert!(
            msg.contains("f32(...)"),
            "diagnostic should suggest f32(...) cast, got: {msg}"
        );
    }

    // ---- Explicit numeric casts ----

    #[test]
    fn f32_cast_of_u32_literal_lowers() {
        // f32(5) — int literal lowers to U32; F32Cast wraps it as
        // BuiltinId::AsF32(U32) emitting WGSL `f32(5u)`.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::F32Cast,
            vec![arg(node(IrExpr::LitInt(5)))],
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s, "(builtin.as_f32.u32 (lit 5u32))",
            "expected f32(<u32>) to lower as builtin.as_f32.u32, got {s:?}"
        );
    }

    #[test]
    fn f32_cast_of_i32_literal_lowers() {
        // f32(-3) — negative int picks I32; F32Cast wraps it as
        // BuiltinId::AsF32(I32).
        let ast = node(IrExpr::BuiltinCall(
            Builtin::F32Cast,
            vec![arg(node(IrExpr::LitInt(-3)))],
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(s, "(builtin.as_f32.i32 (lit -3i32))");
    }

    #[test]
    fn u32_cast_of_f32_literal_lowers() {
        // u32(1.5) — F32 source; lowers as BuiltinId::AsU32(F32).
        let ast = node(IrExpr::BuiltinCall(
            Builtin::U32Cast,
            vec![arg(node(IrExpr::LitFloat(1.5)))],
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(s, "(builtin.as_u32.f32 (lit 1.5f32))");
    }

    #[test]
    fn i32_cast_of_f32_literal_lowers() {
        let ast = node(IrExpr::BuiltinCall(
            Builtin::I32Cast,
            vec![arg(node(IrExpr::LitFloat(2.5)))],
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(s, "(builtin.as_i32.f32 (lit 2.5f32))");
    }

    #[test]
    fn f32_cast_of_f32_value_is_noop_rejected() {
        // f32(1.5) — no-op cast; surfaces as CastNoOp so authors can't
        // mask a type-inference mistake.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::F32Cast,
            vec![arg(node(IrExpr::LitFloat(1.5)))],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::CastNoOp { target, .. } => {
                assert_eq!(target, CgTy::F32);
            }
            other => panic!("unexpected error: {other:?}"),
        }
    }

    #[test]
    fn f32_cast_of_bool_rejected() {
        // f32(true) — non-numeric source; surfaces as CastNonNumericOperand.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::F32Cast,
            vec![arg(node(IrExpr::LitBool(true)))],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        match err {
            LoweringError::CastNonNumericOperand { target, got, .. } => {
                assert_eq!(target, CgTy::F32);
                assert_eq!(got, CgTy::Bool);
            }
            other => panic!("unexpected error: {other:?}"),
        }
    }

    #[test]
    fn f32_cast_arity_mismatch_rejected() {
        // f32(1, 2) — two args; surfaces as BuiltinArityMismatch.
        let ast = node(IrExpr::BuiltinCall(
            Builtin::F32Cast,
            vec![
                arg(node(IrExpr::LitInt(1))),
                arg(node(IrExpr::LitInt(2))),
            ],
        ));
        let err = lower_to_string(&ast).unwrap_err();
        assert!(
            matches!(err, LoweringError::BuiltinArityMismatch { .. }),
            "expected BuiltinArityMismatch, got: {err:?}"
        );
    }

    #[test]
    fn f32_cast_inside_vec3_works() {
        // vec3(f32(1), f32(2), f32(3)) — explicit casts in every slot;
        // each component lowers to as_f32 then feeds Vec3Ctor.
        let mk_cast = |v: i64| {
            node(IrExpr::BuiltinCall(
                Builtin::F32Cast,
                vec![arg(node(IrExpr::LitInt(v)))],
            ))
        };
        let ast = node(IrExpr::BuiltinCall(
            Builtin::Vec3,
            vec![arg(mk_cast(1)), arg(mk_cast(2)), arg(mk_cast(3))],
        ));
        let s = lower_to_string(&ast).unwrap();
        assert_eq!(
            s,
            "(builtin.vec3 \
             (builtin.as_f32.u32 (lit 1u32)) \
             (builtin.as_f32.u32 (lit 2u32)) \
             (builtin.as_f32.u32 (lit 3u32)))",
            "expected vec3(f32(1), f32(2), f32(3)) to lower with three as_f32 children, got {s:?}"
        );
    }
}
