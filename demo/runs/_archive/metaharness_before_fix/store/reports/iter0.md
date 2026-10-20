# Iteration 0: Baseline Seed Harness Report

**What changed**: Baseline only—single LLM call, last-line extraction.

**Score & cost**: 8.3% accuracy (1/12 correct) on search set; ~1,526 tokens per task.

**Unit performance**:
- **Success**: evolve-numeric-011 (sum of digits of 13^10 = 67)
- **Failures** (11/12): All were arithmetic or formatting errors:
  - Off-by-N errors in digit sums (evolve-numeric-000: 198 vs 144; -004: 81 vs 100)
  - Wrong modulo results (evolve-numeric-001: 31 vs 91; evolve-numeric-003: 16 vs 56)
  - Format mismatches (evolve-numeric-002: "-183,764" vs "-183764"; evolve-numeric-008: "253" appeared mid-explanation)
  - Non-numeric last lines (evolve-numeric-010: explanation about binary patterns instead of "14")

**Why**: Baseline has no verification, no tool enforcement, and no output format control. The model calculates but often makes arithmetic mistakes and doesn't isolate answers clearly.

**Takeaway**: Next candidates should (1) explicitly enforce Python tool usage, (2) add verification/multi-attempt steps, and (3) require "ANSWER: <value>" format to isolate numeric answers.

---

## Hypotheses & Prototypes

**Hypothesis 1** (Axis A+F: Prompt + Model-Written Verification):  
Strict prompting + multi-turn verification reduces errors. If the prompt enforces tool use and adds a verification pass, the model will catch arithmetic mistakes.  
*Prototype walk-through (evolve-numeric-001: 40627866717431 mod 148)*:
- Turn 1 (calculate): LLM uses Python, computes 40627866717431 % 148, gets result (correct or wrong)
- Turn 2 (verify): LLM re-computes independently to check, formats as "ANSWER: <value>"
- If Turn 1 was wrong, Turn 2 might catch it via re-verification

**Hypothesis 2** (Axis C+B: Multiple methods + State):  
Multiple independent solution attempts increase reliability. If the harness collects 2+ methods and has the LLM compare, the correct answer is more likely to be selected.  
*Prototype walk-through (same task)*:
- Attempt A: "Compute directly using Python"
- Attempt B: "Verify using division reconstruction: a = (a // mod) * mod + (a % mod)"
- Compare turn: LLM checks if both agree, picks the right one, formats "ANSWER: <value>"
- Mismatch alerts the model to recompute

---

```json
{
  "iteration": 1,
  "candidates": [
    {
      "name": "guided_format",
      "base_system": "seed",
      "hypothesis": "Strict multi-turn prompts with explicit tool enforcement and verification reduce arithmetic errors by forcing recalculation and explicit ANSWER: <value> format.",
      "axis": "exploitation",
      "components": ["axis:A (prompt template)", "axis:F (model-written verification)"]
    },
    {
      "name": "multi_method",
      "base_system": "seed",
      "hypothesis": "Multiple independent solution attempts with comparison increase robustness; disagreement triggers re-verification, catching errors the model might make on a single pass.",
      "axis": "exploration",
      "components": ["axis:C (selection algorithm - multi-attempt comparison)", "axis:B (state storage - intermediate results)", "axis:F (model usage - cross-check reasoning)"]
    }
  ]
}
```

---

## Candidate 1: guided_format
