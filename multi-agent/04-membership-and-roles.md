# 4. Membership and roles

This chapter covers which agents may join your system and what each may do
there. Membership decides which independently governed agents take part; a
role gives each a narrower responsibility in this composition. Membership is
an authorization boundary, not service discovery.

## Admitting a member

Before admission, every member MUST have:

- a valid, versioned Agent Spec;
- an accountable owner;
- a compatible execution class and approved governance tier;
- an unexpired agent risk assessment;
- typed inputs, dependencies, and outputs appropriate to its use;
- explicit skill and tool allowlists;
- required eval, observability, security, and production-readiness evidence;
  and
- a stable manifest or a reproducible manifest construction process.

These are the member's single-agent obligations (see the
[agent contract](../core/07-agent-contract.md) and
[production readiness](../core/12-production-readiness.md)). What
the system adds is the check: it MUST validate these requirements rather than
infer conformance from the presence of files.

## Static and dynamic membership

Production membership SHOULD be resolved before a run and recorded in the
composition manifest. Agents MUST NOT join solely because they are
discoverable through a registry, model context, MCP server, queue, network,
or user-supplied identifier.

Dynamic membership is appropriate when expertise, capacity, locality,
availability, or compatible substitution cannot be predicted economically at
deployment time. It trades reproducibility and a smaller trust surface for
adaptability, extensibility, and resilience.

If you use dynamic membership, you need:

- an authenticated registry and deterministic admission policy;
- allowed publishers, packages, versions, owners, and manifests;
- signature or integrity verification where applicable;
- compatibility, risk, capability, and data-residency checks;
- conservative per-run member and capability limits;
- a composition record identifying the exact admitted member; and
- additional supply-chain, substitution, and containment evals.

The system records a run manifest containing every dynamically admitted
member, version, manifest ID, assigned role, effective capability, policy
decision, and admission reason. Replaying or investigating the run MUST NOT
depend on the registry still returning the same result.

Admitting arbitrary model-generated code, prompts, endpoints, or agent names
is prohibited.

## Roles

A role defines one coherent system responsibility. Role names are stable,
lowercase, and hyphenated. Each role declares:

- purpose and non-goals;
- permitted callers and callees;
- accepted interaction modes;
- input and output contracts;
- maximum data classification;
- maximum delegable authorization scopes;
- tool and skill restrictions;
- budget and concurrency limits;
- required evidence and completion criteria;
- failure and escalation behavior; and
- owner.

Roles constrain agents; they do not grant new capability. The same agent MAY
fill multiple roles only when the System Spec declares each assignment and
evals cover the resulting loss of independence.

The common role names below are descriptive, not privileged. Use narrower
domain-specific names when they say more about the responsibility.

| Role | Responsibility | Prohibited assumption |
| --- | --- | --- |
| Coordinator | Propose bounded routing and synthesize results | Is not the deterministic orchestrator |
| Specialist | Perform one domain task | Does not inherit caller capabilities |
| Investigator | Gather and structure evidence | Does not decide authorization or truth alone |
| Producer | Create a candidate result | Does not self-approve |
| Reviewer | Evaluate against a rubric | Does not provide human approval or risk acceptance |
| Aggregator | Combine typed results | Does not treat agreement as correctness |
| Executor | Perform an approved action | Does not plan, approve, or expand the action |
| Monitor | Detect conditions and propose escalation | Does not take undeclared remediation action |

## Capability intersection

At run time, effective member capability is:

```text
member Agent Spec allowlist
    intersected with system member restrictions
    intersected with role restrictions
    intersected with authenticated actor and tenant policy
    intersected with current workflow state and approval
```

An empty intersection is a valid denial. The runtime MUST NOT fall back to the
member's broader default capability set.

Credentials follow the single-agent
[identity and authorization](../core/09-tools.md#identity-and-authorization)
rules, scoped to the interaction: they SHOULD be minted or selected for the
effective scope and lifetime of the interaction. Members MUST NOT receive the
coordinator's credentials, service identity, full user session, or unrelated
tenant context by default.

## Independence claims

Independent review and voting only help when the members fail differently.
A system claiming independent review, voting, or defense in depth MUST
document the relevant sources of independence, including:

- model and provider;
- instructions and context;
- data and evidence sources;
- tools and retrieval paths;
- implementation and owning team; and
- failure modes and deployment infrastructure.

Different agent names or personas do not establish independence. Shared
models, prompts, evidence, infrastructure, or owners can create correlated
failure and MUST be represented in risk and evaluation evidence.

## Substitution and fallback

A fallback member MUST be independently admitted and declared for the same
role. The substitution policy defines:

- conditions that permit substitution;
- compatible schemas and semantic behavior;
- differences in capability, model, data residency, risk, latency, and cost;
- whether approval or user disclosure is required;
- evaluation evidence for the fallback path; and
- telemetry and incident thresholds.

The system MUST NOT silently substitute a member that changes the effective
execution class, governance tier, authority, data handling, or consequential
behavior.

## Changing membership

Adding, removing, upgrading, restricting, or substituting a member is a
system behavior change, even if no line of system code changed. It requires:

- a system version change;
- composition-manifest regeneration;
- focused interaction and end-to-end evals;
- compatibility and replay review when workflows are active;
- risk reassessment for affected scenarios; and
- rollout and rollback plans.

In-flight durable workflows MUST remain pinned to a compatible composition or
migrate through a tested, explicit process.

## Quality gates

Member admission requires tests proving that:

- unknown or unpinned members are rejected;
- role restrictions cannot expand base capabilities;
- unauthorized callers and interaction modes are denied;
- tenant, actor, and data boundaries survive delegation;
- substitution follows the declared policy;
- removed or quarantined members cannot receive new work; and
- manifest and version mismatches fail closed.

## Common pitfalls

- **Discovery as admission.** An agent appeared in a registry or MCP server
  and started receiving work.
- **Falling back to defaults.** An empty capability intersection was treated
  as "use the agent's normal tools."
- **Personas counted as independent reviewers.** Two roles shared a model,
  prompt, and evidence, so they made the same mistakes.

## Before you move on

- [ ] Admission checks validate member evidence, not just file presence.
- [ ] Each role declares its restrictions, limits, and owner.
- [ ] An empty capability intersection denies the action.
- [ ] Any independence claim lists what is and is not shared.
