# Skill: AI Model Training with Task Fidelity Scaling

## Overview
This skill teaches you how to implement task fidelity scaling for AI model training, based on Snorkel's research showing that high-quality tasks produce 5x greater performance improvement than low-quality tasks. The methodology focuses on four core quality criteria for tasks and demonstrates how to validate, categorize, and utilize tasks for maximum training effectiveness.

Key concepts are covered in [Core Concepts](references/core_concepts.md), with implementation details in [Practical Guide](references/practical_guide.md) and [Code Examples](references/code_examples.md).

## Step-by-Step Workflow
1. **Task Creation**
   - Define tasks with clear, testable outcomes
   - Specify all dependencies and requirements
   - Ensure tasks are containerized for reproducibility

2. **Quality Validation**
   - Test each task against the four criteria:
     1. Achievability
     2. Non-triviality
     3. Functional correctness
     4. Environmental reliability
   - Bucket tasks as Accepted or Rejected

3. **Benchmarking Setup**
   - Prepare evaluation harness
   - Establish baseline metrics:
     - Tool call frequency
     - Pass rates
     - Output token counts

4. **Failure Analysis**
   - Categorize failures as:
     - Meaningful (logic errors, incomplete tasks)
     - Degenerate (environment issues)
   - Compare failure distributions between Accepted/Rejected tasks

5. **Model Training**
   - Run parallel RL training sessions:
     - One with high-quality (Accepted) tasks
     - One with low-quality (Rejected) tasks
   - Use identical models and compute budgets

6. **Performance Comparison**
   - Measure improvement delta for both training runs
   - Analyze quality impact ratio (expected 5x difference)

## Best Practices
1. **Task Specification**
   - Avoid underspecification (clear testable outcomes)
   - Example: Instead of "Improve this code", specify "Reduce cyclomatic complexity below 5 while maintaining functionality"

2. **Quality Thresholds**
   - Set minimums for tool calls and output tokens
   - Example: Reject tasks solved with <3 tool calls or <100 output tokens

3. **Expert Involvement**
   - Use human experts for:
     - Initial task design
     - Quality rubric creation
     - Ambiguous case resolution

## Common Pitfalls
1. **False Difficulty**
   - Tasks appear hard due to poor specification
   - Example: Tests expecting unrequested outcomes

2. **Environmental Noise**
   - Unstable containers masking true performance
   - Solution: Test environment reliability separately

3. **Binary Thinking**
   - Treating all failures equally
   - Solution: Categorize failures meaningfully

## Validation Steps
1. **Inter-Annotator Agreement**
   - Measure consistency between:
     - Human judges
     - LLM judges
     - Automated checks

2. **Training Delta Verification**
   - Confirm high-quality tasks produce significantly better improvement
   - Expected: 5-6% vs 1% improvement

3. **Failure Mode Analysis**
   - Verify Accepted tasks produce cleaner failure patterns
   - Meaningful failures should dominate

## Implementation Notes
- Start with verifiable domains (coding, math)
- Gradually extend to fuzzy domains with spectrum scoring
- Maintain quality rubrics for consistent evaluation
- Monitor task quality as models improve (avoid saturation)