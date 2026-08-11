---
last-updated: 2026-08-11
---

# CCAR-F - Fact Sheet

## Quick Reference

| Detail | Info |
|---|---|
| Exam Code | CCAR-F |
| Full Name | Claude Certified Architect - Foundations |
| Provider | Anthropic |
| Duration | 120 minutes |
| Questions | 60 multiple-choice and multiple-response, scenario-based |
| Passing Score | 720 / 1000 |
| Cost | $125 USD |
| Delivery | Pearson VUE (online proctored or test center) |
| Validity | 12 months, free non-proctored on-time renewal |
| Launched | March 12, 2026 |

Registration is through the [Anthropic Partner Academy](https://anthropic-partners.skilljar.com/page/partner-certifications) and requires free [Claude Partner Network](https://claude.com/partners) membership. Retakes: 14-day wait after attempt 1, 30 days after attempt 2, 90 days after attempt 3, maximum 4 attempts in a rolling 12 months.

---

## Domain Weights

| Domain | Weight | Key Focus |
|---|---|---|
| 1. Agentic Architecture | 27% | Patterns, multi-agent, production |
| 2. Claude Code Configuration | 20% | CLI, CLAUDE.md, hooks, settings |
| 3. Prompt Engineering & Structured Output | 20% | Prompts, JSON, XML, caching |
| 4. Tool Design & MCP Integration | 18% | MCP, tools, function calling |
| 5. Context & Reliability | 15% | Context window, retries, streaming |

---

## Official Documentation Links

### Core Documentation

**[Anthropic Documentation Home](https://docs.anthropic.com)** - Primary documentation portal for all Claude APIs and features

**[API Reference - Messages](https://docs.anthropic.com/en/api/messages)** - Complete Messages API reference including request/response formats

**[API Reference - Message Batches](https://docs.anthropic.com/en/api/creating-message-batches)** - Batch processing API for high-volume workloads

**[Models Overview](https://docs.anthropic.com/en/docs/about-claude/models)** - Model specifications, capabilities, and pricing

**[Getting Started](https://docs.anthropic.com/en/docs/initial-setup)** - Initial API setup, authentication, and first request

**[API Errors](https://docs.anthropic.com/en/api/errors)** - Error codes, meanings, and recommended handling patterns

**[Rate Limits](https://docs.anthropic.com/en/docs/build-with-claude/rate-limits)** - Rate limit tiers, headers, and management strategies

### Prompt Engineering

**[Prompt Engineering Overview](https://docs.anthropic.com/en/docs/build-with-claude/prompt-engineering)** - Comprehensive guide to writing effective prompts for Claude

**[System Prompts](https://docs.anthropic.com/en/docs/build-with-claude/prompt-engineering/system-prompts)** - Best practices for system prompt design and structure

**[Chain of Thought](https://docs.anthropic.com/en/docs/build-with-claude/prompt-engineering/chain-of-thought)** - Techniques for eliciting step-by-step reasoning

**[Use XML Tags](https://docs.anthropic.com/en/docs/build-with-claude/prompt-engineering/use-xml-tags)** - Using XML tags to organize and structure prompts

**[Few-Shot Prompting](https://docs.anthropic.com/en/docs/build-with-claude/prompt-engineering/few-shot-prompting)** - Providing examples to guide Claude's output format and behavior

**[Prompt Caching](https://docs.anthropic.com/en/docs/build-with-claude/prompt-caching)** - Cache static prompt prefixes for up to 90% cost reduction

**[Extended Thinking](https://docs.anthropic.com/en/docs/build-with-claude/extended-thinking)** - Enable Claude's internal reasoning for complex tasks

### Tool Use and Function Calling

**[Tool Use Guide](https://docs.anthropic.com/en/docs/build-with-claude/tool-use)** - Complete guide to function calling with Claude

**[Tool Use Best Practices](https://docs.anthropic.com/en/docs/build-with-claude/tool-use/best-practices)** - Naming, descriptions, and schema design for tools

**[Structured Output via Tool Use](https://docs.anthropic.com/en/docs/build-with-claude/tool-use#json-mode)** - Using tool definitions to extract structured JSON

**[Computer Use](https://docs.anthropic.com/en/docs/build-with-claude/computer-use)** - Claude's ability to interact with computer interfaces

### Agentic Systems

**[Agentic Patterns](https://docs.anthropic.com/en/docs/build-with-claude/agentic)** - Official guide to building agentic systems with Claude

**[Anthropic Cookbook](https://github.com/anthropics/anthropic-cookbook)** - Code examples and recipes for common Claude patterns

**[Token Counting](https://docs.anthropic.com/en/docs/build-with-claude/token-counting)** - Counting tokens before sending requests

### Claude Code

**[Claude Code Overview](https://docs.anthropic.com/en/docs/claude-code/overview)** - Introduction to Claude Code CLI and IDE integration

**[Claude Code Memory (CLAUDE.md)](https://docs.anthropic.com/en/docs/claude-code/memory)** - Project instructions and memory file configuration

**[Claude Code Settings](https://docs.anthropic.com/en/docs/claude-code/settings)** - Configuration options and permissions model

**[Claude Code Hooks](https://docs.anthropic.com/en/docs/claude-code/hooks)** - Pre-tool and post-tool execution hooks

**[Claude Code Slash Commands](https://docs.anthropic.com/en/docs/claude-code/slash-commands)** - Custom and built-in slash commands

**[Claude Code MCP Servers](https://docs.anthropic.com/en/docs/claude-code/mcp-servers)** - Configuring MCP servers in Claude Code

**[Claude Code Best Practices](https://docs.anthropic.com/en/docs/claude-code/best-practices)** - Tips for effective Claude Code usage

**[Claude Code IDE Integration](https://docs.anthropic.com/en/docs/claude-code/ide-integrations)** - VS Code and JetBrains setup

### Model Context Protocol (MCP)

**[MCP Introduction](https://modelcontextprotocol.io/introduction)** - Overview of the Model Context Protocol

**[MCP Architecture](https://modelcontextprotocol.io/docs/concepts/architecture)** - Client-server architecture and design principles

**[MCP Tools](https://modelcontextprotocol.io/docs/concepts/tools)** - Defining and exposing tools via MCP

**[MCP Resources](https://modelcontextprotocol.io/docs/concepts/resources)** - Exposing data and content via MCP resources

**[MCP Prompts](https://modelcontextprotocol.io/docs/concepts/prompts)** - Reusable prompt templates in MCP

**[MCP Transports](https://modelcontextprotocol.io/docs/concepts/transports)** - stdio, SSE, and streamable HTTP transport types

**[MCP Sampling](https://modelcontextprotocol.io/docs/concepts/sampling)** - Server-initiated LLM interactions

**[MCP Specification](https://spec.modelcontextprotocol.io)** - Full protocol specification

**[MCP Servers Repository](https://github.com/modelcontextprotocol/servers)** - Reference server implementations

### Multimodal

**[Vision Guide](https://docs.anthropic.com/en/docs/build-with-claude/vision)** - Image understanding capabilities and best practices

**[PDF Support](https://docs.anthropic.com/en/docs/build-with-claude/pdf-support)** - Processing PDF documents with Claude

### Streaming

**[Streaming Guide](https://docs.anthropic.com/en/docs/build-with-claude/streaming)** - Server-sent events streaming for real-time responses

### Training and Certification

**[Anthropic Academy (Skilljar)](https://anthropic.skilljar.com)** - Free official training courses

**[Anthropic Website](https://www.anthropic.com)** - Company information and announcements

**[Anthropic News/Blog](https://www.anthropic.com/news)** - Latest feature releases and updates

### SDKs

**[Python SDK](https://github.com/anthropics/anthropic-sdk-python)** - Official Python SDK for the Anthropic API

**[TypeScript SDK](https://github.com/anthropics/anthropic-sdk-node)** - Official TypeScript/Node.js SDK for the Anthropic API

---

## Domain 1 - Agentic Architecture (27%)

### Key Facts

- **Agentic system** - A system where Claude uses tools in a loop to accomplish multi-step tasks autonomously
- **Tool use loop** - Claude calls a tool, receives the result, reasons about it, then decides the next action
- **Plan-execute-reflect** - Agent plans steps, executes them with tools, reflects on results, and adjusts
- **Supervisor pattern** - A coordinator agent delegates tasks to specialized sub-agents
- **Single agent** - One Claude instance handles all tasks with available tools
- **Multi-agent** - Multiple Claude instances collaborate, each with specialized roles
- **When NOT to use agents** - Simple classification, single-turn Q&A, straightforward text generation
- **When TO use agents** - Multi-step tasks requiring tool use, complex reasoning, dynamic decision making

### Production Considerations

- Agents amplify both capabilities and costs - each loop iteration is an API call
- Extended thinking increases per-request cost but can reduce total iterations
- Implement maximum iteration limits to prevent runaway costs
- Log all tool calls and decisions for debugging and auditing
- Use cheaper models (Haiku) for simple sub-tasks, expensive models (Opus) for complex reasoning
- Implement circuit breakers - stop after N consecutive errors
- Human-in-the-loop checkpoints for high-stakes decisions

### Agentic Error Handling

- Retry transient failures (rate limits, network errors) with exponential backoff
- Provide error context back to Claude so it can adjust its approach
- Implement fallback strategies (try alternative tools, simplify the task)
- Set maximum retry counts to prevent infinite loops
- Distinguish between recoverable and unrecoverable errors

---

## Domain 2 - Claude Code Configuration (20%)

### Key Facts

- **Claude Code** - Anthropic's official CLI for Claude, available as terminal app and IDE extension
- **CLAUDE.md** - Project instruction files that persist across sessions
- **CLAUDE.md hierarchy** - User-level (~/.claude/CLAUDE.md) -> Project-level (repo root CLAUDE.md) -> Directory-level (subdirectory CLAUDE.md files)
- **Hooks** - Scripts that run before or after Claude Code executes specific tools
- **Pre-tool hooks** - Run before a tool executes (can block execution)
- **Post-tool hooks** - Run after a tool completes (can process results)
- **Custom slash commands** - User-defined commands stored in .claude/commands/ directory
- **Project slash commands** - Team-shared commands in .claude/commands/ at project root
- **Permissions** - Claude Code has a permissions model controlling which tools can run without approval

### CLAUDE.md Best Practices

- Keep instructions concise and actionable
- Use CLAUDE.md for project-specific coding standards, build commands, and conventions
- User-level CLAUDE.md applies to all projects (global preferences)
- Project-level CLAUDE.md is checked into version control for team sharing
- CLAUDE.md content is included in Claude's context, so keep it focused

### Settings Configuration

- Settings file: `~/.claude/settings.json` (user) and `.claude/settings.json` (project)
- Enterprise settings can be managed centrally
- Permissions control which bash commands can run without confirmation
- MCP servers configured via settings or `.mcp.json` files

---

## Domain 3 - Prompt Engineering & Structured Output (20%)

### Key Facts

- **System prompt** - Sets Claude's role, behavior, and constraints. Sent as the `system` parameter.
- **User prompt** - The actual request or question from the user
- **XML tags** - Claude responds exceptionally well to XML-tagged sections in prompts (e.g., `<instructions>`, `<context>`, `<examples>`)
- **Chain-of-thought** - Ask Claude to "think step by step" for complex reasoning tasks
- **Few-shot prompting** - Provide 2-5 input/output examples to guide format and behavior
- **Many-shot prompting** - Provide dozens of examples for highly specific patterns
- **JSON mode** - Force JSON output by using tool definitions as output schemas
- **Temperature** - Controls randomness. 0 = deterministic, 1 = default, higher = more creative
- **Top-p** - Alternative to temperature for controlling output diversity
- **Max tokens** - Limit response length. Required parameter in the API.

### Structured Output Techniques

1. **Tool use for extraction** - Define a tool with the desired JSON schema. Claude will "call" the tool with structured data.
2. **System prompt instructions** - Tell Claude to respond in JSON format within the system prompt
3. **Prefill** - Start the assistant message with `{` to force JSON output
4. **XML wrapping** - Ask Claude to wrap output in specific XML tags for parsing

### Prompt Caching

- Cache static prompt prefixes (system prompts, few-shot examples, reference documents)
- Cached content must be at least 1024 tokens (2048 for Claude 3.5 Haiku)
- Use `cache_control: {"type": "ephemeral"}` to mark cacheable blocks
- Cached tokens cost 90% less on cache hits
- Cache TTL is 5 minutes, refreshed on each hit
- Ideal for: RAG systems, multi-turn conversations, repeated prompt patterns

---

## Domain 4 - Tool Design & MCP Integration (18%)

### Key Facts

- **MCP** - Model Context Protocol - an open standard for connecting AI models to external tools and data
- **MCP Client** - The AI application (Claude Desktop, Claude Code) that connects to MCP servers
- **MCP Server** - A service that exposes tools, resources, and prompts to MCP clients
- **MCP Transport - stdio** - Communication via standard input/output (local processes)
- **MCP Transport - SSE** - Server-Sent Events over HTTP (remote servers, legacy)
- **MCP Transport - Streamable HTTP** - Modern HTTP-based transport (remote servers, recommended)
- **Tool choice: auto** - Claude decides whether to use a tool (default)
- **Tool choice: any** - Claude must use one of the provided tools
- **Tool choice: tool** - Claude must use a specific named tool
- **Parallel tool use** - Claude can request multiple tool calls in a single response

### Tool Design Best Practices

- **Clear names** - Use verb-noun format (e.g., `get_customer`, `search_orders`)
- **Detailed descriptions** - Explain what the tool does, when to use it, and what it returns
- **Precise schemas** - Use JSON Schema with descriptions on every field
- **Minimal parameters** - Only require what is necessary; use optional params for flexibility
- **Error responses** - Return `is_error: true` with a descriptive message for tool failures
- **Idempotent operations** - Prefer idempotent tools for reliability in agentic loops

### MCP Server Components

1. **Tools** - Executable functions the model can call (e.g., query a database, call an API)
2. **Resources** - Read-only data the model can access (e.g., file contents, database records)
3. **Prompts** - Reusable prompt templates with parameters

### API Tool Use vs MCP

| Feature | API Tool Use | MCP |
|---|---|---|
| Where defined | In the API request | On an MCP server |
| Who executes | Your application code | MCP server |
| Protocol | Anthropic Messages API | MCP protocol |
| Transport | HTTP | stdio, SSE, streamable HTTP |
| Use case | Direct API integration | Reusable tool ecosystem |

---

## Domain 5 - Context & Reliability (15%)

### Key Facts

- **Context window** - 200K tokens for Claude 3.5 Sonnet and Claude 3 Opus. Check model docs for latest.
- **Token counting** - Use the token counting API to pre-calculate token usage before sending requests
- **Prompt caching** - Reduces costs by caching static prompt prefixes (up to 90% savings)
- **Extended thinking** - Claude's internal reasoning mode. Uses a "thinking" block before responding.
- **Extended thinking budget** - Set `max_tokens` for thinking budget. Higher budget = deeper reasoning but higher cost.
- **Streaming** - Server-sent events (SSE) for real-time response delivery
- **Rate limits** - Per-model, per-tier limits on requests per minute (RPM) and tokens per minute (TPM)
- **Retry-After header** - API returns this header on 429 errors indicating when to retry

### Reliability Patterns

1. **Exponential backoff with jitter** - Retry failed requests with increasing delays plus random jitter
2. **Fallback models** - If Claude Sonnet fails or is rate-limited, fall back to Claude Haiku
3. **Validation loops** - Check Claude's output against expected schemas/formats; retry if invalid
4. **Circuit breaker** - Stop calling the API after N consecutive failures; resume after cooldown
5. **Timeout management** - Set appropriate timeouts for different request types
6. **Idempotency** - Design tool calls to be safely retryable

### Context Management Strategies

- **Sliding window** - Keep the most recent N messages, drop older ones
- **Summarization** - Periodically summarize conversation history to compress context
- **RAG** - Retrieve only relevant documents rather than including everything
- **Prompt caching** - Cache the static parts of the context (system prompt, reference docs)
- **Chunking** - For large documents, process in chunks and aggregate results
- **Priority ordering** - Place the most important information at the beginning and end of context

### Error Codes

| Code | Meaning | Action |
|---|---|---|
| 400 | Invalid request | Fix request format |
| 401 | Authentication error | Check API key |
| 403 | Permission denied | Check account permissions |
| 404 | Not found | Check endpoint URL |
| 429 | Rate limited | Retry with backoff, check Retry-After header |
| 500 | Server error | Retry with backoff |
| 529 | API overloaded | Retry with backoff |

---

## Exam Tips

### High-Frequency Topics

These topics appear most frequently on the exam:

1. Agentic design patterns and when to use them
2. CLAUDE.md file hierarchy and configuration
3. Tool design best practices (naming, schemas, descriptions)
4. MCP architecture (clients, servers, transports)
5. Prompt caching implementation and cost savings
6. Extended thinking - when and how to use it
7. Reliability patterns for production systems
8. Tool choice modes (auto, any, specific)
9. Structured output extraction techniques
10. Context window management strategies

### Common Exam Traps

1. **Agent vs prompt** - Do not over-engineer. If a simple prompt works, use it.
2. **MCP direction** - Claude is the MCP CLIENT, not the server. Your app provides the SERVER.
3. **Cache minimum** - Cached content needs minimum 1024 tokens (2048 for Haiku)
4. **Tool choice default** - Default is `auto`, not `any`
5. **Streaming with extended thinking** - Extended thinking works with streaming but thinking tokens are delivered as a single event
6. **CLAUDE.md is context** - Everything in CLAUDE.md uses context window tokens
7. **Rate limits are per-model** - Different models have different rate limit tiers
8. **Prompt caching TTL** - Cache expires after 5 minutes without a hit
9. **Temperature 0 is not truly deterministic** - Claude may still vary slightly at temperature 0
10. **MCP resources are read-only** - Use tools for actions, resources for data access

### Answer Selection Strategy

1. Read the complete scenario before looking at answers
2. Identify which domain the question targets
3. Eliminate obviously wrong answers (usually 1-2)
4. Between remaining options, choose the one that is:
   - Most production-appropriate
   - Most cost-effective
   - Simplest solution that meets all requirements
   - Most aligned with Anthropic's documented best practices
5. If truly unsure, favor the answer that prioritizes reliability over performance

---

## Anthropic Academy Courses (Skilljar)

All courses available at https://anthropic.skilljar.com

1. Claude 101
2. AI Fluency Framework and Foundations
3. Building Applications with Claude API
4. Prompt Engineering with Claude
5. Introduction to Model Context Protocol
6. Tool Use with Claude
7. Claude Code Fundamentals
8. Advanced Claude Code
9. Building Agentic Applications
10. Multi-Agent Systems
11. Production AI Systems
12. Responsible AI with Claude
13. Claude for Enterprise Teams

Complete all 13 courses before attempting the exam. They are free and closely aligned with exam content.
