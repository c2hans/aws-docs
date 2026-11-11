---
source_url: https://docs.aws.amazon.com/wellarchitected/latest/video-streaming-advertising-lens/advcost05-bp07.html
---

# ADVCOST05-BP07 Continuously evaluate new models, features, and pricing options to optimize agentic AI advertising costs over time
<a name="advcost05-bp07"></a>

 Managed model services release new foundation models and cost optimization features regularly. Newer models often match or beat older ones on quality at lower cost. Ongoing evaluation limits resource consumption drift and keeps your advertising agent architecture current.

 **Desired outcome:**
+  New models are evaluated against advertising agent benchmarks and promoted to production only after quality regression testing passes.
+  Cost-per-business-outcome trends are tracked to identify efficiency degradation before it compounds.
+  Semi-annual architecture reviews assess whether tasks should be shifted to rule-based logic when AI adds marginal value at disproportionate cost.

 **Common anti-patterns:**
+  Deploying agents with a specific model and never re-evaluating, even as newer models offer equivalent quality at 50–80% lower cost per token.
+  Optimizing prompts or swapping models without regression testing, so quality degradation only surfaces after production deployment affects campaign outcomes.
+  Tracking only aggregate Amazon Bedrock spend without calculating cost-per-business-outcome, which hides which agents are becoming less cost-efficient over time.
+  Ignoring new Amazon Bedrock features after initial architecture deployment, so cumulative savings from capabilities like prompt caching, batch inference, or Intelligent Prompt Routing go unrealized.
+  Maintaining AI-powered agents for tasks that have become deterministic or rule-based over time, which pays inference costs for predictable outputs that basic logic could produce at near-zero cost.

 **Benefits of establishing this best practice:**
+  Ongoing cost reduction as newer, more efficient models replace older assignments across the agent fleet.
+  Quality protection through automated regression testing before any cost optimization reaches production.
+  Clear cost-per-outcome visibility that connects inference spend to business value and identifies degrading efficiency early.
+  Architectural agility to adopt new Bedrock capabilities rapidly and retire agents that no longer justify their inference costs.

 **Level of risk exposed if this best practice is not established:** High

## Implementation guidance
<a name="implementation-guidance"></a>

 New model releases on [Amazon Bedrock](https://aws.amazon.com/bedrock/) often deliver equivalent quality at 50 to 80% lower per-token cost than their predecessors. An agent architecture that was cost-optimal at deployment loses relative efficiency with each new release you don't evaluate. The gap between actual spend and achievable spend widens without any visible change in system behavior.

 A model update can degrade quality. A cheaper model with worse outputs for your advertising tasks costs more in business impact than it saves in inference. Regression testing requires a benchmark dataset for each agent: representative prompts with human-evaluated expected outputs that define acceptable quality. With the benchmark in place, promotion is routine: run the benchmark, compare scores against the baseline, and promote the model only if quality meets the threshold.

 Track cost-per-outcome (cost per campaign plan generated, cost per brand safety assessment completed) to see whether inference spend is justified. When it rises, either the agent is consuming more tokens per task (from prompt bloat, more iterations, or degraded prompt efficiency), or it is producing fewer successful outcomes per invocation (from lower quality or higher failure rates). Review this metric monthly to catch efficiency problems before they compound.

 Semi-annual architecture reviews catch tasks that no longer require AI inference. Agents built to handle variable tasks sometimes converge on predictable patterns over time. A brand safety classifier trained on historical decisions might produce outputs that a rule-based system could replicate at near-zero marginal cost. To find these candidates, examine output variance. If an agent produces the same classification 95% of the time regardless of the input, deterministic logic can replace it.

 New Bedrock capabilities such as prompt caching, Intelligent Prompt Routing, batch inference, and model distillation release independently of model updates. Each can reduce cost but requires architectural changes to adopt. Run a feature-adoption review on its own cadence, separate from model evaluation, to evaluate new capabilities against the current architecture without waiting for a major redesign.

### Implementation steps
<a name="implementation-steps"></a>

1.  **Maintain benchmark datasets for each advertising agent type:** Create test suites with representative advertising prompts and expected outputs for each agent (media planning queries, brand safety assessments, and ad load optimization requests). Run these benchmarks against current model assignments to establish baseline quality scores and cost-per-invocation.

1.  **Implement automated regression testing for model changes:** Before promoting any model swap or configuration change to production, run the updated agent through the benchmark suite. Compare quality scores against the baseline. Gate production deployment on quality scores meeting defined thresholds. This keeps cost optimization from inadvertently degrading agent output quality.

1.  **Enable Bedrock agent tracing and build automated analysis pipelines:** Enable tracing for all production agents. Deploy AWS Lambda or AWS Glue jobs that parse stored traces to identify: agents with consistently high iteration counts (may indicate prompt design issues), knowledge base queries returning low-relevance results, and tool calls that consistently fail and trigger retries.

1.  **Build cost-per-outcome dashboards and review monthly:** Create Quick dashboards tracking cost per campaign plan, cost per brand safety assessment, and cost per ad load recommendation. Pull cost data from Cost Explorer (filtered by agent inference profile) and outcome counts from application logs. Review monthly with advertising operations stakeholders to identify agents where efficiency is degrading.

1.  **Conduct semi-annual architecture reviews:** Twice a year, assess the complete agent topology. Ask whether agents have become more deterministic as the underlying problem has been solved and could be replaced with rule-based logic at much lower cost, and whether any agent's output quality has degraded to the point where its business value no longer justifies its inference cost. Actively retire or simplify agents that no longer justify their cost.

## Resources
<a name="resources"></a>

 **Related best practices:**
+  [ADVCOST05-BP02 Select the right foundation model for each advertising agent's task complexity](advcost05-bp02.md)

 **Related documents:**
+  [Effective cost optimization strategies for Amazon Bedrock](https://aws.amazon.com/blogs/machine-learning/effective-cost-optimization-strategies-for-amazon-bedrock/)
+  [Guidance for Advertising Agents on AWS](https://aws.amazon.com/solutions/guidance/advertising-agents-on-aws/)

 **Related services:**
+  [Amazon Bedrock](https://aws.amazon.com/bedrock/)
+  [Quick](https://aws.amazon.com/quicksight/)
+  [AWS Glue](https://aws.amazon.com/glue/)
