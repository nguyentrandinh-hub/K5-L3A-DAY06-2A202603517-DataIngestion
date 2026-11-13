> ## AI Agent Context
> Get the complete documentation index at: https://aistudio.google.com/llms.txt
> Use this file to discover all available pages.
> For the full documentation in a single file, fetch: https://aistudio.google.com/llms-full.txt

# What's new in Gemini 3.6 Flash and 3.5 Flash-Lite

Gemini 3.6 Flash (`gemini-3.6-flash`) and Gemini 3.5 Flash-Lite
(`gemini-3.5-flash-lite`) are previous-generation releases in the Gemini 3
series and remain available for production use. For our newest Flash model, see
[Gemini 3.8 Flash](/docs/whats-new-gemini-3.8).

* **Gemini 3.6 Flash**: Stronger performance on complex agentic and multimodal tasks while reducing token usage, at a lower price point than 3.5 Flash.
* **Gemini 3.5 Flash-Lite**: The fastest, lowest-cost model in the 3.5 family. Outperforms prior Flash-Lite generations for high-throughput execution.

This guide explains what was introduced in each model, what API changes affect
your code, and how to migrate.

{% callout type="note" %}
  You can automate this migration with a coding agent that supports [skills](/docs/coding-agents#gemini-api-dev) (like Antigravity).

{% /callout %}

{% tabs %}
  {% tab title="Gemini 3.6 Flash" %}
  1.   Install the skill:

  ```bash
  npx skills add google-gemini/gemini-skills --skill gemini-interactions-api --global
  ```

  2.   Apply the skill:

  ```bash
  /gemini-interactions-api migrate my app to Gemini 3.6 Flash
  ```

  {% /tab %}

  {% tab title="Gemini 3.5 Flash-Lite" %}
  1.   Install the skill:

  ```bash
  npx skills add google-gemini/gemini-skills --skill gemini-interactions-api --global
  ```

  2.   Apply the skill:

  ```bash
  /gemini-interactions-api migrate my app to Gemini 3.5 Flash-Lite
  ```

  {% /tab %}

{% /tabs %}

## New models  {% id="new-models" %}

| Model | Model ID | Default thinking level | Pricing | Description |
| :--- | :--- | :---: | --- | :--- |
| Gemini 3.6 Flash | `gemini-3.6-flash` | `medium` | $1.50/1M input tokens and $7.50/1M output tokens | Balances speed with intelligence for agentic and multimodal tasks. |
| Gemini 3.5 Flash-Lite | `gemini-3.5-flash-lite` | `minimal` | $0.30/1M input tokens and $2.50/1M output tokens | The fastest, lowest-cost 3.5 model for high-throughput execution. |

Both models support the 1M token context window, 64k max output tokens, thinking, and the full suite of built-in tools including [Computer Use](/docs/computer-use).

For complete specs, see the model pages:

* [Gemini 3.6 Flash model page](/docs/models/gemini-3.6-flash)
* [Gemini 3.5 Flash-Lite model page](/docs/models/gemini-3.5-flash-lite)

For detailed pricing, see the [pricing page](/docs/pricing).

## Quickstart  {% id="quickstart" %}

{% tabs %}
  {% tab label="Python" %}
  ```python
  from google import genai
  
  client = genai.Client()
  
  interaction = client.interactions.create(
      model="gemini-3.6-flash",
      input="Write a three.js script that renders an interactive 3D robot."
  )
  
  print(interaction.output_text)
  ```

  {% /tab %}

  {% tab label="JavaScript" %}
  ```javascript
  import { GoogleGenAI } from "@google/genai";
  
  const ai = new GoogleGenAI({});
  
  async function main() {
    const interaction = await ai.interactions.create({
      model: "gemini-3.6-flash",
      input: "Write a three.js script that renders an interactive 3D robot.",
    });
    console.log(interaction.output_text);
  }
  
  await main();
  ```

  {% /tab %}

  {% tab label="REST" %}
  ```bash
  curl "https://generativelanguage.googleapis.com/v1beta/interactions"   -H "x-goog-api-key: $GEMINI_API_KEY"   -H 'Content-Type: application/json'   -X POST   -d '{
      "model": "gemini-3.6-flash",
      "input": {
        "parts": [{"text": "Write a three.js script that renders an interactive 3D robot."}]
      }
    }'
  ```

  {% /tab %}

{% /tabs %}

## What's new in Gemini 3.6 Flash  {% id="whats-new-gemini-3-6-flash" %}

* **Token and turn reduction:** Completes multi-step workflows with fewer reasoning steps, conversational turns, and tool calls than Gemini 3.5. It also reduces execution loop spiraling.
* **Improved code generation:** Produces higher quality production-ready code with fewer unwanted edits and fewer debugging loops.
* **Better instruction following**: Reduces unwanted file changes during diagnostic tasks.
* **Strong multimodal and spatial reasoning:** Improved performance on chart interpretation, visual blueprint conversion, and multi-element web layout generation.
* **Upfront programmatic inspection:** Prefers running diagnostic code scripts before making changes more frequently than Gemini 3.5 Flash. This improves accuracy on complex tasks, but can add extra exploratory steps on routine frontend work.
* **Computer Use support:** Supported as a built-in tool for agentic UI automation.
* **UI styling preference**: Better at creating functional code, though human evaluators preferred earlier models for visual layout and styling. You can mitigate this by providing explicit design guidelines.
* **Default thinking effort (medium):** Uses the same `medium` default thinking level as Gemini 3.5 Flash.
* **Reduced pricing**: Lower output token costs ($7.50/1M versus $9.00/1M for 3.5 Flash). Input tokens remain at $1.50/1M.

## What's new in Gemini 3.5 Flash-Lite  {% id="whats-new-gemini-3-5-flash-lite" %}

* **Reduced task execution latency:** Highest throughput in the 3.5 family for high-volume data parsing and document extraction.
* **Enhanced reasoning and multimodal performance:** Strong migration path from Gemini 2.5 Flash, with higher scores on reasoning tasks like HLE (18.0% versus 11.0%) and multimodal benchmarks like CharXIV (74.5% versus 63.7%).
* **Subagent orchestration and tool reliability:** Improves tool execution reliability for code execution, search, and MCP workflows. Increase the thinking level for autonomous planning and complex subagent tasks.
* **Improved document understanding:** Improves accuracy on document parsing and structured data extraction. Experiment with both minimal and high thinking levels depending on document complexity.
* **Interactive web coding and tabular data processing:** Performs strongly on frontend JavaScript and tabular data processing by planning using lightweight code execution.
* **Chatbot and persona persistence:** Stronger multi-turn instruction following and persona consistency over Gemini 3.1 Flash-Lite.
* **Computer Use support:** Supported as a built-in tool for agentic UI automation.

## Choosing the right Flash or Flash-Lite model  {% id="choosing-the-right-flash-model" %}

Use this table to select the right model and migration path for your workloads.

Both models require removing deprecated sampling parameters (`temperature`, `top_p`, `top_k`) and prefilled model turns. See [API changes](/docs/whats-new-gemini-3.6#api-changes-and-parameter-updates) for details.

| Model | Primary use cases | Recommended migration target |
| :--- | :--- | :--- |
| **Gemini 3.6 Flash** (`gemini-3.6-flash`) | Code generation, spatial/multimodal reasoning, multi-step agentic workflows | **Gemini 3.5 Flash**, **Gemini 3 Flash (Preview)**, or **Gemini 3.1 Pro** |
| **Gemini 3.5 Flash-Lite** (`gemini-3.5-flash-lite`) | Autonomous subagent execution, high-volume data analysis and document extraction, structured JSON parsing | **Gemini 3.1 Flash-Lite** or **Gemini 2.5 Flash** |

## Antigravity agent support  {% id="updated-antigravity-agent" %}

Gemini 3.6 Flash introduced support for the [Antigravity agent](/docs/antigravity-agent) in Gemini Managed Agents.

For current code samples and the latest default agent configuration, see the [Antigravity agent guide](/docs/antigravity-agent) and the [Gemini 3.8 Flash guide](/docs/whats-new-gemini-3.8#updated-antigravity-agent).

## API changes and parameter updates  {% id="api-changes-and-parameter-updates" %}

Starting with Gemini 3.6 Flash and Gemini 3.5 Flash-Lite, the following API changes apply to these models and all future Gemini model releases.

* **Sampling parameter deprecation**: `temperature`, `top_p`, and `top_k` are deprecated. The API ignores these parameters and returns an error in future model generations.
* **Prefilled model turn validation**: Prefilling model turns is no longer supported. If the last non-empty turn in the request is a `model` turn, the API returns a `400` error.

The following sections provide detailed explanations and code samples for each API change.

### 1. Sampling parameter deprecation (temperature, top_p, top_k)  {% id="sampling-parameter-deprecation" %}

`temperature`, `top_p`, and `top_k` are deprecated and ignored. In future model generations, supplying these parameters returns an HTTP 400 error. **Remove these parameters from all requests.**

```python
# ⚠️ Remove these parameters (deprecated)
generation_config = {
     "temperature": 0.7,
     "top_p": 0.9,
     "top_k": 40,
}
```

To improve determinism, define a system instruction with explicit rules for your
specific use case.

### 2. Prefilled model turn validation  {% id="prefilled-model-turn-validation" %}

API requests ending with a non-empty model role turn are disallowed and return an **HTTP 400 Error**.

#### ⚠️ Avoid  {% id="prefill-avoid" %}

In legacy `generateContent` or raw REST payloads, ending with a model role turn
is now disallowed:

```json
/* ❌ DO NOT: End payload contents with a 'model' role turn */
{
  "contents": [
    {"role": "user", "parts": [{"text": "Translate 'Hello world' to Spanish."}]},
    {"role": "model", "parts": [{"text": "Translation:"}]}  /* ❌ Returns error */
  ]
}
```

#### ✅ Recommended Migration (Interactions API)  {% id="prefill-recommended-migration" %}

In the Interactions API, model turns are not manually prefilled. If your application previously prefilled a model turn to suppress preambles or force JSON formatting, use system_instruction or [Structured outputs](/docs/structured-output) instead.

```python
# ✅ RECOMMENDED: Use system_instruction in the Interactions API to specify output format
interaction = client.interactions.create(
    model="gemini-3.6-flash",
    input="Translate 'Hello world' to Spanish.",
    system_instruction="Output only the translation without introductory text.",
)
```

## Migration checklist  {% id="migration-checklist" %}

{% callout type="note" %}
  You can automate this migration with a coding agent that supports [skills](/docs/coding-agents#gemini-api-dev) (like Antigravity).

{% /callout %}

{% tabs %}
  {% tab title="Gemini 3.6 Flash" %}
  1.   Install the skill:

  ```bash
  npx skills add google-gemini/gemini-skills --skill gemini-interactions-api --global
  ```

  2.   Apply the skill:

  ```bash
  /gemini-interactions-api migrate my app to Gemini 3.6 Flash
  ```

  {% /tab %}

  {% tab title="Gemini 3.5 Flash-Lite" %}
  1.   Install the skill:

  ```bash
  npx skills add google-gemini/gemini-skills --skill gemini-interactions-api --global
  ```

  2.   Apply the skill:

  ```bash
  /gemini-interactions-api migrate my app to Gemini 3.5 Flash-Lite
  ```

  {% /tab %}

{% /tabs %}

### Migrate to gemini-3.6-flash  {% id="migrate-to-gemini-3-6-flash" %}

* **Update Model ID:** Change your target model string to `gemini-3.6-flash`.
* **Apply parameter updates:** Remove deprecated sampling parameters (`temperature`, `top_p`, `top_k`), `candidate_count` (unsupported in Gemini 3 and later), and prefilled model turns as detailed in [API changes and parameter updates](/docs/whats-new-gemini-3.6#api-changes-and-parameter-updates).
* **Configure thinking level:** Replace `thinking_budget` with `thinking_level` (`"medium"` or `"high"`).
* **Audit function calling:**  * Place multimodal assets inside the response payload.
  * Format inline instructions using `\n\n`.
  * If you see `Malformed_Function_Call` errors tied to pre-tool text, see [Workarounds for pre-tool text requirements](/docs/function-calling#workarounds-for-pre-tool-text-requirements).

*   **Baseline Gemini 3.x requirements:** For SDK updates and thought signature
  preservation, see [Thought signatures](/docs/thinking#signatures).

### Migrate to gemini-3.5-flash-lite  {% id="migrate-to-gemini-3-5-flash-lite" %}

* **Update Model ID:** Change your target model string to `gemini-3.5-flash-lite`.
* **Configure thinking effort level:**  * For high-volume extraction, routing, or classification: leave `thinking_level` at `"minimal"` (default) for maximum throughput.
  * For autonomous subagents with tool calls, code execution, or multi-step reasoning: set `thinking_level` to `"medium"` or `"high"` to prevent premature tool termination.

* **Remove deprecated parameters and validate function calling:** Apply the [same rules as 3.6 Flash](/docs/whats-new-gemini-3.6#migrate-to-gemini-3-6-flash).
*   **Baseline Gemini 3.x requirements:** Refer to
  [Thought signatures](/docs/thinking#signatures).

## Other models  {% id="other-models" %}

*   [Latest Gemini models](/docs/latest-model)
*   [Gemini 4 Hydrogen](/docs/whats-new-gemini-4-hydrogen)
*   [Gemini 4 Carbon](/docs/whats-new-gemini-4-carbon)
*   [Gemini 4 Argon](/docs/whats-new-gemini-4-argon)
*   [Gemini 3.8 Flash](/docs/whats-new-gemini-3.8)
*   [See all models](/docs/models)

## What's next  {% id="whats-next" %}

* Review API specs on the [Models Overview](/docs/models).
* Explore multi-agent orchestration in the [Interactions API Guide](/docs/interactions-overview).
* Test and refine prompts in [Google AI Studio](https://aistudio.google.com/).