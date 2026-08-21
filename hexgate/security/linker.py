"""The linker — compose a bundle of policy modules into one effective policy.

The intermediate step between *many policy files* and *one signed WASM bundle*:

    [modules]  --link()-->  one AgentPolicy  --compile_to_rego-->  rego  -->  wasm

Composition lives here, at the model layer. The output is an ordinary
:class:`~hexgate.security.models.AgentPolicy` whose ``constraints`` are the same
strings the DSL already parses, so the pydantic-vs-WASM **parity gate applies to
the resolved policy for free** — the engines never see the stack.

Rules (see ``policy-modules-plan.md``): **fences intersect, grants union, denies
win.** Per ``(tool, args)`` the most restrictive layer wins:
``deny > approval_required > allow > implicit-deny``.

- **Boundary** — caps + hard denies. An unconditional deny is absolute. A
  ``default_policy: deny`` boundary is a *ceiling*: a tool it doesn't list is
  ineligible. Its ``allow`` entries are ceilings (permit up to a constraint),
  not grants.
- **Capability** — grants only (``allow`` / ``approval_required``). A capability
  ``deny`` is a :class:`LinkError`. Multiple capabilities granting one tool
  *union* (either condition suffices).

Constraint algebra reuses the existing DSL nodes: intersection is list
concatenation (``constraints: list[str]`` is implicit-AND), union is a top-level
``or`` expression, and a conditional boundary deny subtracts via ``and not(…)``.
Every assembled expression is re-parsed with :func:`parse_constraint` to validate
against the live grammar.
"""

from __future__ import annotations

from collections.abc import Mapping, Sequence

from hexgate.security.constraints import parse_constraint
from hexgate.security.models import (
    AgentPolicy,
    BaseToolPolicy,
    FileToolPolicy,
    ToolPolicy,
)
from hexgate.security.modules import (
    GRANT_MODES,
    LinkError,
    LinkResult,
    ModuleContent,
    ProjectLinkResult,
    Provenance,
    RuleTrace,
)
from hexgate.security.policy_set import DEFAULT_ROLE_NAME, PolicySet


def link_policy_set(
    boundaries: list[ModuleContent], capabilities: list[ModuleContent]
) -> LinkResult:
    """Fold a bundle into one effective :class:`PolicySet` + provenance.

    ``boundaries`` are the scope-inherited layers (caps/denies); ``capabilities``
    are the imported packs + the agent's inline leaf, in resolution order. This
    iteration folds into the single ``default`` role; per-role scoping is a
    follow-up.
    """
    effective, trace = link(boundaries, capabilities)
    policy_set = PolicySet({DEFAULT_ROLE_NAME: effective})
    layers = [_prov(m) for m in (*boundaries, *capabilities)]
    return LinkResult(
        policy_set=policy_set,
        effective={DEFAULT_ROLE_NAME: effective},
        layers=layers,
        trace=trace,
    )


def resolve_role_map(
    roles: Mapping[str, Sequence[str]] | None, library: list[ModuleContent]
) -> dict[str, list[ModuleContent]]:
    """Expand a role binding into ``{role: [capability modules]}``.

    The one place that defines role expansion, shared by the resolver and the
    analyzer so they can never lint a different role set than what compiles.

    ``roles is None`` (no ``roles.yaml``) means a single ``default`` importing
    every capability — the all-compose back-compat default. An **empty** binding
    (``{}``, a present-but-empty or typo'd ``roles.yaml``) is not the same: it
    yields a fail-closed empty ``default``, so a mistake can't silently widen
    access. A ``default`` bucket is always present. An unknown capability name is
    a :class:`LinkError` (same contract from both callers).
    """
    index: dict[str, ModuleContent] = {cap.name: cap for cap in library}
    if roles is None:
        names_by_role: dict[str, list[str]] = {
            DEFAULT_ROLE_NAME: [cap.name for cap in library]
        }
    else:
        names_by_role = {name: list(sel) for name, sel in roles.items()}
    names_by_role.setdefault(DEFAULT_ROLE_NAME, [])

    resolved: dict[str, list[ModuleContent]] = {}
    for role, cap_names in names_by_role.items():
        caps: list[ModuleContent] = []
        for name in cap_names:
            cap = index.get(name)
            if cap is None:
                raise LinkError(
                    f"role {role!r} imports unknown capability {name!r} "
                    f"(known capabilities: {sorted(index)!r})"
                )
            caps.append(cap)
        resolved[role] = caps
    return resolved


