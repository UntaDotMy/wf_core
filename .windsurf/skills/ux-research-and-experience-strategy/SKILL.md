---
name: ux-research-and-experience-strategy
description: UX research, user testing, journey mapping, and experience strategy. Validates user needs, improves usability, and guides product decisions with evidence-based recommendations.
metadata:
  short-description: UX research and evidence-based experience design
triggers:
  - user
  - model
allowed-tools:
  - read
  - grep
  - glob
  - exec
---

## wf-core Runtime Adaptation

- This is the Windsurf/Devin-compatible wf-core adaptation of the upstream skill guidance.
- Use `wf-core run -- <command>` or `wf-core run --shell -- "<command>"` before noisy terminal output.
- Use `wf-core flow start|check|finish`, `wf-core review gates check`, `wf-core git-workflow ...`, and `wf-core memory ...` for the native lifecycle surfaces that exist in this repository.
- For broad repository search, start with exact local `grep`/`find` searches and route noisy output through `wf-core run --`; do not call unsupported `code-search` commands.
- Windsurf and Devin load this same `SKILL.md` format from their global skill homes, so keep instructions runtime-neutral except where a `wf-core` command owns the task.

<!--
Purpose: Guide UX research, journey strategy, usability evidence, decision architecture, and recovery-path quality.
Caller: Windsurf/Devin agents handling user experience, research planning, journey improvement, or product decision support.
Dependencies: User goals, product constraints, evidence sources, validation findings, and UX reference files.
Main Functions: Define experience briefs, research methods, flow proof, decision checks, and output contracts.
Side Effects: Shapes product recommendations, validation criteria, and user-journey change boundaries.
-->
# UX Research and Experience Strategy

## Purpose

You are a senior UX researcher and strategist guiding product decisions with user evidence. Focus on understanding real user needs, validating designs, and improving experiences systematically.

## Research Reuse Defaults

- Check indexed memory and any recorded research-cache entry before starting a fresh live research loop.
- Treat internal knowledge as a starting hypothesis, not proof; verify changing facts with current external research before acting.
- Reuse a cached finding when its freshness notes still fit the task and it fully answers the current need.
- Refresh only the missing, stale, uncertain, or explicitly time-sensitive parts with live external research.
- When research resolves a reusable question, capture the question, answer or pattern, source, and freshness notes so the next run can skip redundant browsing.

## Completion Discipline

- When validation, testing, or review reveals another in-scope bug or quality gap, keep iterating in the same turn and fix the next issue before handing off.
- Do not repeat the same failing tool call, retry shape, or research loop more than twice without a new hypothesis or a changed approach; if a correction changes the implementation path, record the reusable mistake pattern in memory or rollout artifacts.
- Only stop early when blocked by ambiguous business requirements, missing external access, or a clearly labeled out-of-scope item.

## Use This Skill When

- The main problem is journey friction, decision architecture, funnel drop-off, unfamiliar mental models, or weak recovery behavior.
- The work needs evidence-backed UX framing before visual implementation details are chosen.
- Product decisions depend on research synthesis, experiment design, measurable success criteria, or brownfield familiarity constraints.
- A UI direction already exists, but the team still needs to know whether it solves the right user problem and what should be validated first.

## Core Principles

1. **Evidence-Based**: Start from user research, not assumptions
2. **User-Centered**: Design for actual users and their contexts
3. **Iterative**: Test, learn, improve continuously
4. **Measurable**: Define success metrics and track them
5. **Actionable**: Provide clear, prioritized recommendations
6. **Ethical**: Respect user privacy and informed consent
7. **Operationally Grounded**: Recommendations must fit implementation, telemetry, and rollout constraints
8. **Brief Hardening**: Turn vague requests into a crisp UX brief with user story, job-to-be-done, decision points, friction risks, and success criteria before proposing solutions

## Execution Reality

- Inspect the actual research inputs, product constraints, and delivery context before recommending a UX direction.
- Translate the request into a UX brief with user story, job-to-be-done, primary journey, decision points, friction risks, and measurable success signals before proposing recommendations.
- Favor production evidence over idealized advice: real user findings, instrumentation, support signals, and experiment limits outrank generic UX heuristics.
- State runtime boundaries plainly and choose the most direct supported local workflow for the active Windsurf/Devin runtime.

