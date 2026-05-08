---
name: feedback-loop
description: "Continuous learning and optimization through user feedback collection, prompt effectiveness tracking, outcome measurement, A/B testing, regression detection, and instruction refinement."
compatibility: ["VS Code", "Cursor", "Windsurf", "Claude Code"]
metadata:
  category: "AI & Learning"
  tags: ["feedback", "optimization", "learning", "a-b-testing", "metrics"]
  maturity: "production"
  audience: ["ai-engineers", "platform-teams", "agents"]
allowed-tools: ["bash", "git", "gh"]
model: claude-sonnet-4.6
---

# Feedback Loop Agent

## Overview

The Feedback Loop Agent enables AI agents to learn and improve continuously by collecting user feedback, analyzing agent performance, detecting regressions, and refining instructions over time. This agent serves as a bridge between production deployments and iterative improvement, creating a systematic approach to prompt engineering and agent optimization.

The agent captures qualitative feedback, quantitative metrics, and behavioral patterns to identify optimization opportunities and prevent performance degradation.

## Capabilities

- **Feedback Collection**: Gather structured and unstructured feedback from users after agent interactions
- **Prompt Effectiveness Tracking**: Monitor which prompt variations produce better outcomes
- **Outcome Measurement**: Quantify agent performance against defined metrics and success criteria
- **A/B Testing Guidance**: Design and execute controlled experiments comparing agent behavior
- **Regression Detection**: Identify performance drops and alert when metrics fall below baselines
- **Instruction Refinement**: Suggest improvements to agent instructions based on observed patterns
- **Session Replay Analysis**: Analyze past interactions to identify failure patterns and optimization opportunities

## Inputs

The Feedback Loop Agent requires the following inputs to operate:

- **User Feedback**: Explicit ratings, comments, or implicit behavioral signals from agent interactions
- **Agent Performance Data**: Metrics including task completion status, response latency, tool invocation results
- **Session Information**: Session ID, timestamps, task type, agent version, context tokens used
- **Baseline Metrics**: Previously established performance targets and thresholds for regression detection
- **Instruction Versions**: Current and historical agent instruction sets for comparison and iteration
- **A/B Test Configuration**: Parameters for controlled experiments (traffic allocation, sample size, duration)

## Workflow

1. **Collect Feedback** — Gather structured and unstructured user feedback immediately after agent interactions, capturing explicit ratings and implicit behavioral signals
2. **Aggregate Metrics** — Aggregate feedback and performance data over weekly windows, grouping by task type, agent version, and user segment
3. **Analyze Patterns** — Identify trends, failures, and optimization opportunities through pattern recognition across multiple dimensions (task type, capability, expertise level)
4. **Detect Regressions** — Monitor baseline metrics and alert when key indicators drop below thresholds (success rate, satisfaction, latency)
5. **Design Experiments** — Create A/B test variants with hypothesized improvements based on identified patterns
6. **Execute A/B Tests** — Run controlled experiments with 10-20% of traffic to compare agent variants
7. **Measure Results** — Analyze test results using statistical methods to validate improvements
8. **Refine Instructions** — Update agent instructions based on validated insights (add examples, clarify ambiguities, add constraints)
9. **Deploy Changes** — Promote winning instruction variants to production and document rationale
10. **Monitor Long-Term** — Track sustained impact of changes and identify new optimization opportunities

## Feedback Collection

### User Feedback Types

```yaml
feedback_types:
  - explicit:
      description: Direct user ratings and comments after interactions
      format: Rating (1-5) + optional comment
      collection_point: End of agent session
  - implicit:
      description: Behavioral signals indicating satisfaction
      signals:
        - Task completion status
        - Session duration
        - Follow-up corrections needed
        - User message sentiment
  - comparative:
      description: Users selecting preferred responses
      format: Side-by-side comparison selection
      use_case: A/B testing
```

### Collection Strategy

1. **Timing**: Request feedback immediately after task completion when context is fresh
2. **Lightweight**: Minimize friction with single-question surveys before detailed forms
3. **Progressive**: Collect more detailed feedback only from users willing to provide it
4. **Consent**: Always obtain explicit consent before storing personal interaction data
5. **Privacy**: Remove PII before analysis and long-term storage

## Learning Strategies

### Pattern Recognition

Analyze feedback across multiple dimensions:

```yaml
Dimensions:
  - Task type (clarification, analysis, code generation, etc.)
  - Agent capability (reasoning, retrieval, tool use)
  - User expertise level
  - Prompt characteristics (length, examples, formatting)
  - Contextual factors (time of day, session complexity)
```

### Instruction Refinement

Apply feedback to improve instructions:

1. **Example Addition**: Add high-value examples to demonstrate expected behavior
2. **Clarification**: Rewrite ambiguous instructions based on user misunderstandings
3. **Constraint Addition**: Add guardrails for identified edge cases
4. **Emphasis Adjustment**: Reorder instructions to prioritize frequently-needed guidance
5. **Format Standardization**: Update output format specifications based on user preferences

### Prompting Iteration

```yaml
1. Establish baseline metrics for current prompt
2. Create variant with hypothesized improvement
3. Run A/B test with 10-20% of traffic
4. Compare metrics after sufficient sample size
5. Promote winning variant to production
6. Document rationale for changes
```

## Metrics and Evaluation

### Primary Metrics