def resolve_for_project(
    boundaries: list[ModuleContent],
    library: list[ModuleContent],
    roles: Mapping[str, Sequence[str]] | None,
    *,
    agent_leaf: Sequence[ModuleContent] = (),
    agent_boundaries: Sequence[ModuleContent] = (),
) -> ProjectLinkResult:
    """Resolve a project into one role-keyed :class:`PolicySet`.

    Boundaries are role-independent: every role is folded against the same
    ``boundaries + agent_boundaries``, so a role can only ever narrow, never
    widen, its ceiling. A role names the **capabilities** it imports; the fold
    (:func:`link`) is reused unchanged, once per role.

    ``roles`` maps a role name to the capability *names* it selects (a name is a
    :attr:`ModuleContent.name`). ``None`` (no binding at all) means a single
    ``default`` role importing every capability — the all-compose back-compat
    path. A ``default`` role is always present, so unroled callers get
    fail-closed deny rather than a missing bucket.

    Every capability in the library is validated up front (:func:`_reject_capability_denies`),
    not just the ones a role imports, so a malformed but unbound module fails
    loudly instead of lurking until someone binds it.
    """
    _reject_capability_denies([*library, *agent_leaf])
    resolved = resolve_role_map(roles, library)
    fences = [*boundaries, *agent_boundaries]
    by_role: dict[str, LinkResult] = {}
    effective: dict[str, AgentPolicy] = {}
    for role, caps in resolved.items():
        result = link_policy_set(fences, [*caps, *agent_leaf])
        by_role[role] = result
        effective[role] = result.effective[DEFAULT_ROLE_NAME]

    return ProjectLinkResult(policy_set=PolicySet(effective), by_role=by_role)


def _reject_capability_denies(capabilities: Sequence[ModuleContent]) -> None:
    """A capability that denies is a config error, checked over the WHOLE library.

    The per-tool guard in :func:`_fold_tool` only runs for capabilities a role
    imports, so an unbound malformed module would slip through resolution. This
    is a per-module property (a capability tool with ``mode: deny``), so it is
    hoisted here and run over every capability, bound or not.
    """
    for cap in capabilities:
        for tool, tp in cap.policy.tools.items():
            if tp.mode == "deny":
                raise LinkError(
                    f"capability {cap.name!r} denies {tool!r}; capabilities may "
                    f"only grant — move the deny to a boundary ({cap.source})"
                )


def link(
    boundaries: list[ModuleContent], capabilities: list[ModuleContent]
) -> tuple[AgentPolicy, RuleTrace]:
    """Fold one role's layers into a single :class:`AgentPolicy`. Pure; no I/O."""
    _reject_file_scope(boundaries, capabilities)
    _reject_unsupported_module_fields(boundaries, capabilities)
    _reject_default_policy_constraints(boundaries, capabilities)
    consts = _merge_consts(boundaries, capabilities)

    trace = RuleTrace()
    tools: dict[str, ToolPolicy] = {}
    for name in _tool_names(boundaries, capabilities):
        rule = _fold_tool(name, boundaries, capabilities, trace)
        if rule is not None:
            tools[name] = rule

    # Effective default is fail-closed: a tool no layer grants is denied.
    effective = AgentPolicy(
        default_policy=BaseToolPolicy(mode="deny"), tools=tools, consts=consts
    )
    return effective, trace