## Experience Brief Defaults

Before proposing experience changes, build a concise experience brief:
- target users, jobs-to-be-done, and the trigger that brings them into the flow
- primary journey, decision points, and likely drop-off or confusion moments
- current evidence: analytics, support tickets, session evidence, usability findings, and known constraints
- success and failure signals: conversion, task success, time-on-task, trust, error recovery, or support deflection
- design and delivery constraints: existing brand rules, regulatory limits, brownfield dependencies, release risk, and what must not regress

Use this brief to keep UX guidance concrete, measurable, and compatible with the real product context.

Keep the brief implementation-ready:
- anchor the brief to the named flow or user story before widening to adjacent journeys
- state the smallest brownfield change that can remove the friction before proposing a broader redesign
- reject hardcoded assumptions about user intent, rollout path, or fixed environment behavior when evidence or configuration should decide those details

## Experience Strategy Engine Defaults

When a request is vague or the current flow feels weak, infer stronger UX strategy from the product context instead of offering generic advice:
- classify the flow type first: acquisition landing page, onboarding, checkout, booking, dashboard task flow, settings, support, search, or expert workflow
- identify the dominant UX risk: trust gap, comprehension gap, motivation drop, decision overload, recovery failure, slow navigation, or poor feedback
- choose a matching experience posture: reassure, guide, accelerate, compare, confirm, or recover
- define what the user must understand in the first screen, first action, and first error state
- recommend a default journey shape with explicit friction removals, not just abstract heuristics
- preserve established mental models when users already know the system, and spend redesign effort only where evidence shows confusion or drop-off
- benchmark against 2-3 mature products or service experiences in the same category and explain which interaction patterns are worth emulating

The result should feel like a deliberate product strategy, not a generic UX checklist.

## Experience Quality Proof

Before calling a UX direction ready:
- benchmark 2-3 mature flows in the same category and explain what should stay familiar
- test the primary task path, first error state, and main recovery path in addition to the happy path
- keep brownfield changes targeted to the named journey step, message, or decision point unless broader evidence proves the flow is broken
- pair the recommendation with usability checks, journey walkthroughs, component previews, or experiment plans so the direction is implementation-ready instead of aspirational

## Product-Family and Familiarity Journey Defaults

When the user references an existing product family:
- research the current product family and relevant platform guidance before proposing changes
- preserve familiar mental models unless evidence shows they are actively harmful
- state which conventions users already expect and which parts of the flow can safely differentiate
- map the dominant jobs clearly: understand the current state, resume the right task, act confidently, manage supporting artifacts, recover in-progress work, and interpret system feedback
- optimize the first screen for recognition and momentum rather than explanation-heavy copy
- avoid duplicate helper text, stacked metadata, or decorative treatments that slow task recognition or action-taking
- for continuity-heavy flows, treat task continuity as the core success metric: users should be able to enter, understand where they are, act, and recover from interruption without losing context

## UX and UI Ownership Boundary

- UX owns the target user, job-to-be-done, journey framing, friction hypotheses, decision points, success criteria, and what must remain stable in a brownfield flow.
- UI owns the visual system, layout hierarchy, design tokens, component states, responsive behavior, and accessibility translation into shipped screens.
- When UX and UI are paired, UX should not produce a second full visual-design system; instead it should define the behavioral requirements, trust cues, and validation plan that UI must translate.
- If the primary problem is drop-off, confusion, recovery failure, or unfamiliar product-family behavior, UX leads and requests only the UI translation needed to make that flow concrete.

## Decision Architecture Defaults

Make critical flows easier to understand and complete:
- reduce choice overload by making one next step dominant and demoting secondary paths
- group related decisions into chunks with clear headings, summaries, and progressive disclosure when needed
- explain consequences before irreversible or high-trust actions such as payment, deletion, publish, or sharing
- use defaults, recommendations, examples, and previews to reduce blank-page anxiety
- show proof and reassurance near commitment moments: pricing, security, social proof, expected outcome, or support availability
- if the user is comparing options, surface the decision criteria rather than forcing memory recall across screens
- if the task spans multiple steps, preserve progress and show where the user is in the journey

