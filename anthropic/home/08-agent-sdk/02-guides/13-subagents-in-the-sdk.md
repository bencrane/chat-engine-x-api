# Subagents in the SDK

Define and invoke subagents to isolate context, run tasks in parallel, and apply specialized instructions in your Claude Agent SDK applications.

Subagents are separate agent instances that your main agent can spawn to handle focused subtasks.

Use subagents to isolate context for focused subtasks, run multiple analyses in parallel, and apply specialized instructions without bloating the main agent's prompt.

## Overview

You can create subagents in three ways:

- **Programmatically**: use the agents parameter in your query() options
- **Filesystem-based**: define agents as markdown files in .claude/agents/ directories
- **Built-in general-purpose**: Claude can invoke the built-in general-purpose subagent at any time via the Agent tool without you defining anything

When you define subagents, Claude determines whether to invoke them based on each subagent's description field. Write clear descriptions that explain when the subagent should be used, and Claude will automatically delegate appropriate tasks.

## Benefits of using subagents

### Context isolation

Each subagent runs in its own fresh conversation. Intermediate tool calls and results stay inside the subagent; only its final message returns to the parent.

### Parallelization

Multiple subagents can run concurrently, dramatically speeding up complex workflows.

### Specialized instructions and knowledge

Each subagent can have tailored system prompts with specific expertise, best practices, and constraints.

### Tool restrictions

Subagents can be limited to specific tools, reducing the risk of unintended actions.

## Creating subagents

### Programmatic definition (recommended)

Define subagents directly in your code using the agents parameter. The Agent tool must be included in allowedTools since Claude invokes subagents through the Agent tool.

```python
import asyncio
from claude_agent_sdk import query, ClaudeAgentOptions, AgentDefinition

async def main():
    async for message in query(
        prompt="Review the authentication module for security issues",
        options=ClaudeAgentOptions(
            allowed_tools=["Read", "Grep", "Glob", "Agent"],
            agents={
                "code-reviewer": AgentDefinition(
                    description="Expert code review specialist. Use for quality, security, and maintainability reviews.",
                    prompt="""You are a code review specialist with expertise in security, performance, and best practices.

When reviewing code:
- Identify security vulnerabilities
- Check for performance issues
- Verify adherence to coding standards
- Suggest specific improvements

Be thorough but concise in your feedback.""",
                    tools=["Read", "Grep", "Glob"],
                    model="sonnet",
                ),
                "test-runner": AgentDefinition(
                    description="Runs and analyzes test suites. Use for test execution and coverage analysis.",
                    prompt="""You are a test execution specialist. Run tests and provide clear analysis of results.

Focus on:
- Running test commands
- Analyzing test output
- Identifying failing tests
- Suggesting fixes for failures""",
                    tools=["Bash", "Read", "Grep"],
                ),
            },
        ),
    ):
        if hasattr(message, "result"):
            print(message.result)

asyncio.run(main())
```

### AgentDefinition configuration

| Field | Type | Required | Description |
|---|---|---|---|
| description | string | Yes | Natural language description of when to use this agent |
| prompt | string | Yes | The agent's system prompt defining its role and behavior |
| tools | string[] | No | Array of allowed tool names. If omitted, inherits all tools |
| model | 'sonnet' \| 'opus' \| 'haiku' \| 'inherit' | No | Model override for this agent |

> Subagents cannot spawn their own subagents. Don't include Agent in a subagent's tools array.

### Filesystem-based definition (alternative)

You can also define subagents as markdown files in .claude/agents/ directories. Programmatically defined agents take precedence over filesystem-based agents with the same name.

## What subagents inherit

| The subagent receives | The subagent does not receive |
|---|---|
| Its own system prompt (AgentDefinition.prompt) and the Agent tool's prompt | The parent's conversation history or tool results |
| Project CLAUDE.md (loaded via settingSources) | Skills (unless listed in AgentDefinition.skills, TypeScript only) |
| Tool definitions (inherited from parent, or the subset in tools) | The parent's system prompt |

The parent receives the subagent's final message verbatim as the Agent tool result, but may summarize it in its own response.

## Invoking subagents

### Automatic invocation

