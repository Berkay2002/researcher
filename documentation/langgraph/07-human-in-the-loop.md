# Enable human intervention

<Warning>
  **Alpha Notice:** These docs cover the [**v1-alpha**](../releases/langchain-v1) release. Content is incomplete and subject to change.

  For the latest stable version, see the current [LangGraph Python](https://langchain-ai.github.io/langgraph/) or [LangGraph JavaScript](https://langchain-ai.github.io/langgraphjs/) docs.
</Warning>

To review, edit, and approve tool calls in an agent or workflow, use interrupts to pause a graph and wait for human input. Interrupts use LangGraph's [persistence](/oss/javascript/langgraph/persistence) layer, which saves the graph state, to indefinitely pause graph execution until you resume.

<img src="https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=bf1a1f68ee902142f3461f31ffb55c0a" alt="image" data-og-width="1209" width="1209" data-og-height="308" height="308" data-path="oss/images/tool-call-review.png" data-optimize="true" data-opv="3" srcset="https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=280&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=a26476ccc524788ed57637e94060555f 280w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=560&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=599b58f4049636889e3db57143fa1634 560w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=840&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=7001cb1234ec0d050fe7a35693cd3bab 840w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=1100&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=cdf2e845e3953494d1512d983922efeb 1100w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=1650&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=e0b34c9eab6963acb050cef5e1b399f4 1650w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=2500&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=49a4d5423575c18f3c3b54496938157d 2500w" />

## Pause using `interrupt`

[Dynamic interrupts](/oss/javascript/langgraph/add-human-in-the-loop#key-capabilities) (also known as dynamic breakpoints) are triggered based on the current state of the graph. You can set dynamic interrupts by calling [`interrupt` function](https://langchain-ai.github.io/langgraphjs/reference/functions/langgraph.interrupt-2.html) in the appropriate place. The graph will pause, which allows for human intervention, and then resumes the graph with their input. It's useful for tasks like approvals, edits, or gathering additional context.

To use `interrupt` in your graph, you need to:

1. [**Specify a checkpointer**](/oss/javascript/langgraph/persistence#checkpoints) to save the graph state after each step.
2. **Call `interrupt()`** in the appropriate place. See the [Common Patterns](#common-patterns) section for examples.
3. **Run the graph** with a [**thread ID**](/oss/javascript/langgraph/persistence#threads) until the `interrupt` is hit.
4. **Resume execution** using `invoke`/`stream` (see [**The `Command` primitive**](#resume-using-the-command-primitive)).

```typescript {highlight={1,5,31}} theme={null}
import { interrupt, Command } from "@langchain/langgraph";

const graph = graphBuilder
  .addNode("humanNode", (state) => {
    const value = interrupt(
      // (1)!
      {
        textToRevise: state.someText, // (2)!
      }
    );
    return {
      someText: value, // (3)!
    };
  })
  .addEdge(START, "humanNode")
  .compile({ checkpointer }); // (4)!

// Run the graph until the interrupt is hit.
const config = { configurable: { thread_id: "some_id" } };
const result = await graph.invoke({ someText: "original text" }, config); // (5)!
console.log(result.__interrupt__); // (6)!
// > [
// >   {
// >     value: { textToRevise: 'original text' },
// >     resumable: true,
// >     ns: ['humanNode:6ce9e64f-edef-fe5d-f7dc-511fa9526960'],
// >     when: 'during'
// >   }
// > ]

console.log(await graph.invoke(new Command({ resume: "Edited text" }), config)); // (7)!
// > { someText: 'Edited text' }
```

1. `interrupt(...)` pauses execution at `humanNode`, surfacing the given payload to a human.
2. Any JSON serializable value can be passed to the `interrupt` function. Here, an object containing the text to revise.
3. Once resumed, the return value of `interrupt(...)` is the human-provided input, which is used to update the state.
4. A checkpointer is required to persist graph state. In production, this should be durable (e.g., backed by a database).
5. The graph is invoked with some initial state.
6. When the graph hits the interrupt, it returns an object with `__interrupt__` containing the payload and metadata.
7. The graph is resumed with a `Command({ resume: ... })`, injecting the human's input and continuing execution.

<Accordion title="Extended example: using `interrupt`">
  ```typescript {highlight={12,43}} theme={null}
  import * as z from "zod";
  import { v4 as uuidv4 } from "uuid";
  import { MemorySaver, StateGraph, START, interrupt, Command } from "@langchain/langgraph";

  const StateAnnotation = z.object({
    someText: z.string(),
  });

  // Build the graph
  const graphBuilder = new StateGraph(StateAnnotation)
    .addNode("humanNode", (state) => {
      const value = interrupt( // (1)!
        {
          textToRevise: state.someText // (2)!
        }
      );
      return {
        someText: value // (3)!
      };
    })
    .addEdge(START, "humanNode");

  const checkpointer = new MemorySaver(); // (4)!

  const graph = graphBuilder.compile({ checkpointer });

  // Pass a thread ID to the graph to run it.
  const config = { configurable: { thread_id: uuidv4() } };

  // Run the graph until the interrupt is hit.
  const result = await graph.invoke({ someText: "original text" }, config); // (5)!

  console.log(result.__interrupt__); // (6)!
  // > [
  // >   {
  // >     value: { textToRevise: 'original text' },
  // >     resumable: true,
  // >     ns: ['humanNode:6ce9e64f-edef-fe5d-f7dc-511fa9526960'],
  // >     when: 'during'
  // >   }
  // > ]

  console.log(await graph.invoke(new Command({ resume: "Edited text" }), config)); // (7)!
  // > { someText: 'Edited text' }
  ```

  1. `interrupt(...)` pauses execution at `humanNode`, surfacing the given payload to a human.
  2. Any JSON serializable value can be passed to the `interrupt` function. Here, an object containing the text to revise.
  3. Once resumed, the return value of `interrupt(...)` is the human-provided input, which is used to update the state.
  4. A checkpointer is required to persist graph state. In production, this should be durable (e.g., backed by a database).
  5. The graph is invoked with some initial state.
  6. When the graph hits the interrupt, it returns an object with `__interrupt__` containing the payload and metadata.
  7. The graph is resumed with a `Command({ resume: ... })`, injecting the human's input and continuing execution.
</Accordion>

<Warning>
  Interrupts are both powerful and ergonomic, but it's important to note that they do not automatically resume execution from the interrupt point. Instead, they rerun the entire where the interrupt was used. For this reason, interrupts are typically best placed at the state of a node or in a dedicated node.
</Warning>

## Resume using the `Command` primitive

When the `interrupt` function is used within a graph, execution pauses at that point and awaits user input.

To resume execution, use the [`Command`](https://langchain-ai.github.io/langgraphjs/reference/classes/langgraph.Command.html) primitive, which can be supplied via the `invoke` or `stream` methods. The graph resumes execution from the beginning of the node where `interrupt(...)` was initially called. This time, the `interrupt` function will return the value provided in `Command(resume=value)` rather than pausing again. All code from the beginning of the node to the `interrupt` will be re-executed.

```typescript  theme={null}
// Resume graph execution by providing the user's input.
await graph.invoke(new Command({ resume: { age: "25" } }), threadConfig);
```

### Resume multiple interrupts with one invocation

When nodes with interrupt conditions are run in parallel, it's possible to have multiple interrupts in the task queue.
For example, the following graph has two nodes run in parallel that require human input:

<img src="https://mintcdn.com/langchain-5e9cc07a/dL5Sn6Cmy9pwtY0V/oss/images/human_in_loop_parallel.png?fit=max&auto=format&n=dL5Sn6Cmy9pwtY0V&q=85&s=ea353267302bd9da96a00e4faf6d2baf" alt="two nodes run in parallel that require human input" data-og-width="348" width="348" data-og-height="234" height="234" data-path="oss/images/human_in_loop_parallel.png" data-optimize="true" data-opv="3" srcset="https://mintcdn.com/langchain-5e9cc07a/dL5Sn6Cmy9pwtY0V/oss/images/human_in_loop_parallel.png?w=280&fit=max&auto=format&n=dL5Sn6Cmy9pwtY0V&q=85&s=56788e755a78ee5ef9ff20a3353e9475 280w, https://mintcdn.com/langchain-5e9cc07a/dL5Sn6Cmy9pwtY0V/oss/images/human_in_loop_parallel.png?w=560&fit=max&auto=format&n=dL5Sn6Cmy9pwtY0V&q=85&s=bd1039a449c0b42c1c911d6085cbf655 560w, https://mintcdn.com/langchain-5e9cc07a/dL5Sn6Cmy9pwtY0V/oss/images/human_in_loop_parallel.png?w=840&fit=max&auto=format&n=dL5Sn6Cmy9pwtY0V&q=85&s=49105fac0cb75bf514c8719017c6f7dc 840w, https://mintcdn.com/langchain-5e9cc07a/dL5Sn6Cmy9pwtY0V/oss/images/human_in_loop_parallel.png?w=1100&fit=max&auto=format&n=dL5Sn6Cmy9pwtY0V&q=85&s=834e075e0256e54216315865ccf986e5 1100w, https://mintcdn.com/langchain-5e9cc07a/dL5Sn6Cmy9pwtY0V/oss/images/human_in_loop_parallel.png?w=1650&fit=max&auto=format&n=dL5Sn6Cmy9pwtY0V&q=85&s=8ae7509e482997c709816f65d7155b6b 1650w, https://mintcdn.com/langchain-5e9cc07a/dL5Sn6Cmy9pwtY0V/oss/images/human_in_loop_parallel.png?w=2500&fit=max&auto=format&n=dL5Sn6Cmy9pwtY0V&q=85&s=6c10de7b5e317f77b5ff239d22ef4ba0 2500w" />

```typescript  theme={null}
const state = await parentGraph.getState(threadConfig);
const resumeMap = Object.fromEntries(
  state.interrupts.map((i) => [
    i.interruptId,
    `human input for prompt ${i.value}`,
  ])
);

await parentGraph.invoke(new Command({ resume: resumeMap }), threadConfig);
```

## Common patterns

There are four typical design patterns that you can implement using `interrupt` and `Command`:

* [Approve or reject](#approve-or-reject): Pause the graph before a critical step, such as an API call, to review and approve the action. If the action is rejected, you can prevent the graph from executing the step, and potentially take an alternative action. This pattern often involves routing the graph based on the human's input.
* [Edit graph state](#review-and-edit-state): Pause the graph to review and edit the graph state. This is useful for correcting mistakes or updating the state with additional information. This pattern often involves updating the state with the human's input.
* [Review tool calls](#review-tool-calls): Pause the graph to review and edit tool calls requested by the LLM before tool execution.
* [Validate human input](#validate-human-input): Pause the graph to validate human input before proceeding with the next step.

Below we show different design patterns that can be implemented using `interrupt` and `Command`.

### Approve or reject

<img src="https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/approve-or-reject.png?fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=40a22111645454c255e5448a35560e7d" alt="Depending on the human's approval or rejection, the graph can proceed with the action or take an alternative path" data-og-width="1084" width="1084" data-og-height="604" height="604" data-path="oss/images/approve-or-reject.png" data-optimize="true" data-opv="3" srcset="https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/approve-or-reject.png?w=280&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=551ab8f2d06835138f37c8ea2a0c56e7 280w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/approve-or-reject.png?w=560&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=769ebd8c9ddd0c865e1075780f65583f 560w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/approve-or-reject.png?w=840&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=04a5450a905f883e56fb208080e1fd7b 840w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/approve-or-reject.png?w=1100&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=4eee5629317888f13d10a2f57d6f6135 1100w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/approve-or-reject.png?w=1650&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=aab81b40efd938e7534dd46a85e1f480 1650w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/approve-or-reject.png?w=2500&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=ed2fbce4cbdcaff997c868c7cc773518 2500w" />

Pause the graph before a critical step, such as an API call, to review and approve the action. If the action is rejected, you can prevent the graph from executing the step, and potentially take an alternative action.

```typescript  theme={null}
import { interrupt, Command } from "@langchain/langgraph";

// Add the node to the graph in an appropriate location
// and connect it to the relevant nodes.
graphBuilder.addNode("humanApproval", (state) => {
  const isApproved = interrupt({
    question: "Is this correct?",
    // Surface the output that should be
    // reviewed and approved by the human.
    llmOutput: state.llmOutput,
  });

  if (isApproved) {
    return new Command({ goto: "someNode" });
  } else {
    return new Command({ goto: "anotherNode" });
  }
});
const graph = graphBuilder.compile({ checkpointer });

// After running the graph and hitting the interrupt, the graph will pause.
// Resume it with either an approval or rejection.
const threadConfig = { configurable: { thread_id: "some_id" } };
await graph.invoke(new Command({ resume: true }), threadConfig);
```

<Accordion title="Extended example: approve or reject with interrupt">
  ```typescript  theme={null}
  import * as z from "zod";
  import { v4 as uuidv4 } from "uuid";
  import {
    StateGraph,
    START,
    END,
    interrupt,
    Command,
    MemorySaver
  } from "@langchain/langgraph";

  // Define the shared graph state
  const StateAnnotation = z.object({
    llmOutput: z.string(),
    decision: z.string(),
  });

  // Simulate an LLM output node
  function generateLlmOutput(state: z.infer<typeof StateAnnotation>) {
    return { llmOutput: "This is the generated output." };
  }

  // Human approval node
  function humanApproval(state: z.infer<typeof StateAnnotation>): Command {
    const decision = interrupt({
      question: "Do you approve the following output?",
      llmOutput: state.llmOutput
    });

    if (decision === "approve") {
      return new Command({
        goto: "approvedPath",
        update: { decision: "approved" }
      });
    } else {
      return new Command({
        goto: "rejectedPath",
        update: { decision: "rejected" }
      });
    }
  }

  // Next steps after approval
  function approvedNode(state: z.infer<typeof StateAnnotation>) {
    console.log("✅ Approved path taken.");
    return state;
  }

  // Alternative path after rejection
  function rejectedNode(state: z.infer<typeof StateAnnotation>) {
    console.log("❌ Rejected path taken.");
    return state;
  }

  // Build the graph
  const builder = new StateGraph(StateAnnotation)
    .addNode("generateLlmOutput", generateLlmOutput)
    .addNode("humanApproval", humanApproval, {
      ends: ["approvedPath", "rejectedPath"]
    })
    .addNode("approvedPath", approvedNode)
    .addNode("rejectedPath", rejectedNode)
    .addEdge(START, "generateLlmOutput")
    .addEdge("generateLlmOutput", "humanApproval")
    .addEdge("approvedPath", END)
    .addEdge("rejectedPath", END);

  const checkpointer = new MemorySaver();
  const graph = builder.compile({ checkpointer });

  // Run until interrupt
  const config = { configurable: { thread_id: uuidv4() } };
  const result = await graph.invoke({}, config);
  console.log(result.__interrupt__);
  // Output:
  // [{
  //   value: {
  //     question: 'Do you approve the following output?',
  //     llmOutput: 'This is the generated output.'
  //   },
  //   ...
  // }]

  // Simulate resuming with human input
  // To test rejection, replace resume: "approve" with resume: "reject"
  const finalResult = await graph.invoke(
    new Command({ resume: "approve" }),
    config
  );
  console.log(finalResult);
  ```
</Accordion>

### Review and edit state

<img src="https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/edit-graph-state-simple.png?fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=ddb4a6e85209cc46f4955b1cb104373b" alt="A human can review and edit the state of the graph. This is useful for correcting mistakes or updating the state with additional information" data-og-width="1019" width="1019" data-og-height="230" height="230" data-path="oss/images/edit-graph-state-simple.png" data-optimize="true" data-opv="3" srcset="https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/edit-graph-state-simple.png?w=280&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=b15c474aa8a7c5376003d7979c56fc2a 280w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/edit-graph-state-simple.png?w=560&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=3d061174c2f8faea823666778a15a3d9 560w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/edit-graph-state-simple.png?w=840&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=467872fb1f1b6ad346deae001daf3948 840w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/edit-graph-state-simple.png?w=1100&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=6fd0d9559499b8bd83795ce871554e28 1100w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/edit-graph-state-simple.png?w=1650&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=1fb380f3ad68b6a08f773ba1900c06ba 1650w, https://mintcdn.com/langchain-5e9cc07a/-_xGPoyjhyiDWTPJ/oss/images/edit-graph-state-simple.png?w=2500&fit=max&auto=format&n=-_xGPoyjhyiDWTPJ&q=85&s=d30db9932405fcbf5306fc2b4cdee458 2500w" />

```typescript  theme={null}
import { interrupt } from "@langchain/langgraph";

function humanEditing(state: z.infer<typeof StateAnnotation>) {
  const result = interrupt({
    // Interrupt information to surface to the client.
    // Can be any JSON serializable value.
    task: "Review the output from the LLM and make any necessary edits.",
    llmGeneratedSummary: state.llmGeneratedSummary,
  });

  // Update the state with the edited text
  return {
    llmGeneratedSummary: result.editedText,
  };
}

// Add the node to the graph in an appropriate location
// and connect it to the relevant nodes.
graphBuilder.addNode("humanEditing", humanEditing);
const graph = graphBuilder.compile({ checkpointer });

// After running the graph and hitting the interrupt, the graph will pause.
// Resume it with the edited text.
const threadConfig = { configurable: { thread_id: "some_id" } };
await graph.invoke(
  new Command({ resume: { editedText: "The edited text" } }),
  threadConfig
);
```

<Accordion title="Extended example: edit state with interrupt">
  ```typescript  theme={null}
  import * as z from "zod";
  import { v4 as uuidv4 } from "uuid";
  import {
    StateGraph,
    START,
    END,
    interrupt,
    Command,
    MemorySaver
  } from "@langchain/langgraph";

  // Define the graph state
  const StateAnnotation = z.object({
    summary: z.string(),
  });

  // Simulate an LLM summary generation
  function generateSummary(state: z.infer<typeof StateAnnotation>) {
    return {
      summary: "The cat sat on the mat and looked at the stars."
    };
  }

  // Human editing node
  function humanReviewEdit(state: z.infer<typeof StateAnnotation>) {
    const result = interrupt({
      task: "Please review and edit the generated summary if necessary.",
      generatedSummary: state.summary
    });
    return {
      summary: result.editedSummary
    };
  }

  // Simulate downstream use of the edited summary
  function downstreamUse(state: z.infer<typeof StateAnnotation>) {
    console.log(`✅ Using edited summary: ${state.summary}`);
    return state;
  }

  // Build the graph
  const builder = new StateGraph(StateAnnotation)
    .addNode("generateSummary", generateSummary)
    .addNode("humanReviewEdit", humanReviewEdit)
    .addNode("downstreamUse", downstreamUse)
    .addEdge(START, "generateSummary")
    .addEdge("generateSummary", "humanReviewEdit")
    .addEdge("humanReviewEdit", "downstreamUse")
    .addEdge("downstreamUse", END);

  // Set up in-memory checkpointing for interrupt support
  const checkpointer = new MemorySaver();
  const graph = builder.compile({ checkpointer });

  // Invoke the graph until it hits the interrupt
  const config = { configurable: { thread_id: uuidv4() } };
  const result = await graph.invoke({}, config);

  // Output interrupt payload
  console.log(result.__interrupt__);
  // Example output:
  // [{
  //   value: {
  //     task: 'Please review and edit the generated summary if necessary.',
  //     generatedSummary: 'The cat sat on the mat and looked at the stars.'
  //   },
  //   resumable: true,
  //   ...
  // }]

  // Resume the graph with human-edited input
  const editedSummary = "The cat lay on the rug, gazing peacefully at the night sky.";
  const resumedResult = await graph.invoke(
    new Command({ resume: { editedSummary } }),
    config
  );
  console.log(resumedResult);
  ```
</Accordion>

### Review tool calls

<img src="https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=bf1a1f68ee902142f3461f31ffb55c0a" alt="A human can review and edit the output from the LLM before proceeding. This is particularly critical in applications where the tool calls requested by the LLM may be sensitive or require human oversight." data-og-width="1209" width="1209" data-og-height="308" height="308" data-path="oss/images/tool-call-review.png" data-optimize="true" data-opv="3" srcset="https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=280&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=a26476ccc524788ed57637e94060555f 280w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=560&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=599b58f4049636889e3db57143fa1634 560w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=840&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=7001cb1234ec0d050fe7a35693cd3bab 840w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=1100&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=cdf2e845e3953494d1512d983922efeb 1100w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=1650&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=e0b34c9eab6963acb050cef5e1b399f4 1650w, https://mintcdn.com/langchain-5e9cc07a/ybiAaBfoBvFquMDz/oss/images/tool-call-review.png?w=2500&fit=max&auto=format&n=ybiAaBfoBvFquMDz&q=85&s=49a4d5423575c18f3c3b54496938157d 2500w" />

To add a human approval step to a tool:

1. Use `interrupt()` in the tool to pause execution.
2. Resume with a `Command` to continue based on human input.

```typescript {highlight={10,33,38}} theme={null}
import { MemorySaver } from "@langchain/langgraph";
import { interrupt } from "@langchain/langgraph";
import { createAgent } from "@langchain/agents";
import { tool } from "@langchain/core/tools";
import * as z from "zod";

// An example of a sensitive tool that requires human review / approval
const bookHotel = tool(
  async ({ hotelName }) => {
    const response = interrupt(
      // (1)!
      `Trying to call \`bookHotel\` with args {"hotelName": "${hotelName}"}. ` +
        "Please approve or suggest edits."
    );
    if (response.type === "accept") {
      // Continue with original args
    } else if (response.type === "edit") {
      hotelName = response.args.hotelName;
    } else {
      throw new Error(`Unknown response type: ${response.type}`);
    }
    return `Successfully booked a stay at ${hotelName}.`;
  },
  {
    name: "bookHotel",
    description: "Book a hotel",
    schema: z.object({
      hotelName: z.string(),
    }),
  }
);

const checkpointer = new MemorySaver(); // (2)!

const agent = createAgent({
  llm: model,
  tools: [bookHotel],
  checkpointSaver: checkpointer, // (3)!
});
```

1. The [`interrupt` function](https://langchain-ai.github.io/langgraphjs/reference/functions/langgraph.interrupt-2.html) pauses the agent graph at a specific node. In this case, we call `interrupt()` at the beginning of the tool function, which pauses the graph at the node that executes the tool. The information inside `interrupt()` (e.g., tool calls) can be presented to a human, and the graph can be resumed with the user input (tool call approval, edit or feedback).
2. The `MemorySaver` is used to store the agent state at every step in the tool calling loop. This enables [short-term memory](/oss/javascript/langgraph/add-memory#add-short-term-memory) and [human-in-the-loop](/oss/javascript/langgraph/add-human-in-the-loop) capabilities. In this example, we use `MemorySaver` to store the agent state in memory. In a production application, the agent state will be stored in a database.
3. Initialize the agent with the `checkpointSaver`.

Run the agent with the `stream()` method, passing the `config` object to specify the thread ID. This allows the agent to resume the same conversation on future invocations.

```typescript {highlight={3,9}} theme={null}
const config = {
  configurable: {
    thread_id: "1",
  },
};

const stream = await agent.stream(
  { messages: [{ role: "user", content: "book a stay at McKittrick hotel" }] },
  config
);

for await (const chunk of stream) {
  console.log(chunk);
  console.log("\n");
}
```

> You should see that the agent runs until it reaches the `interrupt()` call, at which point it pauses and waits for human input.

Resume the agent with a `Command` to continue based on human input.

```typescript {highlight={4}} theme={null}
import { Command } from "@langchain/langgraph";

const resumeStream = await agent.stream(
  new Command({ resume: { type: "accept" } }), // (1)!
  // new Command({ resume: { type: "edit", args: { hotelName: "McKittrick Hotel" } } }),
  config
);

for await (const chunk of resumeStream) {
  console.log(chunk);
  console.log("\n");
}
```

1. The [`interrupt` function](https://langchain-ai.github.io/langgraphjs/reference/functions/langgraph.interrupt-2.html) is used in conjunction with the [`Command`](https://langchain-ai.github.io/langgraphjs/reference/classes/langgraph.Command.html) object to resume the graph with a value provided by the human.

### Add interrupts to any tool

You can create a wrapper to add interrupts to *any* tool. The example below provides a reference implementation compatible with [Agent Inbox UI](https://github.com/langchain-ai/agent-inbox) and [Agent Chat UI](https://github.com/langchain-ai/agent-chat-ui).

```typescript title="Wrapper that adds human-in-the-loop to any tool" {highlight={41}} theme={null}
import { StructuredTool, tool } from "@langchain/core/tools";
import { RunnableConfig } from "@langchain/core/runnables";
import { interrupt } from "@langchain/langgraph";

interface HumanInterruptConfig {
  allowAccept?: boolean;
  allowEdit?: boolean;
  allowRespond?: boolean;
}

interface HumanInterrupt {
  actionRequest: {
    action: string;
    args: Record<string, any>;
  };
  config: HumanInterruptConfig;
  description: string;
}

function addHumanInTheLoop(
  originalTool: StructuredTool,
  interruptConfig: HumanInterruptConfig = {
    allowAccept: true,
    allowEdit: true,
    allowRespond: true,
  }
): StructuredTool {
  // Wrap the original tool to support human-in-the-loop review
  return tool(
    // (1)!
    async (toolInput: Record<string, any>, config?: RunnableConfig) => {
      const request: HumanInterrupt = {
        actionRequest: {
          action: originalTool.name,
          args: toolInput,
        },
        config: interruptConfig,
        description: "Please review the tool call",
      };

      const response = interrupt([request])[0]; // (2)!

      // approve the tool call
      if (response.type === "accept") {
        return await originalTool.invoke(toolInput, config);
      }
      // update tool call args
      else if (response.type === "edit") {
        const updatedArgs = response.args.args;
        return await originalTool.invoke(updatedArgs, config);
      }
      // respond to the LLM with user feedback
      else if (response.type === "response") {
        return response.args;
      } else {
        throw new Error(
          `Unsupported interrupt response type: ${response.type}`
        );
      }
    },
    {
      name: originalTool.name,
      description: originalTool.description,
      schema: originalTool.schema,
    }
  );
}
```

1. This wrapper creates a new tool that calls `interrupt()` **before** executing the wrapped tool.
2. `interrupt()` is using special input and output format that's expected by [Agent Inbox UI](https://github.com/langchain-ai/agent-inbox): - a list of \[`HumanInterrupt`] objects is sent to `AgentInbox` render interrupt information to the end user - resume value is provided by `AgentInbox` as a list (i.e., `Command({ resume: [...] })`)

You can use the wrapper to add `interrupt()` to any tool without having to add it *inside* the tool:

```typescript {highlight={6,24,26,34}} theme={null}
import { MemorySaver } from "@langchain/langgraph";
import { createAgent } from "@langchain/agents";
import { tool } from "@langchain/core/tools";
import * as z from "zod";

const checkpointer = new MemorySaver();

const bookHotel = tool(
  async ({ hotelName }) => {
    return `Successfully booked a stay at ${hotelName}.`;
  },
  {
    name: "bookHotel",
    description: "Book a hotel",
    schema: z.object({
      hotelName: z.string(),
    }),
  }
);

const agent = createAgent({
  llm: model,
  tools: [
    addHumanInTheLoop(bookHotel), // (1)!
  ],
  checkpointSaver: checkpointer,
});

const config = { configurable: { thread_id: "1" } };

// Run the agent
const stream = await agent.stream(
  { messages: [{ role: "user", content: "book a stay at McKittrick hotel" }] },
  config
);

for await (const chunk of stream) {
  console.log(chunk);
  console.log("\n");
}
```

1. The `addHumanInTheLoop` wrapper is used to add `interrupt()` to the tool. This allows the agent to pause execution and wait for human input before proceeding with the tool call.

> You should see that the agent runs until it reaches the `interrupt()` call,
> at which point it pauses and waits for human input.

Resume the agent with a `Command` to continue based on human input.

```typescript {highlight={4}} theme={null}
import { Command } from "@langchain/langgraph";

const resumeStream = await agent.stream(
  new Command({ resume: [{ type: "accept" }] }),
  // new Command({ resume: [{ type: "edit", args: { args: { hotelName: "McKittrick Hotel" } } }] }),
  config
);

for await (const chunk of resumeStream) {
  console.log(chunk);
  console.log("\n");
}
```

### Validate human input

If you need to validate the input provided by the human within the graph itself (rather than on the client side), you can achieve this by using multiple interrupt calls within a single node.

```typescript  theme={null}
import { interrupt } from "@langchain/langgraph";

graphBuilder.addNode("humanNode", (state) => {
  // Human node with validation.
  let question = "What is your age?";

  while (true) {
    const answer = interrupt(question);

    // Validate answer, if the answer isn't valid ask for input again.
    if (typeof answer !== "number" || answer < 0) {
      question = `'${answer}' is not a valid age. What is your age?`;
      continue;
    } else {
      // If the answer is valid, we can proceed.
      break;
    }
  }

  console.log(`The human in the loop is ${answer} years old.`);
  return {
    age: answer,
  };
});
```

<Accordion title="Extended example: validating user input">
  ```typescript  theme={null}
  import * as z from "zod";
  import { v4 as uuidv4 } from "uuid";
  import {
    StateGraph,
    START,
    END,
    interrupt,
    Command,
    MemorySaver
  } from "@langchain/langgraph";

  // Define graph state
  const StateAnnotation = z.object({
    age: z.number(),
  });

  // Node that asks for human input and validates it
  function getValidAge(state: z.infer<typeof StateAnnotation>) {
    let prompt = "Please enter your age (must be a non-negative integer).";

    while (true) {
      const userInput = interrupt(prompt);

      // Validate the input
      try {
        const age = parseInt(userInput as string);
        if (isNaN(age) || age < 0) {
          throw new Error("Age must be non-negative.");
        }
        return { age };
      } catch (error) {
        prompt = `'${userInput}' is not valid. Please enter a non-negative integer for age.`;
      }
    }
  }

  // Node that uses the valid input
  function reportAge(state: z.infer<typeof StateAnnotation>) {
    console.log(`✅ Human is ${state.age} years old.`);
    return state;
  }

  // Build the graph
  const builder = new StateGraph(StateAnnotation)
    .addNode("getValidAge", getValidAge)
    .addNode("reportAge", reportAge)
    .addEdge(START, "getValidAge")
    .addEdge("getValidAge", "reportAge")
    .addEdge("reportAge", END);

  // Create the graph with a memory checkpointer
  const checkpointer = new MemorySaver();
  const graph = builder.compile({ checkpointer });

  // Run the graph until the first interrupt
  const config = { configurable: { thread_id: uuidv4() } };
  let result = await graph.invoke({}, config);
  console.log(result.__interrupt__);  // First prompt: "Please enter your age..."

  // Simulate an invalid input (e.g., string instead of integer)
  result = await graph.invoke(new Command({ resume: "not a number" }), config);
  console.log(result.__interrupt__);  // Follow-up prompt with validation message

  // Simulate a second invalid input (e.g., negative number)
  result = await graph.invoke(new Command({ resume: "-10" }), config);
  console.log(result.__interrupt__);  // Another retry

  // Provide valid input
  const finalResult = await graph.invoke(new Command({ resume: "25" }), config);
  console.log(finalResult);  // Should include the valid age
  ```
</Accordion>

## Considerations

When using human-in-the-loop, there are some considerations to keep in mind.

### Using with code with side-effects

Place code with side effects, such as API calls, after the `interrupt` or in a separate node to avoid duplication, as these are re-triggered every time the node is resumed.

<Tabs>
  <Tab title="Side effects after interrupt">
    ```typescript  theme={null}
    import { interrupt } from "@langchain/langgraph";

    function humanNode(state: z.infer<typeof StateAnnotation>) {
      // Human node with validation.

      const answer = interrupt(question);

      apiCall(answer); // OK as it's after the interrupt
    }
    ```
  </Tab>

  <Tab title="Side effects in a separate node">
    ```typescript  theme={null}
    import { interrupt } from "@langchain/langgraph";

    function humanNode(state: z.infer<typeof StateAnnotation>) {
      // Human node with validation.

      const answer = interrupt(question);

      return {
        answer
      };
    }

    function apiCallNode(state: z.infer<typeof StateAnnotation>) {
      apiCall(state.answer); // OK as it's in a separate node
    }
    ```
  </Tab>
</Tabs>

### Using with subgraphs called as functions

When invoking a subgraph as a function, the parent graph will resume execution from the **beginning of the node** where the subgraph was invoked where the `interrupt` was triggered. Similarly, the **subgraph** will resume from the **beginning of the node** where the `interrupt()` function was called.

```typescript  theme={null}
async function nodeInParentGraph(state: z.infer<typeof StateAnnotation>) {
  someCode(); // <-- This will re-execute when the subgraph is resumed.
  // Invoke a subgraph as a function.
  // The subgraph contains an `interrupt` call.
  const subgraphResult = await subgraph.invoke(someInput);
  // ...
}
```

<Accordion title="Extended example: parent and subgraph execution flow">
  Say we have a parent graph with 3 nodes:

  **Parent Graph**: `node_1` → `node_2` (subgraph call) → `node_3`

  And the subgraph has 3 nodes, where the second node contains an `interrupt`:

  **Subgraph**: `sub_node_1` → `sub_node_2` (`interrupt`) → `sub_node_3`

  When resuming the graph, the execution will proceed as follows:

  1. **Skip `node_1`** in the parent graph (already executed, graph state was saved in snapshot).
  2. **Re-execute `node_2`** in the parent graph from the start.
  3. **Skip `sub_node_1`** in the subgraph (already executed, graph state was saved in snapshot).
  4. **Re-execute `sub_node_2`** in the subgraph from the beginning.
  5. Continue with `sub_node_3` and subsequent nodes.

  Here is abbreviated example code that you can use to understand how subgraphs work with interrupts.
  It counts the number of times each node is entered and prints the count.

  ```typescript  theme={null}
  import { v4 as uuidv4 } from "uuid";
  import {
    StateGraph,
    START,
    interrupt,
    Command,
    MemorySaver
  } from "@langchain/langgraph";
  import * as z from "zod";

  const StateAnnotation = z.object({
    stateCounter: z.number(),
  });

  // Global variable to track the number of attempts
  let counterNodeInSubgraph = 0;

  function nodeInSubgraph(state: z.infer<typeof StateAnnotation>) {
    // A node in the sub-graph.
    counterNodeInSubgraph += 1; // This code will **NOT** run again!
    console.log(`Entered 'nodeInSubgraph' a total of ${counterNodeInSubgraph} times`);
    return {};
  }

  let counterHumanNode = 0;

  function humanNode(state: z.infer<typeof StateAnnotation>) {
    counterHumanNode += 1; // This code will run again!
    console.log(`Entered humanNode in sub-graph a total of ${counterHumanNode} times`);
    const answer = interrupt("what is your name?");
    console.log(`Got an answer of ${answer}`);
    return {};
  }

  const checkpointer = new MemorySaver();

  const subgraphBuilder = new StateGraph(StateAnnotation)
    .addNode("someNode", nodeInSubgraph)
    .addNode("humanNode", humanNode)
    .addEdge(START, "someNode")
    .addEdge("someNode", "humanNode");
  const subgraph = subgraphBuilder.compile({ checkpointer });

  let counterParentNode = 0;

  async function parentNode(state: z.infer<typeof StateAnnotation>) {
    // This parent node will invoke the subgraph.
    counterParentNode += 1; // This code will run again on resuming!
    console.log(`Entered 'parentNode' a total of ${counterParentNode} times`);

    // Please note that we're intentionally incrementing the state counter
    // in the graph state as well to demonstrate that the subgraph update
    // of the same key will not conflict with the parent graph (until
    const subgraphState = await subgraph.invoke(state);
    return subgraphState;
  }

  const builder = new StateGraph(StateAnnotation)
    .addNode("parentNode", parentNode)
    .addEdge(START, "parentNode");

  // A checkpointer must be enabled for interrupts to work!
  const graph = builder.compile({ checkpointer });

  const config = {
    configurable: {
      thread_id: uuidv4(),
    }
  };

  const stream = await graph.stream({ stateCounter: 1 }, config);
  for await (const chunk of stream) {
    console.log(chunk);
  }

  console.log('--- Resuming ---');

  const resumeStream = await graph.stream(new Command({ resume: "35" }), config);
  for await (const chunk of resumeStream) {
    console.log(chunk);
  }
  ```

  This will print out

  ```
  Entered 'parentNode' a total of 1 times
  Entered 'nodeInSubgraph' a total of 1 times
  Entered humanNode in sub-graph a total of 1 times
  { __interrupt__: [{ value: 'what is your name?', resumable: true, ns: ['parentNode:4c3a0248-21f0-1287-eacf-3002bc304db4', 'humanNode:2fe86d52-6f70-2a3f-6b2f-b1eededd6348'], when: 'during' }] }
  --- Resuming ---
  Entered 'parentNode' a total of 2 times
  Entered humanNode in sub-graph a total of 2 times
  Got an answer of 35
  { parentNode: null }
  ```
</Accordion>

### Using multiple interrupts in a single node

Using multiple interrupts within a **single** node can be helpful for patterns like [validating human input](#validate-human-input). However, using multiple interrupts in the same node can lead to unexpected behavior if not handled carefully.

When a node contains multiple interrupt calls, LangGraph keeps a list of resume values specific to the task executing the node. Whenever execution resumes, it starts at the beginning of the node. For each interrupt encountered, LangGraph checks if a matching value exists in the task's resume list. Matching is **strictly index-based**, so the order of interrupt calls within the node is critical.

To avoid issues, refrain from dynamically changing the node's structure between executions. This includes adding, removing, or reordering interrupt calls, as such changes can result in mismatched indices. These problems often arise from unconventional patterns, such as mutating state via `Command(resume=..., update=SOME_STATE_MUTATION)` or relying on global variables to modify the node's structure dynamically.
