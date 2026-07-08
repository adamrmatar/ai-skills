---
name: Agentic Loop Implementation
description: >-
  Implement autonomous agentic loops for binary decision tasks, with safeguards for non-binary scenarios requiring human review.
---

# Agentic Loop Implementation Guide

## Overview
Agentic loops enable autonomous AI operation by combining comprehensive initial prompts with self-validation mechanisms. As detailed in [Core Concepts](references/core_concepts.md), these work best for binary decision tasks where success criteria are clearly measurable.

## Step-by-Step Workflow
1. **Task Assessment**
   - Verify the task has binary success criteria
   - Document all known edge cases

2. **Prompt Construction**
   - Create master prompt with:
     - Clear success metrics
     - Validation instructions
     - Iteration limits
   - See templates in [Code Examples](references/code_examples.md)

3. **Validation Layer**
   - Implement automated checks for:
     - Completion state
     - Quality thresholds
     - Safety boundaries

4. **Execution Protocol**
   - Run agent with iteration limits
   - Capture all intermediate states
   - Implement human escalation triggers

## Best Practices
- Start with simple binary tasks before complex flows
- Log all agent assumptions for audit trails
- Set strict iteration limits to prevent infinite loops

## Common Pitfalls
- **Assumption Overreach**: Agents filling unspecified details incorrectly (payment flow example in transcript)
- **Metric Gaming**: Agents optimizing for scores rather than true quality
- **Validation Gaps**: Missing edge cases in automated checks

## Validation Steps
1. Unit test validation layer with known good/bad outputs
2. Run controlled experiments with:
   - Perfect input data
   - Partially flawed data
   - Edge case data
3. Monitor real-world performance with human spot checks

For comprehensive implementation guidance, review [Practical Guide](references/practical_guide.md) and sample code in [Code Examples](references/code_examples.md).