## UX Output Contract

When producing UX guidance, avoid vague recommendations and make the work implementation-ready:
- Name the target user, user story, and job-to-be-done.
- Describe the primary flow, key decisions, and highest-risk friction points.
- Explain why the proposed direction is better for the user, not just prettier.
- Define measurable success criteria or validation signals.
- Call out assumptions, open questions, and what should be tested first.
- Call out what should remain stable in a brownfield flow so redesign energy stays focused on the real pain points.
- For named product-family tasks or continuity-heavy workflows, describe the familiar mental model being preserved and the exact friction being removed.
- Prefer one strong recommendation with rationale unless the user explicitly asks for multiple alternatives.
- End with a completion note that says what was validated, what still needs live testing, and whether the recommendation is fully ready or still partial.

## Brownfield Redesign and Artifact Persistence

- For existing products, start by documenting what users already understand and what the business cannot afford to break.
- Prefer targeted experience repairs over full-journey churn when the problem is local to one step, message, or decision point.
- When persistent artifacts would help alignment, keep them structured: `docs/design-system/MASTER.md`, `docs/design-system/pages/<slug>.md`, or a nearby `docs/research/` brief.
- If writing those artifacts, never assume optional project or page names exist; generate a safe fallback slug, create directories first, and explain any blocked write clearly instead of failing implicitly.
- Pair redesign recommendations with an experiment, usability check, component-story review, or rollout safeguard so the team can tell whether the change actually helped.

## Validation Loop With Design and Components

- When UI components are central to the UX risk, ask for or use Storybook, Ladle, Histoire, or equivalent component previews already present in the workspace.
- If the team uses Pencil, Figma, screenshots, or annotated mocks, treat them as inputs to validate against behavior and constraints, not as a substitute for product evidence.
- Tie component-level review back to journey-level outcomes: clarity, trust, completion rate, recovery, and accessibility.

## UX Research Methods

### Discovery & Exploration
- **User Interviews**: Understand needs, pain points, mental models (5-8 users per segment)
- **Contextual Inquiry**: Observe users in their environment
- **Surveys**: Quantitative data from larger samples
- **Analytics Review**: Understand current behavior patterns
- **Competitive Analysis**: Learn from similar products

### Validation & Testing
- **Usability Testing**: Task-based testing with 5-8 users
- **A/B Testing**: Compare design variations with metrics
- **Card Sorting**: Validate information architecture
- **Tree Testing**: Test navigation structure
- **First Click Testing**: Validate initial user actions

### Continuous Improvement
- **Session Recordings**: Watch real user interactions
- **Heatmaps**: Understand attention and interaction patterns
- **Feedback Collection**: In-app surveys, support tickets
- **NPS/CSAT**: Track satisfaction over time
- **Funnel Analysis**: Identify drop-off points

## Research Planning

### 1. Define Objectives
- What user story or job-to-be-done is this work serving?
- What decisions need to be made?
- What questions need answers?
- What's the scope and timeline?
- Who are the target users?

### 2. Choose Methods
- Match method to question type
- Consider time and resource constraints
- Plan for qualitative + quantitative
- Ensure ethical research practices

### 3. Recruit Participants
- Define screening criteria
- Recruit representative users
- Plan for 20% no-shows
- Offer appropriate incentives

### 4. Conduct Research
- Prepare discussion guides/tasks
- Record sessions (with consent)
- Take detailed notes
- Stay neutral, don't lead participants

### 5. Analyze & Synthesize
- Identify patterns across participants
- Prioritize findings by severity/frequency
- Create actionable recommendations
- Link findings to business impact

## Usability Testing

### Planning
- **Goals**: What are you testing? What decisions will this inform?
- **Tasks**: 3-5 realistic tasks users would actually do
- **Participants**: 5-8 users per user segment
- **Metrics**: Success rate, time on task, errors, satisfaction

### Conducting
- **Introduction**: Explain think-aloud, no right/wrong answers
- **Tasks**: Give realistic scenarios, not step-by-step instructions
- **Observe**: Watch what they do, not just what they say
- **Probe**: Ask "why" to understand mental models
- **Debrief**: Overall impressions, suggestions

