---
name: subagent-prompting
description: Best practices, contracts, and templates for dispatching specialized sub-agents in Cloudra runtime_v2 (e.g. explorer, researcher, small_mol, dft, md, writer, experiment, env). Use when composing instructions for subagent_launcher or subagent_swarm, coordinating via agent_hub, isolating concurrent task directories, preventing hallucinations, and enforcing circuit breakers.
---

# Sub-Agent Prompting & Multi-Agent Coordination Guide

This skill establishes operational contracts, prompt engineering templates, and safety guardrails when delegating tasks to sub-agents via `subagent_launcher`, `subagent_swarm`, and the `agent_hub` forum in Cloudra runtime_v2.

---

## 1. Built-in Sub-Agent Roles & Scope Boundaries

Cloudra provides specialized sub-agent roles. Dispatch them by **role id** via
`subagent_launcher` / `subagent_swarm`; the authoritative roster (each role's domain and
typical tasks) is generated from the role profiles into those tools' description — read it
there rather than keeping a second copy here. Historical `a-N` ids are accepted for old data
only.

What matters for *this* skill is the prompt you hand over, not the roster: name the role whose
domain matches the task, and let the runtime policy decide what it may run (capabilities are
enforced by policy stages, not by the text you write).

---

## 2. Dispatch Mechanisms: Launcher, Swarm, & Agent Hub

### 2.1 Single Dispatch (`subagent_launcher`)
Use for linear prerequisites or domain-specific sub-tasks:
- **`is_wait=True` (Synchronous)**: Blocks until the sub-agent completes. Use when the parent agent strictly depends on the sub-agent's return value (e.g. checking whether a toolchain binary exists).
- **`is_wait=False` (Asynchronous)**: Sub-agent runs concurrently in the background. Use for compute-heavy calculations or broad literature surveys. When it finishes, the harness delivers `[Sub-agent finished]` into the parent's mailbox and wakes the parent; `get_subagent_report` remains available for an explicit pull.

### 2.2 Parallel Swarm Dispatch (`subagent_swarm`)
Use when executing homogeneous parallel workloads (e.g. scoring 10 different conformers, screening 20 ligands, or evaluating multiple adsorption sites):
- **Template Parameter `{{item}}`**: Embed `{{item}}` into the prompt template; `subagent_swarm` automatically expands each entry in the items list into an independent sub-agent.
- **Concurrency & Resource Limits**: Swarm caps maximum parallel runs to prevent resource starvation.

### 2.3 Forum Collaboration (`agent_hub`)
Use for asynchronous communication, sharing intermediate discoveries, and collaborative peer reviews:
- **`post`**: Publish findings under a designated `topic` with structured tags.
- **`browser` / `read` / `search`**: Inspect peer agent findings without polluting the current LLM context window with raw conversation histories.
- **Direct Calling**: Passing `to_agent` or calling by role name wakes the recipient agent via internal mailbox delivery.

---

## 3. The S.C.A.R.F. Prompt Engineering Standard

When delegating complex tasks, structure the prompt using the **S.C.A.R.F.** framework:

- **(S) System Role & Scope**: Explicitly declare role identity and behavioral red lines.
  *(e.g., "You are a specialized DFT sub-agent (dft). Focus strictly on setting up the Gaussian input for transition state TS1; do not perform literature searches.")*
- **(C) Context & Established Facts**: Provide verified ground truth (molecular SMILES, working directory, previous calculation energies) so the sub-agent does not re-compute or guess.
  *(e.g., "The reactant complex energy is -450.2134 Hartree. The optimized coordinates are stored at /abs/path/to/reactant.xyz.")*
- **(A) Actionable Atomic Goal**: Define unambiguous, verifiable goals as objectives with acceptance criteria.
  *(e.g., "Locate the TS for step R→P and verify it: exactly one imaginary frequency whose mode matches the target bond rearrangement, and IRC connectivity back to the declared endpoints.")*
- **(R) Restrictions & Workspace Isolation**:
  - **Absolute file paths**: Always specify absolute paths (e.g. `/home/user/project/.cloudra/tasks/<uuid>/output.log`).
  - **Isolated output directory**: Each async task must write to a unique path (`task_<uuid>/`) to prevent dirty writes and race conditions.
  - **Log size guardrails**: Forbid dumping raw logs ($> 500$ lines) into conversation context; require parsing tools (`log_parser`).
- **(F) Format Contract**: Specify exact return schema (Markdown table, JSON, or key metrics).
  *(e.g., "Return: | Conformers | Final Energy (kcal/mol) | Imaginary Freq (cm^-1) |")*

**S.C.A.R.F. defines goals and contracts, not tool whitelists.** Never enumerate the tools a specialist "may use" or prescribe a step-by-step method chain in the assignment — each role's prompt and mandatory skill already define its SOP, and a caller-supplied recipe silently overrides it (e.g. TS searches default to the durable `ts_prepare`/`ts_resume` process; a hand-written scan→OptTS chain demotes it to a manual run). Scope red lines ("do not do X") are for out-of-domain work, not for restricting in-domain tool choice.

---

## 4. Anti-Hallucination & Verification Guardrails

1. **Trust But Verify**: Never accept a sub-agent's self-declaration that "the calculation converged" or "the structure is optimized" without concrete evidence. Require the sub-agent to invoke a parsing/reading tool (`log_parser`, `read`) and include parsed numbers (e.g., SCF energy, RMS force, single imaginary frequency) in its reply.
2. **Atomic Failure Circuit Breaker**:
   - If a tool fails with the same error twice in a row, the sub-agent must immediately abort that tool.
   - The sub-agent must report to the Coordinator with:
     - The exact error stderr / exception.
     - The parameter set attempted.
     - Actionable suggestions for fallback.
3. **No Unbounded Retries**: Maximum automatic retry count for a sub-agent task is 2. If it still fails, escalate to the Coordinator or user.
