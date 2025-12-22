# Multi-Profile Claim Scoring - Implementation Summary

## Status: ✅ IMPLEMENTED (December 22, 2025)

The multi-profile scoring system with 6 dimensions is now **fully integrated** into Knowledge Chipper's flagship evaluator.

## What Was Completed

A complete multi-profile scoring system that solves the fundamental problem: **How do we determine if a claim is A-tier?**

**Answer:** A claim is A-tier if it's extremely valuable to at least one type of user (max-scoring across 12 profiles).

## Key Changes (December 22, 2025)

### Expanded from 5 to 6 Dimensions

**Added:**
1. **Temporal Stability** - How long will this claim remain true/relevant? (1=ephemeral to 10=timeless)
2. **Scope** - How broadly applicable is this claim? (1=narrow edge case to 10=universal principle)

**Existing dimensions:**
- Epistemic Value (reduces uncertainty)
- Actionability (enables decisions)
- Novelty (surprisingness)
- Verifiability (evidence strength)
- Understandability (clarity)

### Updated All 12 User Profiles

Each profile now has weights for all 6 dimensions (weights sum to 1.0). Examples:
- **Scientist**: 45% epistemic, 28% verifiability, 13% novelty, 8% temporal, 4% scope, 2% actionability
- **Investor**: 48% actionability, 23% verifiability, 13% epistemic, 8% novelty, 5% temporal, 3% scope
- **Educator**: 37% understandability, 27% epistemic, 15% actionability, 12% scope, 6% temporal, 3% novelty

### Integration Complete

- ✅ Flagship evaluator now requests 6 dimensions from LLM
- ✅ Multi-profile scorer calculates importance for all 12 profiles (FREE arithmetic)
- ✅ Max-scoring selects highest profile score as final importance
- ✅ Database schema updated with new columns
- ✅ Unit and integration tests written
- ✅ Backward compatible with v1 output

### Files Created

1. **`MULTI_PROFILE_SCORING_INTEGRATION_PLAN.md`** (60+ pages)
   - Comprehensive integration plan with:
     - Current system analysis
     - Proposed architecture
     - Schema changes (flagship_output.v2.json)
     - Implementation steps (6 phases)
     - Database migration strategy
     - Testing strategy
     - Cost analysis
     - Success metrics
     - Open questions
     - Complete appendices with profiles, examples, checklist

2. **`multi_profile_scoring_prototype.py`** (450+ lines)
   - Working prototype demonstrating the concept
   - Mock LLM dimension evaluation
   - Profile scoring arithmetic
     - Example claims with dimension profiles
   - Comparison of scoring methods (max, top-k, percentile)

3. **`src/knowledge_system/scoring/profiles.py`** (213 lines)
   - 12 standard user profiles:
     - Scientist, Philosopher, Educator, Student
     - Skeptic, Investor, Policy Maker, Tech Professional
     - Health Professional, Journalist, Generalist, Pragmatist
   - Dimension definitions with examples
   - Profile weight validation

4. **`src/knowledge_system/scoring/multi_profile_scorer.py`** (280+ lines)
   - Core scoring functions:
     - `score_for_profile()` - Calculate score for one profile
     - `score_all_profiles()` - Calculate scores for all profiles
     - `get_importance_max()` - Max-scoring approach
     - `get_importance_top_k()` - Top-k averaging approach
     - `get_importance_percentile()` - Percentile-based approach
     - `get_tier()` - Convert score to A/B/C/D tier
     - `validate_dimensions()` - Validation logic
     - `calculate_composite_importance()` - Unified interface

5. **`src/knowledge_system/scoring/__init__.py`**
   - Clean module exports

## Key Innovation: Separation of Concerns

### The Problem

Current system uses a single "importance" score (1-10) that is:
- Too subjective (importance for whom?)
- Conflates multiple dimensions (epistemic value + actionability + novelty)
- No user context
- Arbitrary tier cutoffs

### The Solution

**Two-stage scoring**:

```python
# Stage 1: LLM evaluates dimensions ONCE ($0.01 per claim)
dimensions = llm.evaluate({
    "epistemic_value": 9,      # Reduces uncertainty
    "actionability": 6,         # Enables decisions
    "novelty": 8,               # Surprisingness
    "verifiability": 8,         # Evidence strength
    "understandability": 7      # Clarity
})

# Stage 2: Arithmetic calculates profile scores (FREE)
for profile in STANDARD_PROFILES:
    score = sum(profile.weights[dim] * dimensions[dim]
                for dim in dimensions)

# Stage 3: Take maximum across profiles
final_importance = max(all_profile_scores)
```

### Cost Efficiency

