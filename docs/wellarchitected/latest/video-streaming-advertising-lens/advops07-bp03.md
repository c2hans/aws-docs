---
source_url: https://docs.aws.amazon.com/wellarchitected/latest/video-streaming-advertising-lens/advops07-bp03.html
---

# ADVOPS07-BP03 Establish A/B testing frameworks for ad format experimentation
<a name="advops07-bp03"></a>

 With an A/B testing framework, you can safely test new ad formats (such as overlays, squeezebacks, pause ads, and shoppable ads), placement strategies, and auction configurations.

 **Desired outcome:**
+  Publishers safely test new ad formats, placement strategies, and auction configurations. Each test measures impact on both revenue and viewer engagement.
+  Guardrail metrics halt experiments automatically when the experiments degrade viewer experience past acceptable thresholds.
+  Every experiment defines success criteria, statistical significance thresholds, and minimum sample sizes before launch. This upfront definition prevents premature conclusions from insufficient data.

 **Common anti-patterns:**
+  You make ad format and placement decisions from intuition instead of controlled experimentation.
+  You declare experiment results before reaching statistical significance.
+  You run experiments without guardrail metrics that protect viewer experience.
+  You cannot halt experiments quickly when they degrade engagement or revenue.

 **Benefits of establishing this best practice:**
+  Data-driven ad format and placement decisions replace intuition-based ones.
+  Automated experiment guardrails improves viewer experience.
+  A validated innovation pipeline reduces the risk of new format launches before full rollout.

 **Level of risk exposed if this best practice is not established:** Medium

## Implementation guidance
<a name="implementation-guidance"></a>

 A more intrusive ad format earns more per impression, so the revenue metric almost always moves in the desired direction. Viewers watch less, return less often, or leave. That cost is delayed and diffuse, while the revenue gain is immediate and attributable. An experiment scoped to revenue alone can approve formats that damage the business, and it does so with statistically sound evidence.

 To defend against this, use a guardrail metric that the experiment is not trying to improve. Treat the metric as a hard condition. This only works when you set the bound before you know the result. If you set the bound afterward, the result can be reinterpreted. For example, retention decline could be interpreted as seasonal noise, or a session-length drop could be seen as a measurement artifact.

 Write the bound down in advance. The choice of which viewer-behavior metrics bound the decision should be a business question about acceptable harm.

 Advertising traffic makes statistical discipline harder than the textbook case. Sample size depends on the baseline rate, and the metrics in play span orders of magnitude. A click-through rate in the percent range and one in the fraction-of-a-percent range need different volumes to resolve the same relative effect. Traffic is also periodic: weekday and weekend viewing differ, dayparts differ, and campaign flights start and stop. Run the experiment for at least a full weekly cycle to measure the cycle itself. Both effects push toward longer runs.

 A small initial exposure limits how many viewers see a format that turns out to be harmful. This contains risk only if reversal is fast. The corresponding risk is that a treatment that looks safe at low exposure behaves differently at full traffic. Treat expansion as a decision point.

 The experiment mechanism itself is a source of false results. Misrouted traffic, cohorts that overlap, or metrics attributed to the wrong variant all produce a clean-looking number that describes nothing. That error does not appear in the results. Rule it out by running the mechanism on a test decision before it contains a production decision.

### Implementation steps
<a name="implementation-steps"></a>

1.  **Implement feature flag infrastructure with AWS AppConfig:** Create an AWS AppConfig application and environment for your advertising platform. Define feature flag configurations for each active experiment. For example, an overlay\_ad\_format\_test flag with an enabled\_percentage parameter that controls traffic allocation. Configure AppConfig deployment strategies with automatic rollback when CloudWatch metric alarms breach thresholds. Deploy the AppConfig client SDK in your ad decisioning service to evaluate feature flags on each ad request.

1.  **Validate experiment infrastructure in staging before production experiments:** Before you launch any production experiments, run a complete test experiment in staging. Configure a feature flag. Deploy it to a test traffic percentage. Confirm that audience segmentation, metric collection, and guardrail triggers function correctly. This validation step catches infrastructure configuration issues before they affect production traffic. It also confirms that your metric collection captures experiment cohort data accurately.

1.  **Define statistical significance thresholds and minimum sample sizes by experiment type:** For each advertising metric type (CTR, eCPM, fill rate, and viewer retention), calculate the minimum sample size to detect the minimum detectable effect at 80% power with p<0.05 significance. Document these calculations and enforce them as experiment-duration minimums. An experiment is not eligible for analysis until it reaches the minimum sample size for both treatment and control groups.

1.  **Configure guardrail metrics with automated experiment halt triggers:** Define guardrail metrics for each experiment category. For ad format experiments, use viewer churn rate, session duration, and ad completion rate. Configure CloudWatch alarms on these metrics that compare treatment to control. Set experiment halt triggers in AppConfig. These triggers deactivate the feature flag automatically when a metric breaches a guardrail threshold. Test the halt mechanism before you launch production experiments.

1.  **Establish an experimentation review cadence for completed experiments:** Schedule monthly reviews of completed experiments. In each review, document the experiment results, statistical validity, and implementation decision. For successful experiments (treatment wins on the primary metric with guardrails intact), document the rollout plan. For failed experiments (treatment loses or guardrails breach), document the lessons. Build an experiment-history repository that becomes a searchable knowledge base for future format and configuration decisions.

## Resources
<a name="resources"></a>

 **Related documents:**
+  [AWS AppConfig feature flags documentation](https://docs.aws.amazon.com/appconfig/latest/userguide/appconfig-integration-feature-flags.html)
+  [Amazon CloudWatch metrics documentation](https://docs.aws.amazon.com/AmazonCloudWatch/latest/monitoring/working_with_metrics.html)

 **Related services:**
+  [AWS AppConfig](https://aws.amazon.com/systems-manager/features/appconfig/)
+  [Amazon CloudWatch](https://aws.amazon.com/cloudwatch/)