def _merge_consts(
    boundaries: list[ModuleContent], capabilities: list[ModuleContent]
) -> dict[str, object]:
    """Merge consts across layers. A constant defined twice with **different**
    values is a hard :class:`LinkError`, never a silent last-wins.

    Two collisions matter: a capability redefining a boundary's constant would
    let a lower-authority layer loosen a cap like ``args.amount <= consts.max``;
    and two boundaries disagreeing on a value would silently pick one. Both are
    rejected. Equal values (or a name unique to one module) merge normally.
    """
    merged: dict[str, object] = {}
    owner: dict[str, ModuleContent] = {}
    owner_is_boundary: dict[str, bool] = {}

    def _put(module: ModuleContent, is_boundary: bool) -> None:
        for name, value in module.policy.consts.items():
            if name in merged and merged[name] != value:
                prev = owner[name]
                if owner_is_boundary[name] and not is_boundary:
                    raise LinkError(
                        f"capability {module.name!r} redefines boundary constant "
                        f"consts.{name} ({value!r} vs {merged[name]!r} from "
                        f"{prev.name!r}); capabilities may not override boundary "
                        f"constants ({module.source})"
                    )
                raise LinkError(
                    f"consts.{name} defined twice with conflicting values: "
                    f"{merged[name]!r} in {prev.name!r} vs {value!r} in "
                    f"{module.name!r} ({module.source})"
                )
            merged[name] = value
            owner[name] = module
            owner_is_boundary[name] = is_boundary

    for module in boundaries:
        _put(module, is_boundary=True)
    for module in capabilities:
        _put(module, is_boundary=False)
    return merged


def _reject_default_policy_constraints(
    boundaries: list[ModuleContent], capabilities: list[ModuleContent]
) -> None:
    """Reject ``default_policy.constraints`` in a module.

    The fold reads a boundary's ``default_policy.mode`` (to tell a ceiling from a
    floor) but the effective default is always fail-closed ``deny``, so any
    constraints on a module's ``default_policy`` would be silently dropped. The
    pydantic engine does enforce them in a single-file policy, so dropping them
    on a migration would quietly lose a fence. Fail loud instead; put the rule on
    a named tool.
    """
    for module in (*boundaries, *capabilities):
        if module.policy.default_policy.constraints:
            raise LinkError(
                f"module {module.name!r} sets default_policy constraints, which "
                f"module composition does not support (the effective default is "
                f"fail-closed deny); move the rule onto a named tool "
                f"({module.source})"
            )


def _reject_file_scope(
    boundaries: list[ModuleContent], capabilities: list[ModuleContent]
) -> None:
    """Reject ``file_scope`` in a module — composing it isn't supported yet.

    Silently dropping it in the fold would erase a path fence (``file_scope`` is
    enforced by the pydantic engine), so fail loud instead. Keep file-scoped
    tools in a single-file policy until module composition supports them.
    """
    for module in (*boundaries, *capabilities):
        for tool_name, tp in module.policy.tools.items():
            if isinstance(tp, FileToolPolicy) and tp.file_scope is not None:
                raise LinkError(
                    f"module {module.name!r} tool {tool_name!r} uses file_scope, "
                    f"which module composition does not support yet — keep it in a "
                    f"single-file policy or drop file_scope ({module.source})"
                )


# The AgentPolicy fields the fold understands. Anything else a module sets is
# rejected by _reject_unsupported_module_fields, so a field added to AgentPolicy
# later fails closed here instead of being silently dropped by _fold_tool.
_MODULE_COMPOSABLE_FIELDS = frozenset(
    {"version", "inherits", "is_mixin", "default_policy", "tools", "consts"}
)


def _reject_unsupported_module_fields(
    boundaries: list[ModuleContent], capabilities: list[ModuleContent]
) -> None:
    """Reject any top-level AgentPolicy field a module sets that the fold does not
    compose (today: ``admission`` / ``agents``; tomorrow: whatever is added next).

    ``_fold_tool`` reads only ``.tools``, so an un-composed field would be silently
    dropped, erasing a rule an operator authored — the same fail-open
    :func:`_reject_file_scope` guards against, generalized. Allowlisting the fields
    the fold understands means a new AgentPolicy field is rejected automatically
    until composition learns it, rather than shipping fail-open by omission."""
    for module in (*boundaries, *capabilities):
        extra = module.policy.model_fields_set - _MODULE_COMPOSABLE_FIELDS
        if extra:
            raise LinkError(
                f"module {module.name!r} sets {sorted(extra)}, which module "
                f"composition does not support (the fold composes only tools); "
                f"keep it in a single-file policy ({module.source})"
            )


