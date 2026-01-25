---
metadata:
  videoId: "opZpIN8g_6M"
  title: "Claude Just Solved Their Biggest Problem"
  description: "Claude MCP as code revolutionizes how we handle tool calls by preventing context window bloat. This approach leverages Claude Code's capabilities to transform MCPs into efficient backend APIs. Discover how Claude Skills combined with MCP as code enables progressive disclosure, smarter workflows, and better state management for AI development.


    Claude MCP as code revolutionizes how we handle tool calls by preventing context window bloat. This approach leverages Claude Code's capabilities to transform MCPs into efficient backend APIs. Discover how Claude Skills combined with MCP as code enables progressive disclosure, smarter workflows, and better state management for AI development.


    In this video, I break down Anthropic's paper on solving MCP context window problems. You'll learn why traditional MCPs consume 10%+ of your context before you even start working, and how converting them to code fixes this issue. I cover progressive disclosure for loading only what you need, context-efficient tool results that prevent data bloat, powerful control flow that reduces hallucinations, privacy-preserving operations for sensitive data, and state persistence using Claude's filesystem-based approach.


    Whether you're building with Claude or just curious about optimizing AI workflows, this video shows you practical solutions that software engineers have used for years—now applied to AI agents. Perfect for developers working with Model Context Protocol and anyone looking to maximize their AI agent's efficiency.


    #ClaudeAI #MCP #AIAgents #ClaudeCode #ModelContextProtocol #AICoding #Anthropic #ClaudeSkills #AIWorkflow #SoftwareDevelopment #AITools #MachineLearning #CodingWithAI #AIAutomation #DeveloperTools"
  channel: "AI LABS"
  channelId: "UCelfWQr9sXVMTvBzviPGlFw"
  duration: "PT9M24S"
  publishedAt: "2025-11-21T13:45:11Z"
  thumbnailUrl: "https://i.ytimg.com/vi/opZpIN8g_6M/hqdefault.jpg"
  youtubeUrl: "https://www.youtube.com/watch?v=opZpIN8g_6M"
processedAt: "2026-01-13T15:53:22.433Z"
source: "youtube"
playlistId: "PL-SEjLl-bojVmsXOvG-TBp7DVv0McXJzn"
playlistName: "AI Summaries"
category: "ai"
tldr: "Anthropic's new **MCP as Code** strategy solves context window bloat by replacing static tool calls with a file-based TypeScript API.

  - **Progressive Disclosure**: Loads only necessary tool definitions on demand instead of all at once.

  - **Data Filtering**: Uses code to aggregate results, preventing token overflow from large datasets.

  - **Logic Control**: Moves execution flow to code to reduce hal\n"
ai:
  provider: "gemini"
  model: "gemini-3-flash-preview"
  apiCalls: 1
  fallbackAttempts: 0
  inputTokens: 2446
  outputTokens: 931
  totalTokens: 4811
  processingTimeMs: 14356
tools:
  - name: "Model Context Protocol"
    url: null
  - name: "Claude Code"
    url: null
  - name: "Claude Skills"
    url: null
---

## Key Takeaways

Anthropic is evolving the **Model Context Protocol (MCP)** by treating tool interactions as executable code rather than static context injections.

* **Context Management**: By using a file-system-based structure with an **index.ts** file, Claude only loads tool definitions when needed, saving massive amounts of context space.

* **Efficiency and Privacy**: Code acts as a filter, allowing agents to process large datasets and return only relevant, non-sensitive summaries to the model.

* **Reduced Hallucinations**: Complex multi-step tool calls are replaced by hard-coded logic, removing the model's need to "decide" every sequential step.

* **Skill Persistence**: Successful code-based tool interactions can be saved as permanent **skills**, creating a reusable library for future tasks.

## Summary

### The Context Bloat Problem
When using the standard **Model Context Protocol (MCP)**, tool definitions are permanently exposed to the model. Even before a task begins, just a few connected MCPs can consume 10% or more of the total context window. Furthermore, the raw output from these tools—such as entire database queries—remains in the context, rapidly exhausting the token limit and increasing latency.

### The Solution: MCP as Code
Anthropic's proposed solution shifts from static tool calls to a backend API approach. Instead of loading an entire server into the context, developers create a **servers folder** where each tool is represented by a specific code file. An **index.ts** file acts as a directory. Claude uses its file-system navigation capabilities to identify the correct tool and only loads that specific code into its active memory.

### Key Advantages of the Code-First Approach
This method introduces **progressive disclosure**, where the model only "sees" what is relevant to the current step. It also allows for **context-efficient tool results**. Rather than dumping massive datasets into the context, the code can transform or aggregate data first. For example, an agent can be programmed to return only the first five rows of a massive Google Sheet or a summarized count of entries, preventing the window from being unnecessarily bloated.

**Control flow** is significantly improved. Traditionally, an agent must make a decision, call a tool, wait for the response, and then make the next decision. With **MCP as code**, the developer can wrap complex sequences in logic like conditional statements. This reduces the number of round-trips to the model, saving time and minimizing the potential for **hallucinations** during execution.

### Privacy and Persistence
From a security perspective, this approach enables **privacy-preserving operations**. The code can be designed to mask sensitive database fields, providing the agent with placeholders or specific logs instead of raw sensitive data. Finally, by integrating with Claude's **skills** feature, these code-based tools can be saved as permanent assets in the file system, allowing the agent to maintain state and "remember" how to perform complex tasks across different sessions.

### The Infrastructure Trade-off
While this reduces token costs and lowers latency, it introduces **technical complexity**. To implement this safely, developers must maintain a secure **sandboxed environment** to execute agent-generated code. This creates a choice for developers: accept high token costs and bloat, or invest in more robust infrastructure and monitoring for code execution.

## Context

This development marks a significant shift in AI agent architecture from prompt-heavy to engineering-heavy design. As LLMs like **Claude** are increasingly used for complex, long-running tasks, managing the **context window** has become the primary bottleneck for performance and cost. The "MCP as Code" approach aligns AI behavior with standard software engineering practices like modularity and abstraction. This matters to developers building enterprise-grade agents that must interact with massive internal databases or sensitive APIs, where token efficiency and data security are paramount. It reflects a broader trend of moving away from simple chat interfaces toward integrated, autonomous development environments.
