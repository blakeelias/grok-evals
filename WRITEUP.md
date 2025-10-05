# Grok Evaluation for Human Collaboration

## Introduction

A key goal for AI development should be effective collaboration with human partners. While early AI research focused on getting computer systems to exhibit even a basic degree of autonomy or competence, more recent literature has acknowledged that even an AI which is fully autonomous and competent at achieving its goals could still pursue the "wrong" goals. Such an AI would end up being irrelevant (or worse) to human interests. A key question of our technological era is thus: what does it mean for humans to be in right relationship with technology / what does it mean for humans and computer or AI systems to co-exist well?

One framing of this is that a human user should set the agenda, and the AI should alternate between acting autonomously and seeking user input so as to maximally advance the human's interests. Here I investigate Grok's performance on the $\Tau^2$ benchmark which tests the ability for an AI system to aid a human in achieving a task, where both human and AI have access to a set of tools through which to solve the problem at hand.


----


A key bottleneck in getting the full value from AI assistants is communicating one's preferences and goals to the AI agent. Today's AI agents do not have perfect knowledge of the human user's preferences _a priori_, and thus much of the time spent interacting with AI systems is spent explaining one's preferences and subsequently validating whether the AI-produced outputs match those preferences. 

If the AI agent had perfect knowledge of the human user's preferences, then in theory a maximally-competent agent could act autonomously and optimally at satisfying those preferences. As AI agents become more competent (via training on larger datasets of mathematical proofs, programs etc., and via continual learning to enable more direct interaction with the world), we can expect that the bottleneck on these agents' utility will become their ability to efficiently gather requirements and understand human users' preferences and goals.

If the AI had perfect understanding of the user's goals, then in principle a maximally-competent agent could autonomously complete a task satisfactorily with zero input from the user. However this is often not the case, which leads to an otherwise competent and capable AI system being of little value. As the saying goes: "if you want something done right, do it yourself." 

In this work, I assess Grok on $\Tau^2$ bench and propose an extension that introduces ambiguity and measures how efficiently the model collaborates with humans to resolve uncertainty. 

## Grok Assessment

## Benchmark Critique

By design, $\Tau^2$ assumes perfect goal alignment, in which the AI's challenge is execution rather than interpretation and exercising judgment. In practice, ambiguity and evolving human preferences are central to collaboration.


The $\Tau^2$ benchmark does not include scenarios where the user intent is ambiguous which would require the AI agent to seek clarification. In $\Tau^2$, if the AI agent had access to all the same tools as the human, then in principle the agent could solve the entire problem itself and verify the outcome. However, the more realistic and challenging scenarios are those in which the user's intent is ambiguous and the user's subjective judgment is required to evaluate whether the task was completed satisfactorily. Here the agent's task is not only to predict the stream of tokens that a reasonable AI agent would say or do in a given scenario, but to predict what _this particular human_ will like or not, whether they will deem a given solution complete or ask for more refinement, and 
what they might do next if doing the task entirely by hand.

## Benchmark Improvements


* Better Methodology:  ??

* New Test Cases or Scenarios

"I propose extending τ²-bench into what could be called τ²-A: Human-in-the-Loop Ambiguity Evaluation. Whereas τ² assumes both participants share a fully specified goal and the challenge lies in coordinating tool use, τ²-A introduces structured uncertainty about the human’s intent. The AI must decide when to act autonomously, when to seek clarification, and how to minimize unnecessary interruptions—balancing efficiency with epistemic humility. Each scenario begins with a partially specified user request, with additional clarifying information available only through explicit “human query” tool calls. Performance is thus measured not only by task success but by how intelligently the agent manages communication: resolving ambiguity with minimal human effort and without premature assumptions. This turns evaluation from a static assessment of execution into a dynamic study of interactive reasoning, testing whether the model can adaptively collaborate with a human partner to uncover and satisfy evolving goals."

Human-in-the-loop Ambiguity Evaluation (HAE)

I propose adding examples which require the AI agent to interpret vague human intent, ask for clarification, explore the environment and see what ambiguity it can resolve for itself, and judge when it has made sufficient progress to be worth checking back in with the human user.

I propose evaluating a model's performance on these examples in the following way:
 - Some positive score for completing the task correctly (potentially with partial credit), proportional to how much human time it would have taken to complete this task otherwise
 - A penalty proportional to the length of the reasoning trace required to complete the task (completing the task more quickly is better)
 - Penalty proportional to the number of times the AI agent makes a "tool-call" requesting human input ("context-switching cost" for the human)
 - Penalty proportional to the number of tokens the human agent ends up writing (shorter human responses are better; longer responses take the human more time)