def _fold_tool(
    tool: str,
    boundaries: list[ModuleContent],
    capabilities: list[ModuleContent],
    trace: RuleTrace,
) -> ToolPolicy | None:
    """Resolve one tool across all layers. ``None`` means implicit-deny (omit)."""
    # Capabilities may only grant. A capability deny is a config error.
    for cap in capabilities:
        tp = cap.policy.tools.get(tool)
        if tp is not None and tp.mode == "deny":
            raise LinkError(
                f"capability {cap.name!r} denies {tool!r}; capabilities may only "
                f"grant — move the deny to a boundary ({cap.source})"
            )

    # 1. Unconditional boundary deny wins absolutely. A *conditional* deny
    #    (has constraints) instead subtracts its region from the grant (step 5).
    conditional_denies: list[tuple[ModuleContent, list[str]]] = []
    for g in boundaries:
        tp = g.policy.tools.get(tool)
        if tp is not None and tp.mode == "deny":
            if tp.constraints:
                conditional_denies.append((g, list(tp.constraints)))
            else:
                trace.record(tool, [_prov(g)])
                return BaseToolPolicy(mode="deny")

    # 2. Ceiling eligibility + ceiling constraints. A ceiling boundary
    #    (default_policy: deny) that doesn't list the tool makes it ineligible.
    contributors: list[Provenance] = []
    ceiling_constraints: list[str] = []
    for g in boundaries:
        tp = g.policy.tools.get(tool)
        is_ceiling = g.policy.default_policy.mode == "deny"
        if tp is not None and tp.mode in GRANT_MODES:
            ceiling_constraints.extend(tp.constraints)  # fences intersect (AND)
            contributors.append(_prov(g))
        elif is_ceiling and (tp is None or tp.mode not in GRANT_MODES):
            # A ceiling only permits tools it explicitly allows/approves. If it
            # doesn't (unlisted, or mentioned only via a conditional deny), the
            # tool is ineligible — a capability grant can't make it eligible.
            trace.shadow(tool, _prov(g))
            return None

    # 3+4. Capability grants. No grant → eligible but ungranted → implicit deny.
    grants: list[tuple[ModuleContent, ToolPolicy]] = []
    for cap in capabilities:
        tp = cap.policy.tools.get(tool)
        if tp is not None and tp.mode in GRANT_MODES:
            grants.append((cap, tp))
    if not grants:
        return None
    contributors.extend(_prov(cap) for cap, _ in grants)

    mode = (
        "approval_required"
        if _any_approval([tp for _, tp in grants], boundaries, tool)
        else "allow"
    )

    # 5. effective = ceiling(AND) ∧ union(grants) ∧ not(conditional denies)
    constraints: list[str] = list(ceiling_constraints)
    union = _union([tp for _, tp in grants])
    if union is not None:
        constraints.append(union)
    for g, region in conditional_denies:
        constraints.append(f"not ({_and_expr(region)})")
        contributors.append(_prov(g))

    for expr in constraints:  # validate the assembled grammar on both engines
        parse_constraint(expr)
    trace.record(tool, contributors)
    return BaseToolPolicy(mode=mode, constraints=constraints)


def _union(grants: list[ToolPolicy]) -> str | None:
    """OR the capability grants into one expression.

    Returns ``None`` when any grant is unconditional (empty constraints) — an
    unconditional grant makes the whole union unconditional, so no constraint is
    emitted for it.
    """
    exprs: list[str] = []
    for tp in grants:
        if not tp.constraints:
            return None
        exprs.append(_and_expr(tp.constraints))
    # One grant needs no OR wrapper; multiple are parenthesised and OR-joined.
    joined = exprs[0] if len(exprs) == 1 else " or ".join(f"({e})" for e in exprs)
    parse_constraint(joined)  # fail loud on assembled grammar we can't parse
    return joined


def _and_expr(constraints: list[str]) -> str:
    """A tool's constraint list → one parenthesised AND-expression."""
    return " and ".join(f"({c})" for c in constraints)


def _any_approval(
    grants: list[ToolPolicy], boundaries: list[ModuleContent], tool: str
) -> bool:
    """Approval is stricter than allow: any approval among grants/ceilings wins."""
    if any(tp.mode == "approval_required" for tp in grants):
        return True
    return any(
        (tp := g.policy.tools.get(tool)) is not None and tp.mode == "approval_required"
        for g in boundaries
    )


def _tool_names(*groups: list[ModuleContent]) -> list[str]:
    names: set[str] = set()
    for group in groups:
        for module in group:
            names.update(module.policy.tools)
    return sorted(names)


def _prov(module: ModuleContent) -> Provenance:
    return Provenance(
        module=module.name,
        kind=module.kind,
        source=module.source,
        content_hash=module.content_hash,
    )
