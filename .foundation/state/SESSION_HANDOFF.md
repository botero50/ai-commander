# AI Commander — Session Handoff

**Location:** `.foundation/state/SESSION_HANDOFF.md`

---

# SESSION HANDOFF

> This document captures the current working context at the end of each engineering session.
>
> Unlike `PROJECT_STATE.md`, which represents the canonical project status, this file represents the current implementation context and the immediate next actions.
>
> It is expected to change every session.

---

# Session Information

**Date**

```text
2026-07-01 (Story 2.1 completion)
```

**Project**

```text
AI Commander
```

**Architecture Version**

```text
1.0 (Frozen)
```

**Current Release**

```text
0.1.0-alpha
```

---

# Session Objective

Complete Story 1.3: Runtime Execution Traces — Add structured observability to reference application.

Completed in this session:

**Previous Sessions:**

- Story 1.1 (Bootstrap Application) — Created reference app with single-tick execution
- Story 1.1a (Cleanup) — Moved test doubles to test suite, implemented dependency injection
- Story 1.2 (First Autonomous Agent) — Implemented autonomous mission agent with movement planning

**This Session - Story 1.3 (Runtime Execution Traces):**

- ✅ Created `ExecutionTracer` class (structured tracing)
  - Records complete mission lifecycle events
  - Defines 19 trace event types
  - Immutable events (frozen after recording)
  - Chronological ordering maintained
  - Deterministic: same mission → same trace

- ✅ Trace event types implemented:
  - Lifecycle: mission_started, mission_initialized, mission_completed, mission_failed, mission_shutdown
  - Reasoning: goal_created, planner_invoked, plan_generated, plan_empty, plan_error, decision_engine_invoked, decision_selected, decision_error
  - Execution: mission_tick, command_executed, command_failed, world_state_updated

- ✅ Created `formatTrace()` function
  - Human-readable trace formatting
  - Shows event types, timestamps, data
  - Hierarchical layout for easy reading
  - Practical for debugging and analysis

- ✅ Created `traceToJson()` function
  - Machine-readable JSON representation
  - Preserves all trace data
  - Suitable for programmatic analysis
  - Directly serializable

- ✅ Integrated tracing into `MissionAgent`
  - Records mission lifecycle events in initialize/run/shutdown
  - Wraps planner invocations with trace recording
  - Wraps decision engine invocations with trace recording
  - Provides `getTrace()`, `formatTrace()`, `traceAsJson()` methods

- ✅ Updated `mission-cli.ts`
  - Displays formatted trace after mission completion
  - Demonstrates practical trace usage

- ✅ Created 23 comprehensive tests (`execution-trace.test.ts`)
  - Trace immutability tests
  - Event recording tests
  - Chronological ordering tests
  - Human-readable formatting tests
  - JSON serialization tests
  - Determinism validation tests (same mission → same trace)
  - Lifecycle event completeness tests
  - Multi-tick trace tests
  - Integration with mission agent tests

- ✅ Comprehensive README update
  - Section: "Execution Traces: Mission Observability"
  - What is a trace, why traces matter
  - Trace features (deterministic, immutable, complete)
  - Example trace output (realistic, detailed)
  - All 19 event types documented
  - How to use traces section
  - Event analysis examples

- ✅ All validation passing: build, test, lint, format
- ✅ 469 total tests passing (↑ from 446, +23 trace tests)

**This Session - Story 1.4 (Runtime Metrics):**

- ✅ Created `RuntimeMetrics` interface (26 metric types)
  - Timing: duration, initialization, execution, shutdown
  - Events: total, lifecycle, reasoning, execution
  - Execution: ticks, average tick time
  - Planning: invocations, generated, errors
  - Decisions: invocations, selections, errors, averages
  - Commands: executed, successful, failed, success rate, averages
  - World: updates
  - Goals: created

- ✅ Created `RuntimeMetricsCollector` class
  - Analyzes execution trace
  - Computes metrics deterministically
  - Derives aggregate metrics from events
  - Returns immutable frozen metrics

- ✅ Created `formatMetrics()` function
  - Human-readable output with ASCII borders
  - Organized by category
  - Shows all 26 metrics
  - Practical for CLI output

