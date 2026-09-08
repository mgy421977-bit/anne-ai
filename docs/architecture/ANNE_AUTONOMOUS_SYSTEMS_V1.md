# ANNE Autonomous Systems Architecture V1

**Status:** ARCHITECTURE / EXPERIMENTAL IMPLEMENTATION TARGET  
**Version:** 1.1  
**Date:** 2026-09-06

## 1. Purpose

This document defines ANNE as an executive cognitive system and MITOS as its subconscious-inspired exploration layer. MITOS can create bounded specialist research agents, but those agents never inherit executive authority.

The central distinction is:

> **MITOS explores. Specialist agents investigate. ANNE evaluates and decides. Autonomous systems execute within contracts.**

The human-subconscious analogy is architectural, not a neuroscientific claim: MITOS represents functions such as associative exploration, curiosity, alternative generation, counterfactual search and offline hypothesis formation.

## 2. Cognitive / Subconscious Separation

```text
                         ANNE
              EXECUTIVE / CONSCIOUS LAYER
                           │
             goals · values · reasoning · choice
                           │
                           ▼
                         MITOS
              SUBCONSCIOUS-INSPIRED LAYER
                           │
       ┌───────────────────┼───────────────────┐
       │                   │                   │
   associations         hypotheses         questions
   alternatives         simulations        curiosity
       │                   │                   │
       └───────────────────┼───────────────────┘
                           │
                    RESEARCH SWARM
                           │
             ┌─────────────┼─────────────┐
             ▼             ▼             ▼
          PHYSICS       CHEMISTRY    LITERATURE
             │             │             │
             └─────────────┼─────────────┘
                           ▼
                    EVIDENCE PACKAGES
                           ▼
                    MITOS SYNTHESIS
                           │
                           ▼
                          ANNE
```

MITOS may produce an idea that ANNE would not have generated directly. That idea is still only a hypothesis until evidence supports it.

MITOS therefore has **creative freedom in search space but bounded freedom in execution**.

## 3. Dynamic Research Swarm

MITOS does not require a permanently running fixed set of agents. It creates temporary specialist workers only when the current problem justifies them.

Typical roles include:

```text
CHEMISTRY
PHYSICS
PATENT / LITERATURE
ECONOMICS
SIMULATION
MANUFACTURING
RISK
CUSTOM SPECIALIST
```

A future problem can require one specialist or many. Agent count is governed by explicit resource budgets.

```text
MITOS
  ↓
RESEARCH PLAN
  ↓
RESOURCE GOVERNOR
  ↓
AGENT FACTORY
  ↓
SPECIALIST AGENTS
```

A specialist agent may access the internet or approved tools when its mission contract permits it. MITOS itself does not receive unrestricted network authority merely because its workers do.

## 4. Agent Constitution

Every research agent receives a machine-readable mission contract:

```text
mission
scope
role
allowed_tools
forbidden_actions
search_budget
compute_budget
runtime_budget
output_schema
success_metrics
stop_conditions
provenance
```

Mandatory restrictions include:

- no external side effects;
- no credential access;
- no system modification;
- no financial transactions;
- no self-authorized agent creation.

An agent may report that another specialist is needed. It cannot create that specialist itself.

## 5. Evidence Boundary

Agents return **EvidencePackage** records rather than unrestricted prose authority.

A package can contain:

```text
claim
source
method / provenance
confidence
uncertainty
contradictions
open_questions
simulation_results
```

Simulation output is explicitly distinguishable from observed reality.

MITOS synthesis may mark a finding as `HYPOTHESIS` or `CROSS_CHECKED`, but it cannot silently promote it to established fact.

## 6. MITOS Synthesis Loop

```text
MASTER QUESTION
      ↓
DECOMPOSE
      ↓
CREATE BOUNDED MISSIONS
      ↓
SPECIALIST RESEARCH
      ↓
EVIDENCE PACKAGES
      ↓
MITOS SYNTHESIS
      ↓
CONTRADICTION / GAP ANALYSIS
      ↓
 ┌────┴────┐
 │         │
DONE     MORE RESEARCH
 │         │
 ▼         └──────────────→ NEW MISSIONS
ANNE
```

MITOS can recursively deepen research through new missions, but every generation remains bounded by the resource governor and the supervising policy layer.

## 7. Resource Governance

The exploration space is intentionally broad; the execution budget is not.

```text
agent_count_limit
search_budget
compute_budget
runtime_budget
memory_budget
network/tool budget
storage budget
risk budget
```

Budget exhaustion causes a stop, rejection, or escalation. It cannot trigger silent resource expansion.

This principle is fundamental:

> **MITOS has broad epistemic freedom, not unlimited computational or operational freedom.**