**Key Insight**: Adding profiles has ZERO marginal cost!

- 1 profile: 1 LLM call per claim
- 12 profiles: 1 LLM call per claim (same!)
- 100 profiles: 1 LLM call per claim (same!)
- 1000 profiles: 1 LLM call per claim (same!)

**Why?** Because dimension evaluation happens once, then profile scoring is pure arithmetic.

## How Multi-Profile Scoring Works

### Example: Neuroscience Claim

**Claim**: "Dopamine regulates motivation, not pleasure"

**LLM evaluates dimensions** (1 call, ~$0.01):
```json
{
  "epistemic_value": 9,
  "actionability": 6,
  "novelty": 8,
  "verifiability": 8,
  "understandability": 7
}
```

**Arithmetic calculates profile scores** (free):
```python
scientist_score = 9×0.50 + 8×0.30 + 8×0.15 + 6×0.05 = 8.4
investor_score  = 6×0.50 + 8×0.25 + 9×0.15 + 8×0.10 = 7.1
philosopher_score = 9×0.40 + 8×0.30 + 8×0.20 + 6×0.10 = 8.2
# ... 9 more profiles
```

**Max-scoring determines final importance**:
```python
final_importance = max(8.4, 7.1, 8.2, ...) = 8.4
best_profile = "scientist"
tier = "A"  # Because 8.4 ≥ 8.0
```

**Insight**: This niche neuroscience claim is A-tier because it's extremely valuable to scientists (epistemic_value: 50% weight), even though it's less valuable to investors. Max-scoring rescues it!

### Example: Trivial Fact

**Claim**: "Jerome Powell is the current Fed Chairman"

**LLM evaluates dimensions**:
```json
{
  "epistemic_value": 1,      // No insight
  "actionability": 2,         // Minimal utility
  "novelty": 1,               // Everyone knows this
  "verifiability": 10,        // Easily verified
  "understandability": 10     // Crystal clear
}
```

**Profile scores**:
```python
scientist_score = 1×0.50 + 10×0.30 + 1×0.15 + 2×0.05 = 3.8
skeptic_score   = 10×0.60 + 1×0.25 + 1×0.10 + 2×0.05 = 6.5
# All other profiles: < 4.0
```

**Final importance**:
```python
final_importance = max(6.5, 3.8, ...) = 6.5
best_profile = "skeptic"
tier = "C"  # Because 6.5 < 6.5 threshold for B-tier
```

**Insight**: Even with max-scoring, this trivial fact scores low (C-tier) because it's low on ALL meaningful dimensions. High verifiability alone isn't enough.

## Profile Definitions

Each profile has different dimension weights (sum to 1.0):

| Profile | Top Priority | Weights |
|---------|-------------|---------|
| **Scientist** | Epistemic Value | 50% epistemic + 30% verifiability + 15% novelty |
| **Investor** | Actionability | 50% actionability + 25% verifiability + 15% epistemic |
| **Philosopher** | Epistemic + Novelty | 40% epistemic + 30% novelty + 20% verifiability |
| **Educator** | Understandability | 40% understandability + 30% epistemic + 20% actionability |
| **Skeptic** | Verifiability | 60% verifiability + 25% epistemic + 10% novelty |
| **Health Professional** | Verifiability + Actionability | 45% verifiability + 30% actionability + 20% epistemic |
| **Journalist** | Novelty | 35% novelty + 30% understandability + 20% verifiability |
| **Pragmatist** | Actionability | 50% actionability + 25% verifiability + 15% understandability |

(See `src/knowledge_system/scoring/profiles.py` for all 12 profiles)

## Dimension Definitions

1. **Epistemic Value** (Does this reduce uncertainty?)
   - Teaches how the world works
   - Explains mechanisms/causality
   - Builds mental models
   - Score: 1 (trivial) to 10 (fundamental insight)

2. **Actionability** (Can this inform decisions?)
   - Enables better choices
   - Provides practical guidance
   - Delivers strategic intelligence
   - Score: 1 (purely theoretical) to 10 (highly actionable)

3. **Novelty** (Is this surprising?)
   - Challenges assumptions
   - Reveals non-obvious insights
   - Introduces new perspectives
   - Score: 1 (obvious) to 10 (groundbreaking)

4. **Verifiability** (How strong is the evidence?)
   - Quality of supporting evidence
   - Source credibility
   - Logical coherence
   - Score: 1 (speculation) to 10 (rigorously proven)

5. **Understandability** (How clear is this?)
   - Clarity of expression
   - Accessibility to non-experts
   - Minimal jargon
   - Score: 1 (opaque) to 10 (crystal clear)