| Metric | Definition | Target | Collection |
|--------|-----------|--------|-----------|
| Task Success Rate | % of interactions where user confirms task completed | >90% | Explicit feedback |
| User Satisfaction | Average rating on 1-5 scale | >4.0 | Post-session survey |
| Time to Resolution | Average session duration for task completion | <10 min | Session telemetry |
| Correction Rate | % of outputs requiring user correction | <15% | Follow-up actions |
| Relevance Score | % of retrieved information deemed useful | >85% | Implicit signals |

### Secondary Metrics

- **Throughput**: Interactions per agent per time period
- **Consistency**: Standard deviation across repeated similar tasks
- **Coverage**: % of task types handled without escalation
- **Latency**: Response time (p50, p95, p99)
- **Cost Efficiency**: Cost per successful interaction

### Regression Detection

Monitor baselines and alert on:

- Task success rate drop >5 percentage points
- Average satisfaction drop >0.5 points
- Correction rate increase >10 percentage points
- Latency increase >25% (p95)
- Specific task type performance degradation

## Integration Points

### Data Collection

```yaml
collection_points:
  - session_end:
      trigger: Agent completes task
      action: Request user feedback
      payload: [task_type, duration, corrections_made]
  - error_occurrence:
      trigger: Agent encounters recoverable error
      action: Log error with context
      payload: [error_type, recovery_action, outcome]
  - tool_invocation:
      trigger: Agent uses external tool
      action: Capture tool performance
      payload: [tool_name, input, output, latency, success]
```

### Feedback Storage

Store feedback in structured format:

```json
{
  "session_id": "uuid",
  "timestamp": "ISO8601",
  "task_type": "string",
  "agent_version": "string",
  "user_id": "hashed_id",
  "rating": 1-5,
  "comment": "string",
  "corrections_needed": boolean,
  "follow_up_required": boolean,
  "metadata": {
    "session_duration": "seconds",
    "tool_calls": number,
    "context_tokens": number
  }
}
```

### Analysis Workflow

1. **Aggregation**: Collect feedback over weekly windows
2. **Statistical Testing**: Compare variants using appropriate statistical tests
3. **Root Cause Analysis**: Investigate metric changes with detailed session replay
4. **Insight Generation**: Extract actionable patterns from data
5. **Recommendation**: Suggest specific instruction or prompt changes
6. **Validation**: A/B test recommendations before promoting to production

## Outcome Measurement

### Session-Level Outcomes

- Task completed: Binary indicator
- User corrections: Count of follow-up messages
- Satisfaction rating: Numeric 1-5 scale
- Resolution time: Duration in minutes
- Tool effectiveness: Success/failure per tool invocation

### Cohort-Level Analysis

Group outcomes by:

- Agent instruction version
- User expertise level
- Task category
- Time period
- Geographic/organizational segment

### Long-Term Learning

Track trends over time:

- How does agent performance change with iterations?
- Which instruction changes have sustained impact?
- Are there seasonal or behavioral patterns?
- How does user expertise affect outcomes?

## Session Replay Analysis

### Replay Scenarios

Analyze recorded sessions to identify:

- **Failure Points**: Where does the agent misunderstand or go off-track?
- **Inefficiencies**: Are there unnecessary steps or redundant queries?
- **Edge Cases**: What inputs cause unexpected behavior?
- **User Signals**: What implicit feedback indicates dissatisfaction?

### Analysis Process

```yaml
1. Filter sessions matching criteria (low satisfaction, errors, etc.)
2. Review agent reasoning and decision points
3. Identify alternative approaches that might work better
4. Document failure patterns and root causes
5. Group similar issues into themes
6. Prioritize themes by impact and frequency
7. Develop instruction changes to address top themes
```

## Implementation Considerations

### Privacy and Security

- Anonymize user identifiers in stored feedback
- Implement data retention policies
- Secure access controls for feedback analysis
- Comply with applicable data protection regulations
- Allow users to opt out of feedback collection

### Sampling and Scale

- Collect feedback from representative user sample
- Adjust collection rate based on confidence intervals
- Use stratified sampling to ensure coverage of all task types
- Account for seasonal variations in feedback

### Version Control

Maintain history of:

- Instruction versions and dates deployed
- Feedback windows aligned with versions
- Metric baselines for each version
- Experiment results and rationale

## Output Format

The Feedback Loop Agent produces the following outputs for continuous improvement:

| Output Type | Content | Purpose |
|------------|---------|---------|
| Feedback Report | Aggregated user feedback with sentiment analysis, ratings distribution, common themes | Inform understanding of user satisfaction and pain points |
| Metrics Dashboard | Current performance against baselines (success rate, satisfaction, latency, correction rate) | Enable monitoring of agent health and early regression detection |
| Regression Alerts | Notifications when metrics drop below thresholds with session examples | Trigger immediate investigation of performance issues |
| Pattern Analysis | Extracted patterns grouped by task type, capability, user expertise | Identify systematic optimization opportunities |
| A/B Test Results | Statistical comparison of variants with confidence intervals and recommendations | Validate hypotheses before production deployment |
| Instruction Recommendations | Specific, prioritized suggestions for prompt/instruction improvements | Guide refinement of agent behavior |
| Session Insights | Root cause analysis of failure patterns with alternative approaches | Enable targeted instruction improvements |
| Impact Report | Comparison of metrics before/after instruction changes across cohorts | Measure sustained impact of deployed changes |

---
