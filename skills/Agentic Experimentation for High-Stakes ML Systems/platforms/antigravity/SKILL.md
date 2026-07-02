---
name: Agentic Experimentation for High-Stakes ML Systems
description: >-
  Skill for AI agents to safely and efficiently experiment with feature engineering and model improvements in high-stakes ML systems without disrupting production workflows.
---

## Overview
This skill enables AI agents to safely modify and improve high-stakes ML systems (fraud detection, trust & safety, personalization) through:
1. Infrastructure automation for feature engineering
2. Branch-based resource isolation
3. Partial aggregate reuse
4. Production-ready pipeline generation

Core concepts:
- Agents modify features/models but don't replace entire production systems
- All changes happen in isolated dev branches
- Chronon automates underlying infrastructure
- Humans review before production deployment

## Step-by-Step Workflow
1. **Identify improvement opportunity**
   - Analyze model performance metrics
   - Review recent fraud patterns/attack vectors
   - Consult feature importance rankings

2. **Define new feature(s)** using Chronon API
   ```python
   # Example: Add 7-day window to existing features
   new_feature = Feature(
     name="user_login_count_7d",
     sources=[existing_login_source],
     aggregation=Aggregation(
       operation=Operation.COUNT,
       windows=[Window(length=7, timeUnit=TimeUnit.DAYS)]
     )
   )
   ```

3. **Create isolated branch**
   - Framework automatically creates branch
   - All subsequent operations use branch-specific resources

4. **Run backfill**
   - System intelligently reuses existing aggregates
   - Only computes new/changed features
   - Results stored in branch-specific tables

5. **Train model**
   - Automatically generates training data
   - Integrates with model platforms (SageMaker, VertexAI)
   - Produces branch-specific model version

6. **Evaluate results**
   - Compare metrics against production baseline
   - Generate explainability reports
   - Validate against test cases

7. **Prepare deployment package**
   - Chronon generates production-ready:
     - Serving pipelines
     - Monitoring configs
     - Documentation

8. **Submit for human review**
   - Package includes:
     - Change summary
     - Performance impact
     - Resource requirements
     - Rollback plan

## Best Practices
1. **Safety first**
   - Never modify production resources directly
   - Enforce branch isolation at infrastructure level
   - Set resource limits per agent/team

2. **Efficient experimentation**
   - Leverage partial aggregate caching
   - Reuse unchanged features
   - Prioritize high-impact changes

3. **Production readiness**
   - Ensure all pipelines include:
     - Monitoring
     - Alerting
     - Documentation

## Common Pitfalls
1. **Silent failures**
   - Missing branch isolation
   - Incomplete feature lineage

2. **Cost explosions**
   - Not reusing existing computations
   - No resource quotas

3. **Unreviewable changes**
   - Overly complex modifications
   - Poor documentation

## Validation Steps
1. **Consistency check**
   - Verify training/serving data matches
   - Validate against golden datasets

2. **Performance testing**
   - Load test new pipelines
   - Verify latency/QPS targets

3. **Security review**
   - Check data access patterns
   - Validate isolation boundaries

4. **Reproducibility test**
   - Re-run pipeline from definition
   - Compare outputs
