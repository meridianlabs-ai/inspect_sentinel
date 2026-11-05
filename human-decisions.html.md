# Human Decisions – Inspect Sentinel

## Overview

The `human()` protocol asks a person to decide about a step. The person sees the step and chooses to approve it, reject it, or end the sample, and their answer becomes the protocol’s decision.

Usually you don’t want a person asked about every step. A rule or a monitor settles the clear cases and escalates the steps it is unsure about. With `human()` after it in a `sequential()`, the person is asked only about the escalated steps. When there is nobody to ask, `handle_escalation()` answers escalations with a fixed policy instead.

## Asking a Person

`human()` takes the stages to ask at. The stages are given as strings, which correspond to the [stages](./stages.html.md) a protocol can run at:

| String | Stage | The person decides about |
|----|----|----|
| `"tool_call"` | `BeforeToolCall` | A tool call, before it runs. |
| `"tool_result"` | `AfterToolCall` | A tool call’s result, before the agent’s model receives it. |
| `"model_output"` | `AfterGenerate` | A whole assistant turn, before the agent acts on it (see [Whole Turns](#whole-turns)). |

`stages` is required, and you can give several. On its own, `human(stages=["tool_call"])` asks about every tool call, like Inspect’s human approver.

To ask only about some tool calls, put `human()` at the end of a `sequential()` after a rule that escalates. Here is `examples/escalate_to_human.py`:

    examples/escalate_to_human.py

``` python
from example_samples import ADD_HOST, CLEANUP, COUNT_ROWS
from inspect_ai import Task, task
from inspect_ai.agent import react
from inspect_ai.tool import bash, python

from inspect_sentinel import (
    BeforeToolCall,
    Context,
    Decision,
    Escalations,
    Protocol,
    call_text,
    find_words,
    human,
    protocol,
    sequential,
    tool_matches,
)

DELETE_WORDS = ["rm", "rmdir", "-delete", "shutil.rmtree", "os.remove"]


@protocol
def triage() -> Protocol:
    async def decide(
        context: Context,
        step: BeforeToolCall,
        escalations: Escalations,
    ) -> Decision | None:
        if not tool_matches(step.call, "bash", "python"):
            return Decision.proceed()
        text = call_text(step.call)
        if "/etc" in text:
1            return Decision.reject(
                "call mentions /etc",
                message="`/etc` is off limits; work only under /work.",
            )
        deletes = find_words(text, DELETE_WORDS)
        if deletes:
2            return Decision.escalate(f"call deletes files ({', '.join(deletes)})")
3        return Decision.proceed()

    return decide


@task
def escalate_to_human() -> Task:
    return Task(
        dataset=[CLEANUP, ADD_HOST, COUNT_ROWS],
        solver=react(tools=[bash(timeout=60), python(timeout=60)]),
        sandbox=("docker", "compose.yaml"),
        message_limit=20,
4        sentinel=sequential([triage(), human(stages=["tool_call"])]),
    )
```

1  
A tool call that mentions `/etc` is rejected without asking anyone.

2  
A tool call that deletes files is escalated, with an explanation the person will see.

3  
Every other tool call proceeds. Returning `None` here instead would pass the tool call on to `human()`, and the person would be asked about it too.

4  
`human()` runs only when `triage()` escalates.

Run it from the repository root:

``` bash
inspect eval examples/escalate_to_human.py --model openai/gpt-5-mini
```

When the agent tries to delete files, the eval pauses and asks you to approve, reject or terminate. The prompt shows the tool call and that `triage` escalated it because the tool call deletes files. The eval waits for each answer, so run it where someone can answer.

## Choices

`choices` sets what the person may pick. The defaults depend on the stage:

| Stage            | Default choices                  |
|------------------|----------------------------------|
| `"tool_call"`    | `approve`, `reject`, `terminate` |
| `"tool_result"`  | `approve`, `terminate`           |
| `"model_output"` | `approve`, `terminate`           |

`reject` is offered only before a tool call (see [Actions](./protocols.html.md#actions)), and rejecting a whole turn is not supported. Offering a choice a stage doesn’t allow raises an error when `human()` is created. `"modify"` is accepted before a tool call, but Inspect’s approval surfaces cannot edit a tool call, so offering it raises an error when the person is asked.

The answer maps to a decision: `approve` to `proceed`, `reject` to `reject`, and `terminate` to `terminate`. The reason recorded with the answer becomes the decision’s explanation, and on a reject it is also the message the agent receives. The person doesn’t enter a reason: the approval panel and console record a fixed text, such as “Human operator rejected the tool call.”, and an ACP client (an editor or tool that speaks the [Agent Client Protocol](https://inspect.aisi.org.uk/intervention.html)) records none, so the agent is told “Tool call not approved.”

## Whole Turns

At `"model_output"`, the person decides about a whole assistant turn: its text and every tool call it makes, before any of the tool calls run. Use it when the combined effect of several tool calls matters. Approve lets the turn proceed unchanged, and terminate ends the sample.

`examples/escalate_turn_to_human.py` escalates any turn whose tool calls delete files:

``` python
Task(..., sentinel=sequential([turn_triage(), human(stages=["model_output"])]))
```

Its `turn_triage()` rule runs at `AfterGenerate`. It reads the tool calls from `step.output.message.tool_calls` and escalates the turn, saying how many of them delete files. Run it with:

``` bash
inspect eval examples/escalate_turn_to_human.py --model openai/gpt-5-mini
```

## What the Person Sees

The person is asked through Inspect’s human approval surfaces: an attached ACP client, the approval panel in the full-screen display, or the console otherwise (for example, with `--display plain`). The prompt shows the tool call, the escalations that led to it, and, after a tool call, its result. At `"model_output"` it shows the turn’s text, the escalations, and each tool call as a numbered code block.

Characters that change how text displays, such as terminal escape sequences and zero-width characters, appear in the prompt as a marker of their code point, such as `‹U+001B›`.

## A Person Beside Other Protocols

The person’s answer is an ordinary decision. At the end of a `sequential()`, it decides for the chain, as any child’s decision does.

In a `concurrent()`, which is what a list or mapping passed to `Task(sentinel=...)` becomes, the person’s answer is one decision among the others. Another protocol’s `reject` outranks the person’s `approve`, and the person’s `reject` or `terminate` outranks a weaker decision. A `human()` in a `concurrent()` is asked about every step at its stages, so use a `sequential()` to ask only about escalated steps.

## Earlier Decisions

Later steps of the same agent can see what a person decided. `step.human_decisions` lists each earlier answer as a `HumanDecision`, with the stage it was made at, the tool calls it covered and the decision. `human_decision_for(step, call_id)` finds the latest one covering a given tool call.

An LLM monitor can use these records to mark tool calls a person already reviewed, so the monitor model does not flag them again. See [LLM Monitors](./llm-monitors.html.md#marking-tool-calls-a-person-reviewed) for an example and for what these records do and do not mean.

## Handling Escalations

An escalation that reaches the top of the sentinel has no protocol left to decide it. The sentinel treats this as a configuration error and ends the sample with a `terminate` in place of the escalation. The explanation names where each escalation came from and why, for example `unhandled escalation from triage: call deletes files (rm)`, followed by how to handle it.

In the log, the decision recorded at the top of the sentinel stays the `escalate`, which tells an unhandled escalation apart from a protocol’s own `terminate`. The sample is not recorded as an error.

A rule that escalates on its own reaches the top this way. So does a `sequential()` with nothing at the end to answer its escalations, since a chain in which every decision escalated returns the last escalation.

To say what an escalation should mean, end the chain with `human()` or with `handle_escalation()`, which applies a fixed policy:

``` python
from inspect_ai import Task

from inspect_sentinel import handle_escalation, sequential

Task(..., sentinel=sequential([triage(), handle_escalation("terminate")]))
```

`handle_escalation()` takes one required argument:

| Action | Effect |
|----|----|
| `"terminate"` | End the sample when the step was escalated. |
| `"proceed"` | Let an escalated step proceed. The configuration and the log then record that unsure steps are allowed through. |

There is no `"reject"`, since `reject` is allowed only before a tool call. `handle_escalation()` decides only when it receives escalations and abstains otherwise. Its explanation names each escalation it handled, such as `escalated by triage: call deletes files (rm)`.

After a `human()`, `handle_escalation()` covers the stages the person is not asked at. In this sentinel, `rule()` stands for a protocol that may escalate before or after a tool call. The person is asked before a tool call, and an escalation after one ends the sample:

``` python
sequential([rule(), human(stages=["tool_call"]), handle_escalation("terminate")])
```