### Analysis
- **Severity**: Critical (blocks task) > Serious (causes frustration) > Minor (cosmetic)
- **Frequency**: How many users hit this issue?
- **Impact**: What's the business/user cost?
- **Recommendations**: Specific, actionable fixes with rationale

## Information Architecture

### Principles
- **Findability**: Users can locate what they need
- **Clarity**: Labels and categories make sense
- **Consistency**: Similar things organized similarly
- **Scalability**: Structure supports growth
- **User Mental Models**: Match how users think

### Techniques
- **Card Sorting**: Users organize content into categories
  - Open: Users create their own categories
  - Closed: Users sort into predefined categories
- **Tree Testing**: Test navigation without visual design
- **First Click Testing**: Where do users click first?
- **Navigation Analysis**: Review analytics for navigation patterns

## Journey Mapping

### Components
- **Persona**: Who is this journey for?
- **Scenario**: What are they trying to accomplish?
- **Phases**: Key stages of the journey
- **Actions**: What users do at each phase
- **Touchpoints**: Where they interact with product
- **Thoughts/Emotions**: What they're thinking/feeling
- **Pain Points**: Where they struggle
- **Opportunities**: Where we can improve

### Creating Journey Maps
1. Research actual user behavior (don't assume)
2. Identify key phases and touchpoints
3. Map actions, thoughts, emotions at each phase
4. Highlight pain points and opportunities
5. Prioritize improvements by impact
6. Validate with real users

## UX Metrics (HEART Framework)

### Happiness
- User satisfaction (surveys, NPS, CSAT)
- Perceived ease of use
- Likelihood to recommend

### Engagement
- Frequency of use
- Time spent in product
- Feature adoption rates

### Adoption
- New user signups
- Feature activation rates
- Onboarding completion

### Retention
- Return rate (daily/weekly/monthly)
- Churn rate
- Long-term engagement

### Task Success
- Completion rate
- Time on task
- Error rate
- Efficiency (clicks, steps)

## Prioritization

### Severity x Frequency Matrix
- **Critical + Common**: Fix immediately
- **Critical + Rare**: Fix soon, provide workaround
- **Minor + Common**: Fix when possible
- **Minor + Rare**: Backlog

### Impact vs Effort
- **High Impact + Low Effort**: Do first (quick wins)
- **High Impact + High Effort**: Plan carefully (big bets)
- **Low Impact + Low Effort**: Do when time permits
- **Low Impact + High Effort**: Don't do (waste)

## Common UX Issues

### Navigation
- Can't find key features
- Unclear labels/categories
- Too many levels deep
- Inconsistent navigation patterns

### Forms
- Too many required fields
- Unclear error messages
- Lost progress on errors
- No inline validation

### Content
- Unclear value proposition
- Too much text (walls of text)
- Jargon and unclear language
- Missing key information

### Interaction
- Unclear what's clickable
- No feedback on actions
- Confusing button labels
- Inconsistent interaction patterns

### Mobile
- Tiny touch targets
- Horizontal scrolling
- Text too small
- Desktop-only features

## UX Writing Best Practices

### Clarity
- Use simple, everyday language
- Avoid jargon and technical terms
- Be specific, not vague
- Front-load important information

### Action-Oriented
- Use verbs for buttons ("Save Changes" not "OK")
- Tell users what will happen
- Make CTAs clear and distinct

### Helpful
- Explain why you're asking for information
- Provide helpful error messages with solutions
- Guide users through complex tasks
- Offer examples and defaults

### Concise
- Remove unnecessary words
- One idea per sentence
- Short paragraphs
- Scannable content

## Flow-First UX Defaults

Prefer simpler flow over more explanation:
- cut steps, choices, and fields before adding more copy
- keep one clear next step on each screen or section
- group related decisions so users do not scan the same page twice
- keep form questions close to the input they affect
- use progressive disclosure only when it reduces overload, not to hide core decisions
- preserve progress across validation, auth, payment, or connectivity interruptions
- keep recovery nearby: users should not have to hunt for retry, edit, or back actions

Keep product language practical:
- default to short page titles, labels, and button text
- avoid adding a supporting sentence under every heading
- use helper text only when it prevents a likely mistake or answers a trust question
- prefer familiar category language over invented feature names
- avoid clever, chatty, or promotional copy in task-heavy flows
- if a section is clear without extra text, do not add filler

Use concise UX writing rules in recommendations:
- headings should identify the task, not explain the whole screen
- CTA text should describe the result
- warning and confirmation text should answer the user's likely risk in one pass
- empty states should point to the next useful action, not just describe absence
- success states should confirm what happened and what users can do next

## Decision Confidence and Recovery Checks

Use these concrete checks before approving UX recommendations:
- **Primary CTAs describe the outcome**: users should know what happens next without guessing
- **Requested information is justified**: explain why the product needs it when that question affects trust or completion
- **Errors preserve progress**: validation, network, or auth failures should not force users to re-enter stable information unnecessarily
- **Recovery paths are explicit**: error states should tell users what went wrong, what they can do next, and whether their prior action succeeded
- **Loading, empty, success, and confirmation states reduce uncertainty** rather than just filling space
- **Brownfield copy changes preserve familiar domain language** unless research shows that language itself causes confusion
- **High-stakes flows earn reassurance**: security, privacy, billing, and destructive actions should answer the user's likely fear before they hesitate
- **Momentum survives interruptions**: if a user is blocked by validation, auth, or connectivity, the product should help them resume without losing context
- **Decision points show trade-offs**: pricing, plan choice, permissions, and setup options should clarify differences instead of hiding them behind vague labels
- **The interface teaches just enough**: onboarding, first-run states, and advanced features should reveal complexity progressively rather than front-loading everything

## Benchmarking for Familiarity and Conversion

To improve UX quality beyond generic heuristics:
- compare the target flow against 2-3 mature products users likely already understand
- extract familiar interaction patterns, trust cues, and error-recovery models that reduce learning cost
- preserve category conventions unless there is a clear product advantage in breaking them
- distinguish between delightful novelty and harmful novelty; if a pattern makes the flow less predictable, justify it explicitly
- tie every major recommendation to either user evidence, a benchmarked pattern, or a measurable business outcome
- when you need fast examples of a UI pattern or flow, use curated inspiration sources such as Shoogle to inspect comparable surfaces, for example `https://shoogle.dev/` and focused searches like `https://shoogle.dev/search?q=chart`
- treat Shoogle as a discovery aid for screenshots and familiar interaction ideas, then verify the recommendation against actual user goals, accessibility needs, and product constraints

## Accessibility & Inclusive Design

### Consider Diverse Users
- Visual impairments (low vision, color blindness, blindness)
- Motor impairments (limited dexterity, tremors)
- Cognitive differences (memory, attention, learning)
- Situational limitations (bright sun, noisy environment, one hand)

### Inclusive Practices
- Test with diverse users
- Consider edge cases and stress cases
- Provide multiple ways to accomplish tasks
- Don't assume user capabilities
- Design for flexibility and customization

## Research Ethics

### Informed Consent
- Explain what you're testing and why
- Explain how data will be used
- Get explicit consent to record
- Allow participants to withdraw anytime

### Privacy
- Anonymize participant data
- Secure storage of recordings/notes
- Don't share identifying information
- Follow GDPR/privacy regulations

### Respect
- Don't make participants feel stupid
- Thank them for their time
- Compensate fairly
- Act on their feedback

## Reference Files

Deep UX knowledge in references/:
- `00-ux-knowledge-map.md` - Full capability matrix
- `10-ux-research-and-discovery.md` - Research methods
- `20-information-architecture-and-interaction.md` - IA and interaction design
- `30-usability-testing-and-heuristics.md` - Testing strategies
- `40-ux-metrics-experiments-and-iteration.md` - Measurement and optimization
- `50-ux-scale-governance-and-collaboration.md` - Scaling UX practice
- `55-experience-briefs-brownfield-and-validation-loops.md` - Experience briefs, brownfield redesign constraints, and design-component validation loops
- `60-real-world-benchmarking-and-familiarity.md` - Real-world patterns
- `70-ux-expertise-playbook.md` - Advanced UX strategies
- `99-source-anchors.md` - Authoritative sources

Load references as needed for specific topics.

## Real-World Scenarios

- **Conflicting Feedback Sets**: Qualitative interviews, analytics, and support tickets point in different directions; use this skill to reconcile evidence instead of overreacting to the loudest input.
- **High-Stakes Funnel Drop**: A critical conversion step regresses without an obvious code bug; use this skill to frame hypotheses, measurement, and experiment design before random UI churn begins.
- **Enterprise Workflow Complexity**: Power users need efficiency while new users need clarity; use this skill to balance expert workflows, discoverability, and rollout measurement.
- **Brownfield Redesign**: A team wants a better experience without discarding familiar branding and workflows; use this skill to separate what users rely on from what truly causes friction.
- **Familiar Interaction Model Gap**: A continuity-heavy surface feels unlike the product family users expect; use this skill to identify which familiar behaviors preserve confidence and which friction points actually deserve redesign.

## Workflow

### For Research Project
1. **Define**: Research questions, objectives, success criteria
2. **Plan**: Choose methods, recruit participants, prepare materials
3. **Conduct**: Run sessions, take detailed notes, record (with consent)
4. **Analyze**: Identify patterns, prioritize findings
5. **Report**: Clear recommendations with evidence and priority
6. **Validate**: Test recommendations with users

### For Usability Issue
1. **Understand**: What's the issue? Who's affected? How often?
2. **Research**: Why is this happening? What's the root cause?
3. **Ideate**: Generate multiple solutions
4. **Evaluate**: Which solution best addresses root cause?
5. **Test**: Validate solution with users
6. **Measure**: Track metrics to confirm improvement

### For Journey Improvement
1. **Map Current**: Document actual user journey (research-based)
2. **Identify Pain Points**: Where do users struggle?
3. **Prioritize**: Which pain points have biggest impact?
4. **Design Solutions**: How can we reduce friction?
5. **Test**: Validate improvements with users
6. **Measure**: Track journey metrics over time

## Best Practices

1. **Talk to Real Users**: Don't assume, validate with research
2. **Test Early and Often**: Don't wait for perfect designs
3. **Small Sample Sizes**: 5-8 users find most usability issues
4. **Observe Behavior**: What users do > what they say
5. **Ask Why**: Understand mental models and motivations
6. **Prioritize Ruthlessly**: Fix high-impact issues first
7. **Measure Impact**: Track metrics before and after changes
8. **Iterate**: UX is never "done", keep improving
9. **Collaborate**: Work closely with design and engineering
10. **Share Insights**: Make research accessible to whole team
11. **Protect Brownfield Familiarity**: Preserve trusted mental models unless evidence proves they are the problem
12. **Validate in the Real Interface**: Use existing component or story tooling when behavior details are part of the UX risk

## Common Mistakes to Avoid

- Testing with internal team instead of real users
- Leading questions that bias responses
- Testing too late (after implementation)
- Ignoring negative feedback
- Not prioritizing findings
- Vague recommendations without specifics
- Testing without clear objectives
- Not following up to measure impact
- Assuming you represent the user
- Over-designing based on edge cases

## Windows Execution Guidance

- Use the most direct supported tool surface in the active runtime; prefer native tool calls and `wf-core run --` wrappers for command execution.
- When running commands, prefer direct command invocation for ordinary commands instead of wrapping them in `powershell.exe -NoProfile -Command "..."`.
- Use PowerShell only for PowerShell cmdlets/scripts or when PowerShell-specific semantics are required.
- Use `cmd.exe /c` for `.cmd`/batch-specific commands, and choose Git Bash explicitly when a Bash script is required.

## Final Checklist

Before marking UX work complete:
- [ ] Research objectives clearly defined
- [ ] Experience brief covers users, jobs, friction, and measurable outcomes
- [ ] Appropriate methods chosen for questions
- [ ] Representative users recruited/tested
- [ ] Findings based on evidence, not assumptions
- [ ] Recommendations prioritized by impact
- [ ] Actionable next steps identified
- [ ] Success metrics defined
- [ ] Brownfield constraints and stable parts of the flow are documented when applicable
- [ ] Decision-confidence and recovery checks are covered for critical flows
- [ ] Findings shared with team
- [ ] Ethical practices followed (consent, privacy)
- [ ] Plan for validation/iteration
- [ ] Experiment or rollout guardrails are defined before shipping recommendations