## Scoring Methods

Three aggregation approaches, each with different selectivity:

### 1. Max-Scoring (Most Inclusive) ✅ RECOMMENDED

```python
final_importance = max(all_profile_scores)
```

- **Rationale**: "Is this A-tier for ANYONE?"
- **Effect**: Rescues niche-but-valuable claims
- **Use case**: When you want to surface specialized insights

### 2. Top-K Averaging (More Selective)

```python
top_k = sorted(all_profile_scores)[:k]
final_importance = mean(top_k)
```

- **Rationale**: "Is this A-tier for at least K profiles?"
- **Effect**: Requires broader appeal
- **Use case**: When you want claims that appeal to multiple audiences

### 3. Percentile-Based (Tunable)

```python
final_importance = percentile(all_profile_scores, p)
```

- **Rationale**: Tune from max (p=100) to median (p=50)
- **Effect**: Adjustable selectivity
- **Use case**: When you want fine-grained control

## Integration Steps

### Phase 1: Prototype Testing (1 day) ✅ COMPLETED

- [x] Create working prototype
- [x] Define 12 standard profiles
- [x] Implement scoring functions
- [x] Demonstrate with example claims

### Phase 2: Schema Updates (2 days) ✅ COMPLETED (Dec 22, 2025)

- [x] Created `schemas/flagship_output.v2.json` with 6 dimensions
- [x] Added `dimensions`, `profile_scores`, `best_profile` fields
- [x] Updated `prompts/flagship_evaluator.txt` with 6-dimension scoring (added temporal_stability and scope)
- [x] Maintained backward compatibility with v1

### Phase 3: Code Integration (2 days) ✅ COMPLETED (Dec 22, 2025)

- [x] Updated `flagship_evaluator.py` to use multi-profile scorer
- [x] Added `dimensions`, `profile_scores`, `best_profile`, `tier` to `EvaluatedClaim`
- [x] Integrated `calculate_composite_importance()` into evaluation pipeline via `_process_multi_profile_scoring()`
- [x] Maintained backward compatibility with v1 output

### Phase 4: Database Migration (1 day) ✅ COMPLETED (Dec 22, 2025)

- [x] Created migration: `2025_12_22_multi_profile_scoring.sql`
- [x] Added columns: `dimensions JSON`, `profile_scores JSON`, `best_profile TEXT`, `temporal_stability REAL`, `scope REAL`
- [x] Created indexes on `best_profile`, `temporal_stability`, `scope`, `tier`
- [x] Documented column purposes and data formats

### Phase 5: Testing (2 days) ✅ COMPLETED (Dec 22, 2025)

- [x] Unit tests: Profile scoring arithmetic (`test_multi_profile_scorer.py`)
- [x] Unit tests: Dimension validation (6 dimensions including temporal_stability and scope)
- [x] Unit tests: Profile weight validation (all sum to 1.0)
- [x] Integration tests: v2 evaluator output (`test_flagship_evaluator_v2.py`)
- [x] Integration tests: Backward compatibility with v1

### Phase 6: Deployment 🔲 PENDING

- [ ] Run smoke test: Process 10 test episodes
- [ ] Monitor LLM costs (expect +50% due to longer output)
- [ ] Validate tier distributions (target: 10-30% A-tier)
- [ ] Create analytics queries for dimension filtering
- [ ] Implement temporal stability filtering UI (optional)

## Cost Analysis

### LLM Costs

| System | LLM Calls | Tokens | Cost per Claim |
|--------|-----------|--------|----------------|
| v1 (current) | 1 | ~300 | $0.01 |
| v2 (multi-profile) | 1 | ~450 | $0.015 |
| **Increase** | **0%** | **+50%** | **+50%** |

**For 10,000 claims**:
- v1: $100
- v2: $150
- **Additional cost: $50**

### Computational Costs

| Operation | v1 Time | v2 Time | Increase |
|-----------|---------|---------|----------|
| LLM call | 500ms-2s | 500ms-2s | 0% |
| Profile scoring (12 profiles) | N/A | <1ms | +1ms |
| Profile scoring (100 profiles) | N/A | ~10ms | +10ms |
| **Total per claim** | **~1s** | **~1s** | **0%** |

**Verdict**: 50% LLM cost increase is worth it for:
- Unlimited profiles at no marginal cost
- Better tier accuracy (fewer false negatives)
- Queryable dimensions for analytics
- Recalculable scores without re-running LLM

## Usage Example

