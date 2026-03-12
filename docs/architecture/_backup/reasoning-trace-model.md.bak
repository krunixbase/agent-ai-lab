# Reasoning Trace Model

## Overview

The reasoning trace model defines how the agent internally represents, structures, and manages its reasoning process across single‑step and multi‑step tasks. The model ensures that the agent maintains a coherent internal chain of decisions without exposing sensitive chain‑of‑thought details to the user. It provides a structured way to track planner decisions, tool calls, intermediate results, and state transitions.

Reasoning traces are essential for debugging, transparency, planner continuity, and safe multi‑step execution.

---

## Purpose of the Reasoning Trace

- maintain continuity across multi-step plans,
- track dependencies between steps,
- support planner–LLM coordination,
- enable safe recovery after errors,
- provide internal transparency without leaking chain‑of‑thought,
- allow post‑execution analysis and optimization.

The reasoning trace is **never exposed directly to the user**.

---

## Trace Components

### Step Metadata
Each reasoning step includes:
- step ID,
- step type (LLM, tool, planner),
- timestamp,
- originating planner state.

### Input Context
The trace stores:
- user input snapshot,
- memory context used,
- planner instructions,
- relevant retrieved data.

### Action Record
Describes what the agent attempted:
- tool call details,
- LLM output schema type,
- planner decision type,
- expected next step.

### Intermediate Results
Captures:
- tool outputs,
- LLM structured outputs,
- validation results,
- safety filtering outcomes.

### State Transitions
Tracks how the agent’s internal state changed:
- planner state updates,
- memory updates,
- session boundary effects,
- error recovery actions.

---

## Trace Lifecycle

### 1. Step Initialization
The planner creates a new trace entry when:
- a new plan begins,
- a tool call is issued,
- the LLM is invoked,
- a state transition occurs.

### 2. Context Capture
The agent records:
- memory used,
- user message,
- planner context,
- system instructions.

### 3. Action Execution
The trace logs:
- tool execution attempt,
- LLM output,
- validation results.

### 4. Result Integration
The agent stores:
- normalized tool results,
- validated LLM outputs,
- planner decisions.

### 5. State Update
The trace records:
- updated planner state,
- memory writes,
- session boundary effects.

### 6. Finalization
When the turn ends, the trace entry is closed and stored in episodic memory (internal only).

---

## Trace Structure Diagram

```
┌──────────────────────────┐
│     Step Initialization   │
└─────────────┬────────────┘
│
▼
┌──────────────────────────┐
│      Context Capture      │
└─────────────┬────────────┘
│
▼
┌──────────────────────────┐
│      Action Execution     │
└─────────────┬────────────┘
│
▼
┌──────────────────────────┐
│     Result Integration    │
└─────────────┬────────────┘
│
▼
┌──────────────────────────┐
│       State Update        │
└─────────────┬────────────┘
│
▼
┌──────────────────────────┐
│        Finalization       │
└──────────────────────────┘
```

---

## Trace Storage Model

### Short‑Term Trace
Used during the current turn:
- supports planner continuity,
- enables multi-step execution,
- allows error recovery.

### Long‑Term Trace
Stored in internal episodic memory:
- used for debugging,
- supports meta‑reasoning,
- never exposed to the user.

### Summary Trace
A compressed version used for:
- session summaries,
- planner optimization,
- performance metrics.

---

## Safety Considerations

- chain‑of‑thought is never exposed,
- sensitive data is filtered before storage,
- traces are internal and not user‑visible,
- only structured outputs are stored, not raw reasoning,
- error traces avoid leaking internal logic.

---

## Design Principles

### Internal Transparency
The agent maintains a complete internal record of reasoning steps.

### External Safety
The user receives only final answers or structured outputs, never raw reasoning.

### Deterministic Structure
All traces follow the same schema for consistency.

### Extensibility
New planner types or tool workflows can add trace fields without breaking existing logic.

### Debuggability
Traces allow developers to analyze failures, loops, or inefficiencies.

---

## Future Extensions

- reasoning trace visualization tools,
- automated trace‑based optimization,
- anomaly detection in reasoning patterns,
- cross‑session reasoning analytics,
- trace‑driven planner adaptation.