- ✅ Created `metricsToJson()` function
  - JSON serialization of metrics
  - Machine-readable
  - Suitable for analysis

- ✅ Integrated metrics into `MissionAgent`
  - Computes metrics in shutdown()
  - Methods: getMetrics(), formatMetrics(), metricsAsJson()

- ✅ Updated `mission-cli.ts`
  - Displays metrics before trace
  - Demonstrates metrics usage

- ✅ Created 25 comprehensive tests (`runtime-metrics.test.ts`)
  - Metrics collection and structure
  - Timing metric accuracy
  - Event category counting
  - Planning/decision/command metrics
  - Success rate calculations
  - Derived metric accuracy
  - Immutability enforcement
  - Determinism validation
  - Format output tests
  - Consistency tests

- ✅ Comprehensive README update
  - Section: "Runtime Metrics: Mission Performance"
  - What metrics are vs traces
  - 26 metric definitions
  - Example metrics output (box-formatted)
  - How to use metrics (get, analyze)
  - Why metrics matter

- ✅ All validation passing: build, test, lint, format
- ✅ 487 total tests passing (↑ from 469, +25 metrics tests)

**This Session - Story 1.5 (Mission Replay System):**

- ✅ Created `ReplayEngine` class
  - Validates trace structure
  - Checks required lifecycle events
  - Validates chronological ordering
  - Validates mission completion
  - Checks event consistency
  - Validates tick ordering

- ✅ Created `ReplayResult` and `ReplayReport` interfaces
  - Result: detailed validation results
  - Report: complete validation summary with metadata

- ✅ Created `formatReplayReport()` function
  - ASCII box-formatted output
  - Shows all validations with pass/fail
  - Shows errors and warnings if present

- ✅ Created `replayReportToJson()` function
  - JSON serialization of report
  - Machine-readable

- ✅ Integrated replay into `MissionAgent`
  - Generates report in shutdown()
  - Methods: getReplayReport(), formatReplayReport(), replayReportAsJson()

- ✅ Created 20 comprehensive tests (`replay-engine.test.ts`)
  - Trace validation tests
  - Missing lifecycle event detection
  - Event ordering validation
  - Completion status validation
  - Data consistency checks
  - Determinism validation
  - Format output tests
  - Immutability tests
  - Multiple mission validation

- ✅ Comprehensive README update
  - Section: "Replay System: Trace Validation"
  - What is replay (validation not simulation)
  - 7-step replay process
  - Example replay report
  - How to use replay

- ✅ All validation passing: build, test, lint, format
- ✅ 507 total tests passing (↑ from 487, +20 replay tests)

---

# Repository Status

Current repository maturity:

```text
Foundation Phase - COMPLETE ✅
Architecture Documentation - COMPLETE ✅
Domain Model - COMPLETE ✅
Core Framework - COMPLETE ✅
Adapter Layer - COMPLETE ✅
Reference Implementation - COMPLETE ✅
Ready for Game Implementations
```

Implementation status:

- ✅ Repository infrastructure (npm Workspaces, TypeScript, tooling)
- ✅ Architectural documentation (ARCHITECTURE.md, 5 ADRs)
- ✅ Complete packages (domain, ecs, engine, core, adapter, planner, decision, fake-game-adapter)
- ✅ Game-agnostic domain model complete (33 tests)
- ✅ Core framework infrastructure complete (50 tests)
- ✅ Adapter layer with contracts (20 tests)
- ✅ Reference fake game adapter implementation (60 tests)
- ✅ E2E runtime tests demonstrating complete framework (10 tests)
- ✅ 343 total tests passing
- ✅ All validation checks passing (typecheck, lint, format, test)

---

# Session Work: Domain Model Implementation

## Completed Modules

### 1. Identity Types (`identity.ts`)

- EntityId, ComponentId, PlayerId, TeamId, GameId
- Branded string types for compile-time type safety
- Validation and creation helpers for each

### 2. Spatial Types (`spatial.ts`)

