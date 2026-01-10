# Phase 1 Implementation Status

**Date:** 2026-01-10
**Goal:** Implement real gameplay instrumentation for decision_density and interaction_frequency

## Progress Summary

### ✅ Phase 1A: Schema & Python Infrastructure (COMPLETE)

**Completed:**
1. Extended FlatBuffers schema (`schema/simulation.fbs`)
   - Added `total_decisions`, `total_valid_moves`, `forced_decisions`
   - Added `total_interactions`, `total_actions`
   - Regenerated Python bindings

2. Updated Python fitness evaluator (`src/darwindeck/evolution/fitness_full.py`)
   - Modified `SimulationResults` dataclass with Phase 1 fields
   - Implemented real metric calculation with fallback to heuristics
   - Backward compatible (defaults to 0, uses heuristics when unavailable)

**Metrics:**
- `decision_density`: Uses `(avg_valid_moves - 1) / 5.0` when real data available
- `interaction_frequency`: Uses `total_interactions / total_actions` ratio

### ⏳ Phase 1B: Go-Side Collection (TODO)

**Required changes in `src/gosim/`:**

#### 1. Update FlatBuffers schema compilation
```bash
cd src/gosim
flatc --go ../../schema/simulation.fbs
```

#### 2. Add counters to game simulation loop

**File:** `src/gosim/simulation/engine.go` (or equivalent)

**Counters to add:**
```go
type GameMetrics struct {
    TotalDecisions      uint64  // Increment at each decision point
    TotalValidMoves     uint64  // Add count of valid moves at each decision
    ForcedDecisions     uint64  // Increment when only 1 valid move
    TotalInteractions   uint64  // Increment when action affects opponent
    TotalActions        uint64  // Increment on every action taken
}
```

**Collection points:**

**A. Decision counting** (when player chooses a move):
```go
// At move generation
validMoves := generateValidMoves(gameState, player)
metrics.TotalDecisions++
metrics.TotalValidMoves += uint64(len(validMoves))
if len(validMoves) == 1 {
    metrics.ForcedDecisions++
}
```

**B. Interaction counting** (when action executed):
```go
// When applying a move
metrics.TotalActions++
if affectsOpponent(move, gameState) {
    metrics.TotalInteractions++
}

// affectsOpponent checks:
// - Modifies opponent's hand (stealing, forcing discard)
// - Modifies opponent's score
// - Modifies opponent's tableau/played cards
// - Triggers opponent effects
```

#### 3. Aggregate counters per batch

**File:** `src/gosim/simulation/batch.go` (or equivalent)

**Aggregation:**
```go
// Thread-local accumulation (per worker)
type WorkerMetrics struct {
    decisions      uint64
    validMoves     uint64
    forcedMoves    uint64
    interactions   uint64
    actions        uint64
}

// Merge at batch completion
func aggregateMetrics(workers []WorkerMetrics) AggregatedStats {
    stats := AggregatedStats{}
    for _, w := range workers {
        stats.TotalDecisions += w.decisions
        stats.TotalValidMoves += w.validMoves
        // ... etc
    }
    return stats
}
```

#### 4. Return via FlatBuffers

**File:** Where `AggregatedStats` is built

**Update builder:**
```go
cardsim.AggregatedStatsAddTotalDecisions(builder, aggregated.TotalDecisions)
cardsim.AggregatedStatsAddTotalValidMoves(builder, aggregated.TotalValidMoves)
cardsim.AggregatedStatsAddForcedDecisions(builder, aggregated.ForcedDecisions)
cardsim.AggregatedStatsAddTotalInteractions(builder, aggregated.TotalInteractions)
cardsim.AggregatedStatsAddTotalActions(builder, aggregated.TotalActions)
```

### 🎯 Expected Impact

**Without Phase 1B (current):**
- Fitness: ~0.80 (reweighted heuristics)
- Still using structural proxies
- Evolution converges to simple games

**With Phase 1B complete:**
- Fitness: Should differentiate better (0.75-0.95 range expected)
- Real decision measurement (not phase count)
- Real interaction measurement (not special effect count)
- Evolution should explore richer game space

**Performance target:**
- <3% overhead per consensus plan
- Maintain 750K+ games/sec on 256 cores
- Thread-local counters (no contention)

### 📋 Implementation Checklist

- [x] Extend FlatBuffers schema
- [x] Regenerate Python bindings
- [x] Update SimulationResults dataclass
- [x] Implement real metric formulas in fitness evaluator
- [ ] Regenerate Go bindings from schema
- [ ] Add GameMetrics struct to Go simulator
- [ ] Instrument decision counting in move generation
- [ ] Instrument interaction counting in move execution
- [ ] Aggregate metrics per worker (thread-local)
- [ ] Merge aggregated metrics at batch boundaries
- [ ] Update FlatBuffers builder to include new fields
- [ ] Test: Verify real metrics return non-zero values
- [ ] Benchmark: Confirm <3% overhead
- [ ] Deploy to 256-core server
- [ ] Run evolution: Compare results vs heuristic baseline

### 🔗 Related Documents

- `docs/plans/2026-01-10-fitness-instrumentation-consensus.md` - Multi-agent consensus plan
- `docs/analysis-0.8403-ceiling.md` - Analysis showing need for real metrics
- `schema/simulation.fbs` - Extended FlatBuffers schema
- `src/darwindeck/evolution/fitness_full.py` - Updated fitness evaluator

### 🚀 Next Actions

1. **Understand Go codebase structure:**
   - Locate game simulation loop
   - Identify move generation function
   - Find action execution function

2. **Implement Phase 1B:**
   - Follow checklist above
   - Start with decision counting (simpler)
   - Add interaction counting second
   - Test with small batch first

3. **Validate:**
   - Print metrics for a single game
   - Verify non-zero values make sense
   - Check performance impact
   - Run full evolution on server

### 💡 Tips for Go Implementation

**Decision counting gotchas:**
- Count only player decisions (not forced game actions)
- Don't double-count in loops
- Include all move types (play, draw, discard, pass)

**Interaction detection strategies:**
- Simple: Flag trick-taking phases as interactive
- Better: Check if move targets opponent locations
- Best: Track state diffs (did opponent hand/score change?)

**Performance optimization:**
- Use stack-allocated structs (not pointers)
- Atomic increments only at merge points
- Cache-align worker metrics to avoid false sharing

**Testing strategy:**
- Start with War (simple): Should show low decision_density (forced moves)
- Test with Hearts: Should show higher interaction_frequency (tricks)
- Verify metrics correlate with game complexity

---

**Status:** Phase 1A complete, ready for Go implementation (Phase 1B)
**Blocker:** None - schema and Python ready, Go work can proceed
**ETA:** 1-2 days for experienced Go developer