Conducting this evaluation would require having either a real human user, or a simulated human user represented as an LLM. The user would provide an intentionally vague statement of their desire (e.g. just a few words or a short sentence), and the AI agent would be measured on how well it disambiguates and fulfills the request, according to the criteria above. The AI agent would have access to a tool-call in which it can ping the human user to ask for clarification or present its work thus far. 

If the human user is being simulated by an LLM, the user LLM would have a held-out "full" description of its desires which live in the user's head, which might be a paragraph long. With the idea being that typing out this full set of desires would take the human too long, the user would be instructed to only share partial clarification: to answer the AI agent's questions but not to write the full description of its desires. 

There would be a "ground-truth" execution trace of what the human would do itself, given the full held-out preference description -- i.e. how long it would take the human to do the task themself, knowing their own preferences. The AI agent would be measured 

and subsequently write a prompt for the AI agent containing a condensed version of the desires, intentionally leaving ambiguity for the AI agent to sort out. The human- or machine-provided trace as the "ground-truth" optimal way to execute on that desire (as a proxy for how long it would take a human or LLM to complete the task given full knowledge of preferences ahead-of-time). 


* Better Metrics: ??

Extending $\Tau^2$'s binary success metric to a continuous utility metric balancing correctness, efficiency and communication cost.

"Better Metrics

To capture this richer notion of collaboration, I propose replacing τ²’s binary success criterion with a continuous utility function that balances task correctness, efficiency, and communication cost. Each episode yields a composite reward:

𝑅 = 𝛼𝑆−𝛽1𝐻−𝛽2𝑇−𝛽3𝐶

where 𝑆 represents successful completion or partial credit for progress toward the goal, 𝐻 is the number of human interventions or clarification requests, 𝑇 measures total reasoning or execution time, and 𝐶 quantifies human communication effort (e.g., tokens typed or time spent responding). This metric rewards agents that are both effective and considerate collaborators—achieving high task success while minimizing human cognitive load. Unlike fixed accuracy metrics, this formulation evaluates how well the AI manages uncertainty and partnership dynamics, aligning performance assessment with real-world human preferences for systems that are helpful, efficient, and low-friction to work with."

* Implementation Considerations:

A study with real humans could have humans present realistic requests to an AI agent, provide a time-estimate of how long the task would take them if on their own, and then respond in a timed environment any time the AI agent requests their input.


"Implementing the proposed τ²-A benchmark requires capturing realistic human input while maintaining reproducibility. Two complementary approaches can achieve this. First, in simulated-user mode, an auxiliary LLM acts as the human partner, holding a hidden “ground-truth” preference description while revealing only partial information through responses to clarification queries. This enables large-scale, deterministic evaluation of ambiguity resolution. Second, in human-study mode, real users provide authentic requests and clarifications in a timed environment, allowing direct measurement of communication cost and subjective satisfaction. Both modes can share the same infrastructure as τ²—tools, task APIs, and interaction logging—augmented with new tool-calls for requesting clarification and recording response metadata. By keeping the environment modular and extending τ²’s existing protocols, τ²-A remains technically compatible while introducing the crucial dimension of adaptive collaboration, making it feasible for both automated and human-centered evaluation at scale."


## Benchmark Implementation

* Benchmark Development:
  - 10 test cases
  - code snippet
    - setup instructions (save to end?)

## Benchmark Results

* Results (evaluated against Grok), quantitative, qualitative
* Failure Analysis
  - Model improvements:  fine-tuning strategies, architectural changes, data augmentation


## (Bonus): Suggested Training Data

 * Generation
 * Labeling
 * Augmentation


## Code Instructions

## Conclusion


In the long-term, there may be a pathway to optimally extracting human preferences and drives via neurotechnology or other wearables (e.g. Neuralink, EEG, or Silent Speech Recognition (SSR) technologies). As LLMs gain online-learning / continual-learning capabilities, there may be models which can more optimally pursue the objectives stated here. In the meantime we provide an offline method which aims to approximate these scenarios, via an evaluation metric which balances the three factors of correctness, speed, and the amount of human input required. Benchmarks that incorporate human-in-the-loop ambiguity resolution represent a birdge between today's offline training and evaluation methods and tomorrow's contunual, online learning which will leverage neuroadaptive interfaces.