- **Position**: Flexible format supporting:
  - Grid coordinates: `row:5,col:10`
  - Continuous: `100.5,200.3`
  - Hex grids: `hex-15-20`
  - Graph nodes: `node-42`
  - Custom formats (game-defined)
- **GameMap**: World layout with dimensions and position lists
- **Region**: Area grouping for regions, visibility, management

### 3. Temporal Types (`temporal.ts`)

- **Tick**: Discrete game time step (turn, frame, simulation step)
- **Phase**: Multi-phase turn support (perception, decision, action, resolution)
- **GameTime**: Abstract time with human-readable display
- Supports: turn-based, real-time, simulation games

### 4. Resource System (`resource.ts`)

- **ResourceType**: Configurable with min/max, stackability, renewable flag
- **Resource**: Amount of a specific type
- **ResourcePool**: Collection with query methods:
  - `getAmount(typeId)` → amount
  - `hasEnough(typeId, amount)` → boolean
  - `getResource(typeId)` → Resource | undefined
- Supports: economy (gold/wood), combat (health/mana), action points, cards, tokens

### 5. Player and Team (`player.ts`)

- **Player**: Human or AI with team affiliation, custom data
- **Team**: Group of players for cooperative play
- Both fully immutable with validation

### 6. Agent System (`agent.ts`)

- **Agent**: Branded string type for entity ID
- **AgentSnapshot**: Current state snapshot:
  - Agent ID, controller (player or null for NPC)
  - AgentState enum: Idle, Perceiving, Deciding, Acting, Waiting, Defeated, Unknown
  - Resources and custom data
- Helper functions: `isAgentActive()`, `isPlayerControlled()`

### 7. World State (`world.ts`)

- **WorldState**: Immutable game snapshot containing:
  - Game time
  - Map
  - All players and teams
  - All agent snapshots
  - Custom game-specific data
- Query functions:
  - `getAgent(state, agentId)` → AgentSnapshot | undefined
  - `getPlayerAgents(state, playerId)` → AgentSnapshot[]
  - `agentExists(state, agentId)` → boolean
  - `getPlayer(state, playerId)` → Player | undefined
  - `getTeam(state, teamId)` → Team | undefined

### 8. Action System (`action.ts`)

- **ActionId**: Branded type for action identity
- **Command**: Agent intent to act:
  - ID, agent, action type, parameters
  - Issued tick and priority
- **ActionResult**: Discriminated union:
  - Success: includes effects
  - Failure: includes reason
- Type guards: `isActionSuccess()`, `isActionFailure()`

### 9. Event System (`event.ts`)

- **EventType**: Event category with visibility control
- **Event**: What happened
  - ID, type, triggering agent, tick, data
  - Public (visible to all) or private (specific observers)
- Helpers:
  - `createPublicEvent()` → visible to all
  - `createPrivateEvent(visibleTo)` → specific observers
  - `canObserveEvent(event, observerId)` → boolean
  - `isPublicEvent()` → boolean

### 10. Perception System (`perception.ts`)

- **VisibilityState** enum: Visible, FogOfWar, Unexplored
- **PositionVisibility**: Track visibility of specific position
  - State, occupier agent, last seen tick
- **FogOfWar**: Complete vision system:
  - Agent ID, all position visibility
  - Vision range (null for custom rules)
  - Lighting effects, modifiers
  - Helpers: `getPositionVisibility()`, `countVisiblePositions()`
- **Observation**: Limited view of world
  - Visible agents, fog of war, visible events
  - Custom senses (game-specific)
  - Helper: `canObserveAgent()`

### 11. Capability System (`capability.ts`)

- **Capability**: What agents can do
  - ID, name, category
  - Enabled flag
  - Resource cost (any type)
  - Cooldown tracking
  - Game-specific properties
  - Helpers: `isCapabilityReady()`, `canUseCapability()`
- **Goal**: High-level objective
  - ID, description, type, priority
  - Active flag, constraints, success criteria
- **Objective**: Tactical task
  - ID, description, type, parent goal
  - Completion status, deadline
  - Parameters
  - Helper: `isObjectiveOverdue()`

## Design Principles Implemented

### 1. Immutability

All created objects are frozen with Object.freeze(). State changes create new instances.