Claude automatically decides when to invoke subagents based on the task and each subagent's description. Write clear, specific descriptions so Claude can match tasks to the right subagent.

### Explicit invocation

To guarantee Claude uses a specific subagent, mention it by name in your prompt:

```
"Use the code-reviewer agent to check the authentication module"
```

### Dynamic agent configuration

You can create agent definitions dynamically based on runtime conditions:

```python
import asyncio
from claude_agent_sdk import query, ClaudeAgentOptions, AgentDefinition

def create_security_agent(security_level: str) -> AgentDefinition:
    is_strict = security_level == "strict"
    return AgentDefinition(
        description="Security code reviewer",
        prompt=f"You are a {'strict' if is_strict else 'balanced'} security reviewer...",
        tools=["Read", "Grep", "Glob"],
        model="opus" if is_strict else "sonnet",
    )

async def main():
    async for message in query(
        prompt="Review this PR for security issues",
        options=ClaudeAgentOptions(
            allowed_tools=["Read", "Grep", "Glob", "Agent"],
            agents={
                "security-reviewer": create_security_agent("strict")
            },
        ),
    ):
        if hasattr(message, "result"):
            print(message.result)

asyncio.run(main())
```

### Detecting subagent invocation

Subagents are invoked via the Agent tool. To detect when a subagent is invoked, check for tool_use blocks where name is "Agent". Messages from within a subagent's context include a parent_tool_use_id field.

> The tool name was renamed from "Task" to "Agent" in Claude Code v2.1.63. Check both values for compatibility.

### Resuming subagents

Subagents can be resumed to continue where they left off. Resumed subagents retain their full conversation history.

To resume a subagent programmatically:
1. Capture the session ID from messages during the first query
2. Extract the agent ID from the message content
3. Resume the session by passing `resume: sessionId` in the second query's options

```typescript
import { query, type SDKMessage } from "@anthropic-ai/claude-agent-sdk";

function extractAgentId(message: SDKMessage): string | undefined {
  if (!("message" in message)) return undefined;
  const content = JSON.stringify(message.message.content);
  const match = content.match(/agentId:\s*([a-f0-9-]+)/);
  return match?.[1];
}

let agentId: string | undefined;
let sessionId: string | undefined;

for await (const message of query({
  prompt: "Use the Explore agent to find all API endpoints in this codebase",
  options: { allowedTools: ["Read", "Grep", "Glob", "Agent"] }
})) {
  if ("session_id" in message) sessionId = message.session_id;
  const extractedId = extractAgentId(message);
  if (extractedId) agentId = extractedId;
  if ("result" in message) console.log(message.result);
}

if (agentId && sessionId) {
  for await (const message of query({
    prompt: `Resume agent ${agentId} and list the top 3 most complex endpoints`,
    options: { allowedTools: ["Read", "Grep", "Glob", "Agent"], resume: sessionId }
  })) {
    if ("result" in message) console.log(message.result);
  }
}
```

## Tool restrictions

Subagents can have restricted tool access via the tools field:

- **Omit the field**: agent inherits all available tools (default)
- **Specify tools**: agent can only use listed tools

Common tool combinations:

| Use case | Tools | Description |
|---|---|---|
| Read-only analysis | Read, Grep, Glob | Can examine code but not modify or execute |
| Test execution | Bash, Read, Grep | Can run commands and analyze output |
| Code modification | Read, Edit, Write, Grep, Glob | Full read/write without command execution |
| Full access | All tools | Inherits all tools from parent (omit tools field) |

## Troubleshooting

### Claude not delegating to subagents

- Include the Agent tool in allowedTools
- Use explicit prompting: mention the subagent by name
- Write a clear description explaining when the subagent should be used

### Filesystem-based agents not loading

Agents defined in .claude/agents/ are loaded at startup only. Restart the session after creating new agent files.

### Windows: long prompt failures

On Windows, subagents with very long prompts may fail due to command line length limits (8191 chars). Keep prompts concise or use filesystem-based agents.

## Related documentation

- Claude Code subagents: comprehensive subagent documentation including filesystem-based definitions
- SDK overview: getting started with the Claude Agent SDK
