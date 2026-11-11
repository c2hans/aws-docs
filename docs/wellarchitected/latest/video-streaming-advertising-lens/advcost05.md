---
source_url: https://docs.aws.amazon.com/wellarchitected/latest/video-streaming-advertising-lens/advcost05.html
---

# Agentic AI cost optimization
<a name="advcost05"></a>

 In high-scale adtech environments engineered for low-latency and high-volume operations, fraudulent activity directly amplifies usage across compute, storage, and networking resources. Design fraud detection pipelines to minimize redundant processing and optimize inference costs through caching known outcomes, filtering threats as early as possible, and running only necessary inference steps on cost-efficient compute. Beyond fraud detection, agentic AI advertising workloads on Amazon Bedrock incur costs through foundation model inference, knowledge base retrieval, and multi-agent orchestration. Without ongoing cost monitoring tied to business outcomes, spending grows unchecked as agent usage scales with campaign activity. The highest-impact optimizations are matching model capability to task complexity, optimizing token consumption, and aligning pricing models to invocation patterns.

|  ADVCOST05: How do you minimize the cost of agentic AI in advertising, including fraud detection and inference, while maintaining quality?  |
| --- |
| [ADVCOST05-BP01 Design fraud detection pipelines to minimize redundant processing and optimize inference costs](advcost05-bp01.md) |
| [ADVCOST05-BP02 Select the right foundation model for each advertising agent's task complexity](advcost05-bp02.md) |
| [ADVCOST05-BP03 Implement prompt caching and optimize prompt design to minimize token consumption](advcost05-bp03.md) |
| [ADVCOST05-BP04 Optimize knowledge base indexing frequency and retrieval strategies to minimize costs](advcost05-bp04.md) |
| [ADVCOST05-BP05 Design small, focused agents and use appropriate orchestration patterns to minimize multi-agent collaboration costs](advcost05-bp05.md) |
| [ADVCOST05-BP06 Use provisioned throughput for steady-state agents and on-demand pricing for variable workloads](advcost05-bp06.md) |
| [ADVCOST05-BP07 Continuously evaluate new models, features, and pricing options to optimize agentic AI advertising costs over time](advcost05-bp07.md) |

## Capability intent
<a name="advcost05-capability-intent"></a>
+  Known-bad traffic is blocked at the network edge using AWS WAF rules, avoiding compute costs for processing traffic destined for rejection.
+  ML inference runs only on ambiguous cases that simpler upstream filters can't resolve.
+  Fraud evaluation results are cached for known creatives, IPs, and device IDs to avoid reprocessing identical inputs.
+  Each advertising agent uses the least expensive foundation model that meets its quality threshold, validated through benchmarking.
+  Common context blocks (campaign taxonomies, audience schemas, brand safety rules) are cached and reused across agent invocations at reduced token rates.
+  Knowledge bases sync only when underlying data changes, with chunk sizes and retrieval counts optimized for minimum token consumption.
+  Multi-agent orchestration uses the minimum number of invocations needed. Deterministic workflows bypass supervisor overhead, and iteration limits are bounded.
+  Steady-state advertising agents use Provisioned Throughput when volume exceeds the break-even point. Bursty agents use on-demand pricing, and latency-tolerant workloads use batch inference.
+  A repeatable process exists for evaluating new models against advertising agent benchmarks and promoting cost-optimized configurations after quality regression testing passes.

## Common issues to watch for
<a name="advcost05-common-issues-to-watch-for"></a>
+  Running full ML inference on every bid request without first checking whether the creative, IP, or device ID has already been evaluated and cached.
+  Applying the same expensive evaluation pipeline to all traffic regardless of risk signal.
+  Assigning the same high-capability model to all agents regardless of task complexity, paying premium per-token costs for tasks that simpler models handle equivalently.
+  Sending full campaign taxonomies and audience schemas in every agent invocation without using prompt caching.
+  Re-indexing all knowledge base data sources on the same aggressive schedule regardless of change frequency.
+  Not setting MaxIterations on agents, enabling reasoning loops that consume tokens without producing better outputs.
+  Using on-demand pricing for all agents regardless of volume, overpaying for steady-state agents above the Provisioned Throughput break-even point.
+  Deploying agents with a specific model and never re-evaluating, even as newer models offer equivalent quality at 50-80% lower cost per token.