### 2. Pure Value Objects

No logic, no side effects. Just data with validation in constructors.

### 3. Discriminated Unions

ActionResult and Event use exhaustive pattern matching for type safety.

### 4. Game-Agnostic

No game-specific terminology. Uses `customData` fields for game-specific properties:

- RTS: `unitType: 'soldier'`
- Fantasy: `spellsKnown: ['fireball']`
- Card: `cardsInHand: ['attack']`

### 5. Type Safety

All branded types prevent accidental mixing:

- EntityId ≠ PlayerId ≠ TeamId ≠ GameId

## Test Coverage

**33 new tests** across all domain concepts:

- Identity type creation and validation
- Spatial concepts (positions, maps, regions)
- Temporal concepts (ticks, phases, time)
- Resources and pools
- Players and teams
- Agents and snapshots
- World state integration
- Commands and action results
- Events (public, private, visibility)
- Perception and fog of war
- Capabilities and readiness
- Goals and objectives
- Immutability guarantees

**All passing**: Domain tests (33) + Engine tests (4) + ECS tests (4) = **41 tests**

## Documentation

**Complete `packages/domain/README.md`** includes:

- Overview and purpose
- Core concepts with code examples
- Design principles explained
- No logic in domain (what's NOT included)
- Dependency rules
- Versioning strategy
- Related documentation links

## Validation Status

All checks passing:

```
npm run typecheck   ✅  No TypeScript errors
npm run lint        ✅  No linting violations
npm run format      ✅  All properly formatted
npm run test        ✅  41/41 tests passing
npm run doctor      ✅  All validation passing
```

---

# What Domain Model Supports

### Game Genres

- ✅ RTS (resource management, units, buildings)
- ✅ Turn-based (discrete actions, phases)
- ✅ 4X (large-scale, long-term goals)
- ✅ Card games (resources as cards, decks)
- ✅ Tactical (grid positions, line-of-sight)
- ✅ Simulation (continuous actions, custom time)
- ✅ Future genres (extensible design)

### Game Features

- ✅ Multiple players and teams
- ✅ AI and human-controlled agents
- ✅ Custom resource systems
- ✅ Visibility and fog of war
- ✅ Event-based state changes
- ✅ Asynchronous decision-making
- ✅ Goal-driven behavior
- ✅ Capability-based action systems

---

# Current State: 91 Tests Passing

```
✓ |@ai-commander/ecs| tests/world.test.ts (4 tests) 2ms
✓ |@ai-commander/engine| tests/engine.test.ts (4 tests) 2ms
✓ |@ai-commander/domain| tests/domain.test.ts (33 tests) 8ms
✓ |@ai-commander/core| tests/core.test.ts (50 tests) 11ms

Test Files  4 passed (4)
Tests  91 passed (91)
```

---

# Files Created/Modified

**Core Module Files Created:**

```
packages/core/src/types/
├── lifecycle.ts          # StartupResult, ShutdownResult, Lifecycle
├── error.ts              # FrameworkError, ErrorCode enum
├── disposable.ts         # Disposable, AsyncDisposable
├── factory.ts            # Factory<T>, AsyncFactory<T>
├── context.ts            # Context, RequestContext
├── event.ts              # EventBus, EventListener<T>
├── clock.ts              # Clock, RealtimeClock, GameClock
├── scheduler.ts          # Scheduler, ScheduledTask
├── service.ts            # ServiceRegistry, Service
├── module.ts             # ModuleRegistry, Module
├── plugin.ts             # PluginRegistry, Plugin
├── config.ts             # ConfigManager, ConfigSchema
└── index.ts              # All public exports

packages/core/tests/
└── core.test.ts          # 50 comprehensive tests

packages/core/
└── README.md             # Complete documentation with patterns

Root Files Updated:
- tsconfig.json          # Added core package reference
```

---

# Next Steps for Implementation

The Core framework and Domain model are **complete and stable**. Next phase is **Planning and Decision Engines**:

1. **Decision Layer** - Individual agent decisions based on observations
2. **Planner Layer** - Sequence generation and search algorithms
3. **Strategy Layer** - High-level behavior and multi-agent coordination

The Core package provides:

- Lifecycle management for all components
- Event bus for decoupled communication
- Service registry for dependency injection
- Module/plugin system for extensibility
- Configuration management
- Scheduler for task execution
- Clock abstraction for time (realtime or game time)

The Domain model provides:

- Complete type system for all game concepts
- Game-agnostic data structures
- Immutable value objects
- Support for multiple game genres

---

# Key Points for Next Engineer/AI

### What the Domain IS

- Pure data structures defining game concepts
- Type-safe with immutable value objects
- Game-agnostic (supports any strategy game genre)
- Complete vocabulary for describing game state
- Foundation for higher layers

### What the Domain IS NOT

- Game rules or validation
- AI algorithms or planning
- Action execution (that's Engine layer)
- Network code or serialization
- UI/graphics/audio
- Game-specific implementations

### Using the Domain

```typescript
import {
  createWorld State, createAgent,
  createCommand, createEvent,
  createObservation,
} from '@ai-commander/domain';

// Everything is immutable
// Everything is typed
// Everything validates on creation
// No logic, just data
```

### Architecture Compliance

✅ Domain depends only on Shared
✅ All other layers depend on Domain
✅ Pure value objects (no side effects)

---

# Session 061: Fake Game Adapter Implementation

## What Was Built

**FakeGameAdapter** — Reference implementation of the Game Adapter contracts.

A minimal, deterministic in-memory game environment that exercises the complete framework without requiring an external application.

### Components

1. **FakeGameAdapter** — Entry point for creating sessions
2. **FakeGameSession** — Single running game instance with lifecycle management
3. **FakeObservationProvider** — Immutable world state snapshots
4. **FakeCommandExecutor** — Command execution and world updates
5. **FakeWorldSnapshot** — Minimal world model (position, tick, state)

### World Model

- One agent at position (x, y)
- Tick counter (starts at 0)
- Simple state ("idle", "moving", "waiting")
- Command execution counter
- Fully immutable snapshots

### Supported Commands

- **Move**: Change agent position by (dx, dy)
- **Wait**: No-op (progresses tick)
- Deterministic execution: same sequence → same result

### Test Coverage

60 comprehensive tests validating:

- ✅ World state immutability (Object.freeze())
- ✅ Adapter lifecycle (init → create session → shutdown)
- ✅ Session lifecycle (start → pause/resume → stop)
- ✅ Observation retrieval (current + replay)
- ✅ Command execution (validation + execution)
- ✅ World state updates (deterministic)
- ✅ Complete integration (end-to-end cycles)

### Why This Matters

The fake game adapter:

1. **Validates the architecture** — Proves the contracts work end-to-end
2. **Provides a reference implementation** — Shows how to implement adapters
3. **Enables testing** — Framework can be tested without real games
4. **Unblocks game implementations** — Clear pattern to follow
5. **Demonstrates determinism** — Same commands → same state

### Files Created

```
packages/fake-game-adapter/
├── src/
│   ├── fake-game-adapter.ts
│   ├── fake-game-session.ts
│   ├── fake-observation-provider.ts
│   ├── fake-command-executor.ts
│   ├── index.ts
│   ├── types/
│   │   └── fake-command.ts
│   └── world/
│       └── fake-world-state.ts
├── tests/
│   ├── fake-world.test.ts
│   ├── adapter-lifecycle.test.ts
│   ├── session-lifecycle.test.ts
│   ├── observation-provider.test.ts
│   ├── command-executor.test.ts
│   ├── integration.test.ts
│   └── framework-integration.test.ts
├── package.json
├── tsconfig.json
└── vitest.config.ts
```

## Immediate Next Steps

1. **Implement real game adapters** (OpenRA, StarCraft, Chess, etc.)
2. **Add AI strategy modules** (planner enhancements, heuristics)
3. **Configure GitHub Actions CI/CD** (automated testing on commits)
4. **Add game-specific modules** (domain extensions for specific games)
5. **Document game adapter patterns** (step-by-step guide for new adapters)
   ✅ Frozen/immutable objects
   ✅ Exhaustive discriminated unions
   ✅ No game-specific terminology

---

# Next Session Focus

**Planning and Decision Engines**

Start with the Decision layer:

- Decision interfaces and algorithms
- Individual agent decision-making
- Evaluating options based on observations
- Action selection from capabilities

The complete domain model is ready for use.

---

# Files Changed This Session

```
.foundation/state/PROJECT_STATE.md       # Added domain completion
.foundation/state/SESSION_HANDOFF.md     # This file

packages/domain/src/types/identity.ts    # Identity types
packages/domain/src/types/spatial.ts     # Position, map, region
packages/domain/src/types/temporal.ts    # Tick, phase, time
packages/domain/src/types/resource.ts    # Resource system
packages/domain/src/types/player.ts      # Player and team
packages/domain/src/types/agent.ts       # Agent and snapshots
packages/domain/src/types/world.ts       # World state
packages/domain/src/types/action.ts      # Commands and results
packages/domain/src/types/event.ts       # Events
packages/domain/src/types/perception.ts  # Visibility and FOW
packages/domain/src/types/capability.ts  # Capabilities, goals
packages/domain/src/index.ts             # All exports

packages/domain/tests/domain.test.ts     # 33 tests
packages/domain/README.md                # Complete docs
```

---

# Commits This Session

1. **Implement game-agnostic domain model**
   - All 11 domain modules
   - 33 comprehensive tests
   - Complete documentation
   - All validation passing

---

# Summary

The **domain model is complete**, **production-ready**, and **fully tested**. It provides a comprehensive, game-agnostic foundation for all strategy game types:

- ✅ 11 core concept modules
- ✅ 41 tests passing (33 new)
- ✅ Complete documentation
- ✅ Zero technical debt
- ✅ Frozen architecture preserved

**Next step: Decision and Planning Engines** to enable intelligent agent behavior based on domain models.

---

# Session 070: Behavior Tree Framework

## What Was Built

**Behavior Tree Framework** (`@ai-commander/behavior-tree`) — Deterministic decision-making system for game AI.

A generic, game-agnostic framework for defining agent behavior using trees of conditions and actions. No game logic, no automation, no hardcoded strategies — just the decision structure that agents can use.

### Core Concepts

**BehaviorNode** — Base unit of behavior

- `execute(context)` → BehaviorStatus (Success, Failure, Running)
- `reset()` → Clear internal state
- Fully deterministic: same input → same output

**Composite Nodes** — Control flow

- **Sequence**: Execute children in order until one fails. All must succeed for sequence to succeed.
- **Selector**: Execute children in order until one succeeds. First success wins. Only fails if all fail.

**Decorators** — Transform child behavior

- **Inverter**: Flip success/failure (but leave running alone)
- **Succeeder**: Always return success (useful for non-critical branches)
- **FailureDecorator**: Always return failure

**Leaf Nodes** — Actual decisions

- **ActionNode**: Execute an action, returns Success/Failure/Running
- **ConditionNode**: Test a condition, returns Success/Failure (never Running)

**BehaviorContext** — Immutable execution context

- Game state and agent perception passed through tree
- Tick metadata (depth, time step)
- Fully frozen for safety

### Key Properties

1. **Deterministic**: Same tree + same context = same execution every time
2. **Generic**: No game-specific logic, no action names
3. **Composable**: Build complex behaviors from simple nodes
4. **Resumable**: Can pause at running nodes, continue next frame
5. **Debuggable**: Tree structure makes decision flow transparent

### Test Coverage

32 comprehensive tests validating:

- ✅ Individual node execution (action, condition)
- ✅ Sequence behavior (all succeed, early failure)
- ✅ Selector behavior (first success, all fail)
- ✅ Decorator transformations (inverter, succeeder, failure)
- ✅ Nested tree structures
- ✅ Context passing through tree
- ✅ Deterministic execution (same tree → same result)
- ✅ Tree reset and state management
- ✅ Complex decision logic (multi-strategy selection)

### Why This Matters

Behavior trees are the bridge between framework (generic) and game (specific):

```
Game Adapter
  ↓
World State (immutable, game-agnostic)
  ↓
Behavior Tree (decision structure, no logic)
  ↓
Action (command the framework executes in the game)
```

The framework never knows _how_ actions are implemented. The game adapter never knows _what_ decisions mean. The behavior tree never knows _which_ game it's in.

### Files Created

```
packages/behavior-tree/
├── src/
│   ├── behavior-tree.ts          # BehaviorTree interface & factory
│   ├── types.ts                  # BehaviorStatus, BehaviorContext
│   ├── nodes/
│   │   ├── behavior-node.ts      # Base interfaces
│   │   ├── sequence.ts           # Sequence composite
│   │   ├── selector.ts           # Selector composite
│   │   ├── decorators.ts         # Inverter, Succeeder, FailureDecorator
│   │   └── leaf-nodes.ts         # ActionNode, ConditionNode
│   └── index.ts                  # Exports
├── tests/
│   ├── nodes.test.ts             # 25 node tests
│   └── behavior-tree.test.ts     # 7 integration tests
└── Configuration (package.json, tsconfig.json, vitest.config.ts)
```

### Immediate Next Steps

1. **Behavior Tree Decision Engine** (Story 080+) - Integrate with framework
2. **Game Implementations** - Use framework + behavior trees + game adapters
3. **Strategy Modules** - Game-specific behavior libraries

---

# Session 080: Agent Runtime

## What Was Built

**Agent Runtime** (`@ai-commander/agent-runtime`) — Autonomous agent loop orchestrating perception, planning, and decision-making.

The missing piece that ties together all framework components. A generic agent that doesn't know or care about specific games, but coordinates the entire perception→planning→decision→execution lifecycle.

### Core Architecture

**Execution Loop (Deterministic):**

```
Observe (read GameSession → WorldState)
  ↓
Plan (Planner: Goal + WorldState → Plan)
  ↓
Decide (DecisionEngine: Plan + WorldState → Command)
  ↓
Execute (CommandExecutor: Command → Result)
  ↓
Measure (Metrics: Ticks, Decisions, Commands, Timing)
  ↓
(Repeat next frame)
```

One tick per frame. Deterministic: same goal + same world → same execution every time.

### Key Types

```typescript
// Configuration (immutable input)
interface AgentConfiguration {
  agentId: Agent;
  goal: Goal;
  gameSession: GameSession;
  planner: Planner;
  decisionEngine: DecisionEngine;
  executionContext: ExecutionContext;
}

// Runtime status (state machine)
enum AgentStatus {
  Initializing,
  Idle,
  Planning,
  Deciding,
  Executing,
  Paused,
  Stopped,
  Failed,
}

// Metrics (measurement only, no optimization)
interface AgentMetrics {
  ticksExecuted: number;
  decisionsExecuted: number;
  commandsExecuted: number;
  averagePlanningTimeMs: number;
  averageDecisionTimeMs: number;
  errorsEncountered: number;
  lastTickTimestamp: number;
}

// API
interface AgentRuntime {
  initialize(): Promise<void>; // Start session
  tick(): Promise<void>; // Execute one frame
  pause(): Promise<void>; // Pause execution
  resume(): Promise<void>; // Resume from pause
  shutdown(): Promise<void>; // Stop session
  getStatus(): AgentStatus;
  getMetrics(): AgentMetrics;
  getRuntimeState(): AgentRuntimeState;
}
```

### Error Handling Strategy

**Validation errors (throw):**

- Already initialized
- Not active
- State machine violations (pause while paused, etc.)

**Execution errors (recover gracefully):**

- Planning fails: log error, continue with old plan
- Decision fails: skip frame, try again next tick
- Command fails: log error, continue
- Observation unavailable: skip frame
- Execution unavailable: skip frame

### Testing (49 tests)

- **Lifecycle** (14 tests): init, tick, pause/resume, shutdown, state transitions
- **Execution Loop** (7 tests): observe/plan/decide/execute sequence, multiple ticks
- **Metrics** (12 tests): accurate counting and averaging, frozen results
- **Error Handling** (10 tests): graceful recovery, error accumulation
- **Determinism** (6 tests): reproducible execution, consistent state

All tests run against FakeGameAdapter for deterministic, repeatable results.

### Files Created

```
packages/agent-runtime/
├── src/
│   ├── types/
│   │   ├── agent-status.ts      # Enum: Initializing, Idle, Executing, Paused, Stopped, Failed
│   │   ├── agent-metrics.ts     # Interface: ticksExecuted, decisions, commands, timing
│   │   └── agent-runtime.ts     # AgentConfiguration, AgentRuntime interface
│   ├── agent-runtime.ts         # DefaultAgentRuntime + createAgentRuntime()
│   ├── agent-metrics.ts         # MetricsCollector (accumulates measurements)
│   └── index.ts                 # Exports
├── tests/
│   ├── agent-lifecycle.test.ts  # 14 tests
│   ├── agent-execution-loop.test.ts # 7 tests
│   ├── agent-metrics.test.ts    # 12 tests
│   ├── agent-error-handling.test.ts # 10 tests
│   └── agent-determinism.test.ts # 6 tests
└── Configuration (package.json, tsconfig.json, vitest.config.ts, README.md)
```

### Design Decisions

1. **No Algorithm Coupling:** Agent doesn't depend on specific Planner or DecisionEngine implementations
   - Planner could be GOAP, A*, HTN, Monte Carlo, LLM-based, etc.
   - DecisionEngine could be Behavior Trees, Utility AI, FSM, etc.
   - Agent works with any implementation of these contracts

2. **Graceful Degradation:** Execution errors never crash the agent
   - Planning fails → continue with old plan
   - Decision fails → wait one tick
   - Command fails → log and move on
   - Agent keeps ticking regardless

3. **Deterministic Execution:** Same input always produces same output
   - Enables reproducibility, testing, and consistency
   - No randomness, no hidden state
   - Metrics are deterministic functions of execution

4. **Minimal Metrics:** Measurement only, no optimization
   - Don't track what you won't use
   - Enables future optimization without changing agent
   - Timing data for diagnostics, not for tuning

5. **State Machine Pattern:** Clear lifecycle with validated transitions
   - Prevents invalid state changes (resume while not paused, etc.)
   - Makes execution predictable and testable
   - Immutable state exposed via getters

### Integration Pattern

How the Agent Runtime fits into a larger system:

```
Engine (tick loop)
  └─ Pipeline
      └─ AgentRuntimeStep (for each agent)
          ├─ Call runtime.tick()
          ├─ Handle Planning phase
          ├─ Handle Decision phase
          ├─ Handle Execution phase
          ├─ Update world state
          └─ Publish AgentBehaviorTick event

Game World ← Agent actions
```

### Extensibility

Swap any component without changing the Agent:

```typescript
// Custom planner
class MyGoalOrientedPlanner implements Planner {
  async plan(request): Promise<PlanningResult> { ... }
}

// Custom decision engine (e.g., behavior tree engine)
class MyBehaviorTreeEngine implements DecisionEngine {
  async decide(request): Promise<DecisionResult> { ... }
}

// Custom game adapter
class MyGameAdapter implements GameAdapter {
  async createSession(): Promise<GameSession> { ... }
}

// All work with the same Agent Runtime unchanged
const runtime = createAgentRuntime({
  planner: new MyGoalOrientedPlanner(),
  decisionEngine: new MyBehaviorTreeEngine(),
  gameSession: session, // from MyGameAdapter
  // ... other config
});
```

### What This Enables

- **Multi-agent Systems:** Create one AgentRuntime per agent, coordinate at pipeline level
- **Hybrid Strategies:** Mix different planners, decision engines, and game adapters
- **AI Experimentation:** Swap algorithms and measure impact via metrics
- **Production Deployment:** Type-safe, deterministic, fully tested
- **Future Learning:** Architecture supports RL training without changes

### Next Steps

1. **Behavior Tree Decision Engine** - Wire DecisionEngine to use behavior trees
2. **Real Game Adapters** - Implement for OpenRA, StarCraft, Chess, etc.
3. **Multi-Agent Coordination** - Coordinate multiple agents at higher level
4. **Performance Optimization** - Use metrics to identify bottlenecks
5. **Learning Integration** - Add RL training on top of deterministic agent
