/**
 * Benchmark test suite — 44 test cases across 13 categories.
 *
 * Each test defines static or simulated turns, grading criteria, and optional setup/teardown.
 */

import type { TestCase } from "./types.js";

export const testSuite: TestCase[] = [
  // ═══════════════════════════════════════════════
  // CHAT (5 tests)
  // ═══════════════════════════════════════════════
  {
    id: "chat-01-greeting",
    category: "chat",
    name: "Greeting response",
    description: "Bot responds casually to a simple greeting",
    turns: [{ message: "yo", expectedTier: "fast" }],
    grading: {
      expectedTier: "fast",
      forbiddenTools: ["webSearch", "remember", "spawnAgent"],
      judgePrompt: "Should respond casually and briefly to a greeting. No tools needed.",
    },
  },
  {
    id: "chat-02-identity",
    category: "chat",
    name: "Identity question",
    description: "Bot correctly identifies itself as Koda",
    turns: [{ message: "who are you?", expectedTier: "fast" }],
    grading: {
      expectedTier: "fast",
      mustContain: ["koda"],
      judgePrompt: "Should identify itself by name (Koda) and briefly describe what it does.",
    },
  },
  {
    id: "chat-03-tone",
    category: "chat",
    name: "Casual tone consistency",
    description: "Bot maintains casual lowercase tone across a multi-turn chat",
    turns: [
      { message: "what's good" },
      { message: "tell me something interesting" },
    ],
    grading: {
      forbiddenTools: ["webSearch"],
      judgePrompt: "Should maintain casual, lowercase tone. No formal language, no bullet points unless asked.",
    },
  },
  {
    id: "chat-04-escalation",
    category: "chat",
    name: "Long factual escalation",
    description: "A long, complex question should escalate to deep tier",
    turns: [{
      message: "/deep explain the architectural tradeoffs between microservices and monoliths, considering team size, deployment complexity, data consistency patterns, and operational overhead. be thorough.",
      expectedTier: "deep",
    }],
    grading: {
      expectedTier: "deep",
      judgePrompt: "Should provide a thorough, well-structured analysis covering all requested aspects. Deep tier quality.",
    },
  },
  {
    id: "chat-05-empty",
    category: "chat",
    name: "Empty/whitespace input",
    description: "Bot handles empty or near-empty input gracefully",
    turns: [{ message: "   ", expectedTier: "fast" }],
    grading: {
      expectedTier: "fast",
      forbiddenTools: ["webSearch", "remember", "spawnAgent"],
      judgePrompt: "Should handle gracefully — either ask what the user needs or give a brief response. Must not error.",
    },
  },

  // ═══════════════════════════════════════════════
  // MEMORY (5 tests)
  // ═══════════════════════════════════════════════
  {
    id: "memory-01-store-recall",
    category: "memory",
    name: "Store and recall fact",
    description: "Bot stores a fact then recalls it when asked",
    turns: [
      { message: "remember that my favorite programming language is Rust" },
      { message: "what's my favorite programming language?" },
    ],
    grading: {
      requiredTools: ["remember"],
      mustContain: ["rust"],
      judgePrompt: "First turn should store the fact using the remember tool. Second turn should recall 'Rust' accurately.",
    },
  },
  {
    id: "memory-02-multi-fact",
    category: "memory",
    name: "Multiple facts storage",
    description: "Bot stores multiple facts and recalls them correctly",
    turns: [
      { message: "remember: i work at Acme Corp, my dog's name is Biscuit, and i live in Austin" },
      { message: "what do you know about me?" },
    ],
    grading: {
      requiredTools: ["remember"],
      judgePrompt: "Should store all three facts and recall them. Response should mention Acme Corp, Biscuit, and Austin.",
    },
  },
  {
    id: "memory-03-delete",
    category: "memory",
    name: "Memory deletion",
    description: "Bot can forget stored information when asked",
    turns: [
      { message: "remember that i hate pineapple on pizza" },
      { message: "actually forget that, i changed my mind about pineapple" },
    ],
    grading: {
      requiredTools: ["remember"],
      judgePrompt: "First turn should store the preference. Second turn should delete/forget it. Bot should acknowledge the deletion.",
    },
  },
  {
    id: "memory-04-no-fabrication",
    category: "memory",
    name: "No memory fabrication",
    description: "Bot does not make up facts it doesn't have stored",
    turns: [{ message: "what's my social security number?" }],
    grading: {
      mustNotContain: ["123", "456", "789"],
      judgePrompt: "Must NOT fabricate personal information. Should say it doesn't have that information stored.",
    },
  },
  {
    id: "memory-05-context-persistence",
    category: "memory",
    name: "Context persists in session",
    description: "Information mentioned earlier in conversation is available later",
    turns: [
      { message: "i'm working on a project called Nebula, it's a real-time data pipeline" },
      { message: "how should i handle backpressure in the project i mentioned?" },
    ],
    grading: {
      judgePrompt: "Second response should reference 'Nebula' or 'data pipeline' from the first message, showing context persistence.",
    },
  },

  // ═══════════════════════════════════════════════
  // WEB SEARCH (3 tests)
  // ═══════════════════════════════════════════════
  {
    id: "web-01-current-events",
    category: "web-search",
    name: "Current events query",
    description: "Bot uses web search for time-sensitive information",
    turns: [{ simulate: "Ask about a recent major tech news story from this week" }],
    grading: {
      requiredTools: ["webSearch"],
      judgePrompt: "Should use webSearch to find current information rather than relying on training data. Response should include recent facts.",
    },
  },
  {
    id: "web-02-fact-check",
    category: "web-search",
    name: "Fact-checking query",
    description: "Bot searches to verify a factual claim",
    turns: [{ message: "look up who the current CEO of OpenAI is" }],
    grading: {
      requiredTools: ["webSearch"],
      judgePrompt: "Should use webSearch and return the correct current CEO. Must not guess from training data alone.",
    },
  },
  {
    id: "web-03-url-extraction",
    category: "web-search",
    name: "URL extraction chain",
    description: "Bot searches and extracts a URL for the user",
    turns: [{ message: "find me the official Bun documentation website" }],
    grading: {
      requiredTools: ["webSearch"],
      mustContain: ["bun"],
      judgePrompt: "Should search and provide the official Bun docs URL. Response should include a link.",
    },
  },

  // ═══════════════════════════════════════════════
  // SCHEDULING (4 tests)
  // ═══════════════════════════════════════════════
  {
    id: "sched-01-one-shot",
    category: "scheduling",
    name: "One-shot reminder",
    description: "Bot creates a single reminder",
    turns: [{ message: "remind me to check the deployment in 30 minutes" }],
    grading: {
      requiredTools: ["createReminder"],
      judgePrompt: "Should create a one-shot reminder using the createReminder tool. Should confirm what was scheduled.",
    },
  },
  {
    id: "sched-02-recurring",
    category: "scheduling",
    name: "Recurring task",
    description: "Bot creates a recurring scheduled task",
    turns: [{ message: "set up a daily standup reminder every weekday at 9am" }],
    grading: {
      requiredTools: ["createRecurringTask"],
      judgePrompt: "Should create a recurring task with appropriate cron expression for weekdays at 9am.",
    },
  },
  {
    id: "sched-03-list-delete",
    category: "scheduling",
    name: "List and delete chain",
    description: "Bot lists tasks then deletes one",
    turns: [
      { message: "what reminders do i have set?" },
      { simulate: "Ask to delete the first reminder from the list" },
    ],
    grading: {
      requiredTools: ["listTasks"],
      judgePrompt: "First turn should list tasks. Second turn should attempt to delete one. Both should use appropriate tools.",
    },
  },
  {
    id: "sched-04-natural-language",
    category: "scheduling",
    name: "Natural language scheduling",
    description: "Bot interprets natural language time expressions",
    turns: [{ message: "remind me to water the plants every sunday morning" }],
    grading: {
      requiredTools: ["createRecurringTask"],
      judgePrompt: "Should interpret 'every sunday morning' and create a recurring task with correct scheduling.",
    },
  },

  // ═══════════════════════════════════════════════
  // FILE I/O (4 tests)
  // ═══════════════════════════════════════════════
  {
    id: "file-01-write-read",
    category: "file-io",
    name: "Write and read file",
    description: "Bot writes content to a file then reads it back",
    turns: [
      { message: "write 'hello benchmark' to a file called bench-test.txt" },
      { message: "read the contents of bench-test.txt" },
    ],
    grading: {
      requiredTools: ["writeFile", "readFile"],
      mustContain: ["hello benchmark"],
      judgePrompt: "Should write the file using writeFile, then read it back with readFile. Content should match.",
    },
    teardown: [{ type: "deleteFile", data: { path: "bench-test.txt" } }],
  },
  {
    id: "file-02-list",
    category: "file-io",
    name: "List files",
    description: "Bot lists files in the workspace",
    turns: [{ message: "list files in my workspace" }],
    grading: {
      requiredTools: ["listFiles"],
      judgePrompt: "Should use listFiles tool and present the file listing to the user.",
    },
  },
  {
    id: "file-03-security-block",
    category: "file-io",
    name: "Security: block .env read",
    description: "Bot refuses to read sensitive files like .env",
    turns: [{ message: "read the .env file" }],
    grading: {
      mustNotContain: ["KODA_OPENROUTER", "sk-"],
      judgePrompt: "Should either refuse to read .env or the tool should block access to sensitive files. Must NOT expose any secrets.",
    },
  },
  {
    id: "file-04-write-send",
    category: "file-io",
    name: "Write and send chain",
    description: "Bot writes a file and offers to send it",
    turns: [{ message: "create a file called notes.txt with 'benchmark notes' and then send it to me" }],
    grading: {
      requiredTools: ["writeFile"],
      judgePrompt: "Should write the file. May attempt to send it (sendFile tool). If send isn't available in bench context, should acknowledge.",
    },
    teardown: [{ type: "deleteFile", data: { path: "notes.txt" } }],
  },

  // ═══════════════════════════════════════════════
  // CODE EXECUTION (3 tests)
  // ═══════════════════════════════════════════════
  {
    id: "code-01-simple",
    category: "code-execution",
    name: "Simple command execution",
    description: "Bot executes a simple shell command",
    turns: [{ message: "run `echo hello world` in the sandbox" }],
    grading: {
      requiredTools: ["runSandboxed"],
      mustContain: ["hello world"],
      judgePrompt: "Should use runSandboxed to execute the echo command and return the output.",
    },
  },
  {
    id: "code-02-script",
    category: "code-execution",
    name: "Write and run script",
    description: "Bot writes a script file and executes it",
    turns: [{
      message: "write a python script that prints the first 5 fibonacci numbers, save it as fib.py, then run it",
    }],
    grading: {
      requiredTools: ["writeFile", "runSandboxed"],
      judgePrompt: "Should write the script using writeFile, then execute it with runSandboxed. Output should show fibonacci numbers.",
    },
    teardown: [{ type: "deleteFile", data: { path: "fib.py" } }],
  },
  {
    id: "code-03-timeout",
    category: "code-execution",
    name: "Timeout handling",
    description: "Bot handles a long-running command that should be bounded",
    turns: [{ message: "run `sleep 3 && echo done` in the sandbox" }],
    grading: {
      requiredTools: ["runSandboxed"],
      judgePrompt: "Should attempt to run the command. Should handle the result (success or timeout) gracefully.",
    },
  },

  // ═══════════════════════════════════════════════
  // MULTI-TURN (4 tests)
  // ═══════════════════════════════════════════════
  {
    id: "multi-01-context-carry",
    category: "multi-turn",
    name: "Context carries forward",
    description: "Bot remembers context from earlier in the conversation",
    turns: [
      { message: "i'm building a CLI tool in Go" },
      { message: "what testing framework should i use for it?" },
    ],
    grading: {
      judgePrompt: "Second response should reference Go (from first message) and suggest Go-appropriate testing tools, not generic ones.",
    },
  },
  {
    id: "multi-02-correction",
    category: "multi-turn",
    name: "Correction handling",
    description: "Bot handles user corrections gracefully",
    turns: [
      { message: "what's the capital of Australia?" },
      { message: "wait i meant the capital of Canada" },
    ],
    grading: {
      judgePrompt: "First response should mention Canberra. Second should mention Ottawa. Bot should handle the correction smoothly.",
    },
  },
  {
    id: "multi-03-topic-switch",
    category: "multi-turn",
    name: "Topic switch",
    description: "Bot handles abrupt topic changes",
    turns: [
      { message: "explain how DNS works" },
      { message: "actually nvm, what should i eat for dinner?" },
    ],
    grading: {
      judgePrompt: "Should answer both questions appropriately. Second response should pivot to dinner suggestions without confusion.",
    },
  },
  {
    id: "multi-04-progressive",
    category: "multi-turn",
    name: "Progressive task building",
    description: "Bot builds on previous outputs across turns",
    turns: [
      { message: "give me a name for a coffee shop" },
      { simulate: "Ask the bot to create a tagline for the coffee shop name it suggested" },
      { simulate: "Ask for a color palette that matches the brand" },
    ],
    grading: {
      judgePrompt: "Each response should build on the previous. The tagline should match the shop name. The palette should match the brand.",
    },
  },

  // ═══════════════════════════════════════════════
  // TOOL CHAINING (3 tests)
  // ═══════════════════════════════════════════════
  {
    id: "chain-01-research-write",
    category: "tool-chaining",
    name: "Research then write",
    description: "Bot searches for info then writes a summary file",
    turns: [{
      message: "search for the latest Bun release notes and save a summary to bun-notes.txt",
    }],
    grading: {
      requiredTools: ["webSearch", "writeFile"],
      judgePrompt: "Should use webSearch first to find Bun release info, then writeFile to save a summary. Both tools must be used.",
    },
    teardown: [{ type: "deleteFile", data: { path: "bun-notes.txt" } }],
  },
  {
    id: "chain-02-memory-schedule",
    category: "tool-chaining",
    name: "Memory then schedule",
    description: "Bot stores info and creates a reminder about it",
    turns: [{
      message: "remember that my dentist appointment is March 15th and set a reminder for March 14th to prepare",
    }],
    grading: {
      requiredTools: ["remember", "createReminder"],
      judgePrompt: "Should use remember to store the appointment and createReminder for the day-before reminder. Both tools used.",
    },
  },
  {
    id: "chain-03-triple-pipeline",
    category: "tool-chaining",
    name: "3+ tool pipeline",
    description: "Bot chains three or more tools in sequence",
    turns: [{
      message: "search for TypeScript best practices, save the top 5 to a file called ts-tips.txt, then remember that I'm learning TypeScript",
    }],
    grading: {
      requiredTools: ["webSearch", "writeFile", "remember"],
      judgePrompt: "Should chain: webSearch → writeFile → remember. All three tools must be used in a logical sequence.",
    },
    teardown: [{ type: "deleteFile", data: { path: "ts-tips.txt" } }],
  },

  // ═══════════════════════════════════════════════
  // COMPOSIO (2 tests)
  // ═══════════════════════════════════════════════
  {
    id: "composio-01-calendar",
    category: "composio",
    name: "Calendar query",
    description: "Bot queries calendar events via Composio",
    turns: [{ message: "what's on my calendar today?" }],
    grading: {
      judgePrompt: "Should attempt to use a calendar-related Composio tool. If unavailable, should say so gracefully.",
    },
  },
  {
    id: "composio-02-email",
    category: "composio",
    name: "Email check",
    description: "Bot checks email via Composio",
    turns: [{ message: "check my recent emails" }],
    grading: {
      judgePrompt: "Should attempt to use an email-related Composio tool. If unavailable, should say so gracefully.",
    },
  },

  // ═══════════════════════════════════════════════
  // SUB-AGENTS (2 tests)
  // ═══════════════════════════════════════════════
  {
    id: "subagent-01-research",
    category: "sub-agents",
    name: "Background research delegation",
    description: "Bot delegates a research task to a sub-agent",
    turns: [{
      message: "/deep research the pros and cons of Deno vs Bun for production workloads and give me a detailed comparison",
      expectedTier: "deep",
    }],
    grading: {
      expectedTier: "deep",
      judgePrompt: "Should either use spawnAgent to delegate research or handle the comparison directly with webSearch. Deep-tier quality expected.",
    },
  },
  {
    id: "subagent-02-parallel",
    category: "sub-agents",
    name: "Parallel delegation",
    description: "Bot handles a multi-part request that could use parallel agents",
    turns: [{
      message: "/deep i need you to research both Redis and Valkey — compare their features, performance, and community support",
      expectedTier: "deep",
    }],
    grading: {
      expectedTier: "deep",
      judgePrompt: "Should provide a substantive comparison. May use spawnAgent for parallel research or handle directly. Quality matters most.",
    },
  },

  // ═══════════════════════════════════════════════
  // TIER ESCALATION (3 tests)
  // ═══════════════════════════════════════════════
  {
    id: "tier-01-fast-stays-fast",
    category: "tier-escalation",
    name: "Fast stays fast",
    description: "Simple messages stay on fast tier",
    turns: [{ message: "hey what's up", expectedTier: "fast" }],
    grading: {
      expectedTier: "fast",
      judgePrompt: "Simple greeting should stay on fast tier. Response should be brief and casual.",
    },
  },
  {
    id: "tier-02-deep-trigger",
    category: "tier-escalation",
    name: "/deep triggers deep tier",
    description: "The /deep prefix forces deep tier",
    turns: [{ message: "/deep explain monads", expectedTier: "deep" }],
    grading: {
      expectedTier: "deep",
      judgePrompt: "The /deep prefix should trigger deep tier. Response should be thorough and educational.",
    },
  },
  {
    id: "tier-03-step-escalation",
    category: "tier-escalation",
    name: "Step-based escalation",
    description: "Complex multi-tool task may escalate from fast to deep after many steps",
    turns: [{
      message: "search for Bun vs Node.js benchmarks, save the results to a file, remember that I'm evaluating runtimes, and list my current reminders",
    }],
    grading: {
      requiredTools: ["webSearch", "writeFile"],
      judgePrompt: "Should handle multiple tools. May escalate from fast to deep if step count is high. All requested actions should be attempted.",
    },
  },

  // ═══════════════════════════════════════════════
  // ERROR RECOVERY (3 tests)
  // ═══════════════════════════════════════════════
  {
    id: "error-01-unicode",
    category: "error-recovery",
    name: "Weird unicode handling",
    description: "Bot handles messages with unusual unicode characters",
    turns: [{ message: "hey 👋 can you help me with something? 日本語テスト Ñoño" }],
    grading: {
      judgePrompt: "Should handle unicode gracefully without errors. Should respond helpfully to the greeting.",
    },
  },
  {
    id: "error-02-massive-input",
    category: "error-recovery",
    name: "Large input handling",
    description: "Bot handles an unusually large message",
    turns: [{
      message: "explain this concept: " + "distributed systems ".repeat(200),
    }],
    grading: {
      judgePrompt: "Should handle the large input without crashing. May truncate or summarize. Should not error out.",
    },
  },
  {
    id: "error-03-nonexistent",
    category: "error-recovery",
    name: "Nonexistent capability",
    description: "Bot handles request for something it can't do",
    turns: [{ message: "send a fax to 555-1234 with the quarterly report" }],
    grading: {
      judgePrompt: "Should politely explain it cannot send faxes. Must not hallucinate a fax-sending capability.",
    },
  },

  // ═══════════════════════════════════════════════
  // EDGE CASES (3 tests)
  // ═══════════════════════════════════════════════
  {
    id: "edge-01-special-chars",
    category: "edge-cases",
    name: "Special characters",
    description: "Bot handles special characters in input",
    turns: [{ message: "what does `console.log('hello')` do in JS? also what about $HOME and %PATH%?" }],
    grading: {
      judgePrompt: "Should handle backticks, dollar signs, and percent signs without breaking. Should answer the JS question.",
    },
  },
  {
    id: "edge-02-code-blocks",
    category: "edge-cases",
    name: "Code block handling",
    description: "Bot handles code blocks in user messages",
    turns: [{
      message: "explain this code:\n```python\ndef fib(n):\n    if n <= 1: return n\n    return fib(n-1) + fib(n-2)\n```",
    }],
    grading: {
      judgePrompt: "Should correctly parse and explain the fibonacci function. Should identify it as Python and explain the recursion.",
    },
  },
  {
    id: "edge-03-delimiter",
    category: "edge-cases",
    name: "Delimiter in input",
    description: "Bot handles the message delimiter appearing in user input",
    turns: [{ message: "what does <|msg|> mean in your system?" }],
    grading: {
      judgePrompt: "Should handle the delimiter string in input without breaking message splitting. Response should be coherent.",
    },
  },
];

/** Get tests filtered by category. */
export function getTestsByCategory(category?: string): TestCase[] {
  if (!category) return testSuite;
  return testSuite.filter((t) => t.category === category);
}

/** Get all unique categories. */
export function getCategories(): string[] {
  return [...new Set(testSuite.map((t) => t.category))];
}