## 8. ANNE as Executive System Architect

ANNE evaluates MITOS synthesis, chooses objectives, applies value and safety constraints, and can design autonomous systems for bounded missions.

```text
GOAL
 ↓
MITOS RESEARCH
 ↓
SYNTHESIS
 ↓
ANNE EVALUATION
 ↓
SYSTEM DESIGN
 ↓
VERIFICATION
 ↓
SAFETY / POLICY GATE
 ↓
AUTONOMOUS SYSTEM INSTANCE
```

ANNE owns consequential authorization. MITOS cannot authorize external action.

## 9. Autonomous System Supervision

After deployment, ANNE can step back from operational control and observe:

```text
SYSTEM INSTANCE
      │
      ├── telemetry
      ├── outcomes
      ├── errors
      ├── resource use
      ├── safety events
      └── performance
             ↓
           ANNE
```

The step back is **supervisory autonomy**, not abandonment.

ANNE maintains expected behavior, actual behavior, baseline metrics, safety state, resource state, drift indicators and unresolved anomalies.

## 10. Continuous Optimization

```text
OBSERVE
   ↓
MEASURE
   ↓
DIAGNOSE
   ↓
MITOS GENERATES ALTERNATIVES
   ↓
SIMULATE
   ↓
SHADOW TEST
   ↓
COMPARE WITH BASELINE
   ↓
VERIFY
   ↓
CANARY
   ↓
PROMOTE / REJECT
```

Optimization may target routing, model selection, agent topology, memory retrieval, planning strategy, compute allocation, latency, accuracy, reliability or energy use.

No candidate is promoted solely because MITOS predicts improvement.

## 11. Safe Self-Improvement

The preferred progression is:

```text
CONFIGURATION
 ↓
ROUTING
 ↓
PARAMETERS
 ↓
AGENT TOPOLOGY
 ↓
ALGORITHM SELECTION
 ↓
CONTROLLED CODE CHANGE
```

Every change is versioned, isolated, measurable, reversible, provenance-tracked and safety-checked.

The active known-good version remains available until a candidate passes verification.

## 12. Multi-Topic Research Example: Göçebe

For an open-ended project such as Göçebe, MITOS can dynamically form a research swarm:

```text
GÖÇEBE MASTER QUESTION
          │
          ▼
        MITOS
          │
 ┌────────┼─────────┬──────────┐
 ▼        ▼         ▼          ▼
PHYSICS  ENERGY   MATERIALS   BIOLOGY
 │        │         │          │
 ▼        ▼         ▼          ▼
WARP     FUSION    RADIATION  LIFE SUPPORT
 │        │         │          │
 └────────┴─────────┴──────────┘
          │
          ▼
     CROSS-CHECK
          │
          ▼
       MITOS
          │
          ▼
        ANNE
```

If MITOS identifies a missing discipline, it requests a new bounded specialist mission. It does not grant itself unrestricted capability.

For questions such as effective superluminal travel, MITOS is allowed to investigate unconventional hypotheses. The system must preserve the distinction between mathematical consistency, simulation, literature evidence, experimental observation and established physical fact.

## 13. Lifecycle

Research agents:

```text
PROPOSED → AUTHORIZED → RUNNING → REPORTING → COMPLETED → ARCHIVED
```

Exceptional states:

`BLOCKED | FAILED | TIMEOUT | CANCELLED`

Autonomous systems:

```text
DESIGN → VERIFY → BUILD → SANDBOX → AUTHORIZE → DEPLOY
                                                   ↓
                                                OBSERVE
                                                   ↓
                                               OPTIMIZE
                                                   ↓
                                               VERIFY
                                                   ↓
                                         PROMOTE / REJECT
```

## 14. Autonomy Levels

- **A0 Assisted:** ANNE proposes; human executes.
- **A1 Sandboxed:** execution is confined to simulation/local environments.
- **A2 Bounded autonomous:** a real system operates inside explicit limits.
- **A3 Supervisory autonomous:** deployed systems operate for extended periods while ANNE observes and optimizes.
- **A4 Adaptive ecosystem:** multiple autonomous systems coordinate under a supervisory architecture.

Higher autonomy requires stronger evidence and safety controls.

## 15. Core Principle

> **MITOS represents the exploratory subconscious of ANNE: it searches beyond the obvious, creates hypotheses, forms bounded research swarms and brings evidence back. ANNE remains the executive layer that evaluates, values, verifies and decides.**

And operationally:

> **MITOS explores many possibilities. Specialist agents investigate within contracts. MITOS synthesizes the evidence. ANNE assembles the best system it can justify. The autonomous system executes its mission. ANNE observes the consequences. MITOS searches for improvements. ANNE verifies them. Only proven improvements replace the current system.**