```python
from knowledge_system.scoring import (
    calculate_composite_importance,
    get_tier,
    STANDARD_PROFILES
)

# LLM returns dimensions
dimensions = {
    "epistemic_value": 9,
    "actionability": 6,
    "novelty": 8,
    "verifiability": 8,
    "understandability": 7
}

# Calculate importance using max-scoring
importance, best_profile, all_scores = calculate_composite_importance(
    dimensions,
    method="max"
)

# Get tier
tier = get_tier(importance)

print(f"Importance: {importance}")
print(f"Best Profile: {best_profile}")
print(f"Tier: {tier}")
print(f"\nAll Profile Scores:")
for profile, score in sorted(all_scores.items(), key=lambda x: x[1], reverse=True):
    print(f"  {profile:20s}: {score:4.1f}")

# Output:
# Importance: 8.4
# Best Profile: scientist
# Tier: A
#
# All Profile Scores:
#   scientist           : 8.4
#   skeptic             : 8.3
#   philosopher         : 8.2
#   health_professional : 8.0
#   educator            : 7.8
#   generalist          : 7.8
#   student             : 7.6
#   policy_maker        : 7.5
#   tech_professional   : 7.3
#   investor            : 7.1
#   pragmatist          : 7.1
```

## Benefits

### 1. Cost Efficiency
- **Adding profiles is FREE** (no additional LLM calls)
- Same cost whether you have 1 profile or 1000 profiles
- Profile weights can be changed and scores recalculated instantly

### 2. Better Tier Accuracy
- **Rescues niche-but-valuable claims** that would be missed by single-profile scoring
- Example: Technical neuroscience insight scores high for scientists, even if low for others
- **Still rejects trivial claims** that score low on all dimensions

### 3. Transparency
- **Explainable scores**: "This is A-tier because it's high epistemic_value for scientists"
- **Queryable dimensions**: Find all claims with high actionability or high novelty
- **Analytics**: Track dimension distributions over time

### 4. Flexibility
- **Multiple scoring methods**: max, top-k, percentile
- **Customizable profiles**: Users can define their own dimension weights
- **Extensible**: Can add new profiles or dimensions without re-scoring

### 5. Personalization
- **User-specific profiles**: Store custom weights per user
- **Learned preferences**: Use collaborative filtering to learn from feedback
- **Episode-specific**: Could use different profiles for finance vs science podcasts

## Next Steps

1. **Review the integration plan** (`MULTI_PROFILE_SCORING_INTEGRATION_PLAN.md`)
2. **Test the prototype** (`multi_profile_scoring_prototype.py`)
   ```bash
   python multi_profile_scoring_prototype.py
   ```
3. **Run on real claims**: Export 100 claims, manually score dimensions, validate tier distributions
4. **Decide on implementation**:
   - Full v2 migration (recommended)
   - A/B test v1 vs v2 first
   - Gradual rollout with feature flag

## Open Questions

1. **Should we expose dimension scores in the UI?**
   - Pro: Transparency, filtering, analytics
   - Con: Complexity, potential user confusion
   - Recommendation: Expose in "Advanced" view

2. **Should we re-score all existing claims?**
   - Option A: Lazy (only new claims use v2)
   - Option B: Approximate (map old importance → estimated dimensions, free)
   - Option C: Bulk re-scoring (re-run evaluator, $100-200)
   - Recommendation: Start with A, do B for analytics

3. **Should users be able to create custom profiles?**
   - v1: Predefined profiles only (MVP)
   - v2: Custom profile builder (3 months)
   - v3: Learned profiles via collaborative filtering (6 months)

4. **Should we allow per-episode profile selection?**
   - Example: "I'm processing a finance podcast, use 'investor' profile"
   - Not in MVP, evaluate after usage data

## Files to Review

1. **`MULTI_PROFILE_SCORING_INTEGRATION_PLAN.md`** - Full 60+ page plan
2. **`multi_profile_scoring_prototype.py`** - Working prototype with examples
3. **`src/knowledge_system/scoring/profiles.py`** - Profile definitions
4. **`src/knowledge_system/scoring/multi_profile_scorer.py`** - Scoring functions
5. **`CLAIM_IMPORTANCE_SCORING_ANALYSIS.md`** - Academic research background

## Conclusion

This multi-profile scoring system solves the fundamental question: **"How do we determine if a claim is A-tier?"**

The answer: **"A claim is A-tier if it's extremely valuable to at least one type of user."**

Key innovations:
- **Dimension-based evaluation** (LLM does semantic analysis once)
- **Profile-based scoring** (arithmetic calculates importance for many users)
- **Max-scoring aggregation** (rescues niche insights)
- **Zero marginal cost** (add unlimited profiles for free)

The system is ready for integration into the flagship evaluator. Next step: Schema updates and prompt engineering for 5-dimension evaluation.
