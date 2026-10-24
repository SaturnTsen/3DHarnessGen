Run JavaScript code to orchestrate/compose tool calls
- Evaluates the provided JavaScript code in a fresh V8 isolate as an async module.
- All nested tools are available on the global `tools` object, for example `await tools.exec_command(...)`. Tool names are exposed as normalized JavaScript identifiers, for example `await tools.mcp__ologs__get_profile(...)`.
- Nested tool methods take either a string or an object as their input argument.
- Nested tools return either an object or a string, based on the description.
- Runs raw JavaScript -- no Node, no file system, no network access, no console.
- Accepts raw JavaScript source text, not JSON, quoted strings, or markdown code fences.
- You may optionally start the tool input with a first-line pragma like `// @exec: {"yield_time_ms": 10000, "max_output_tokens": 1000}`.
- `yield_time_ms` asks `exec` to yield early if the script is still running. Defaults to 30000 ms.
- `max_output_tokens` sets the token budget for direct `exec` results. Defaults to 10000 tokens.
- When the JS code is fully evaluated, the isolate's lifetime ends and unawaited promises are silently discarded.

- Global helpers:
- `exit()`: Immediately ends the current script successfully (like an early return from the top level).
- `text(value: string | number | boolean | undefined | null)`: Appends a text item. Non-string values are stringified with `JSON.stringify(...)` when possible.
- `image(imageUrlOrItem: string | { image_url: string; detail?: "auto" | "low" | "high" | "original" | null } | ImageContent, detail?: "auto" | "low" | "high" | "original" | null)`: Appends an image item. `image_url` should be a base64-encoded `data:` URL. To forward an MCP tool image, pass an individual `ImageContent` block from `result.content`, for example `image(result.content[0])`. MCP image blocks may request detail with `_meta: { "codex/imageDetail": "original" }`. When provided, the second `detail` argument overrides any detail embedded in the first argument.
- `audio(audioUrlOrItem: string | { audio_url: string } | AudioContent)`: Appends an audio item. `audio_url` should be a base64-encoded `data:` URL. To forward an MCP tool audio block, pass an individual `AudioContent` block from `result.content`, for example `audio(result.content[0])`.
- `generatedImage(result: { image_url: string; output_hint?: string })`: Appends an image-generation result and its optional output hint. HTTP(S) URLs are not supported.
- `store(key: string, value: any)`: stores a serializable value under a string key for later `exec` calls in the same session.
- `load(key: string)`: returns the stored value for a string key, or `undefined` if it is missing.
- `notify(value: string | number | boolean | undefined | null)`: immediately injects an extra `custom_tool_call_output` for the current `exec` call. Values are stringified like `text(...)`.
- `setTimeout(callback: () => void, delayMs?: number)`: schedules a callback to run later and returns a timeout id. Pending timeouts do not keep `exec` alive by themselves; await an explicit promise if you need to wait for one.
- `clearTimeout(timeoutId?: number)`: cancels a timeout created by `setTimeout`.
- `ALL_TOOLS`: metadata for the enabled nested tools as `{ name, description }` entries.
- `yield_control()`: yields the accumulated output to the model immediately while the script keeps running.

Some deferred nested tools may be omitted from this description. They are still available on the global `tools` object and listed in `ALL_TOOLS`.
To find one, filter `ALL_TOOLS` by `name` and `description`.

Tool availability can change between calls.

Shared MCP Types:
```ts
type Role = "user" | "assistant";
type MetaObject = Record<string, unknown>;
type Annotations = {
  audience?: Role[];
  priority?: number;
  lastModified?: string;
};
type Icon = {
  src: string;
  mimeType?: string;
  sizes?: string[];
  theme?: "light" | "dark";
};
type TextResourceContents = {
  uri: string;
  mimeType?: string;
  _meta?: MetaObject;
  text: string;
};
type BlobResourceContents = {
  uri: string;
  mimeType?: string;
  _meta?: MetaObject;
  blob: string;
};
type TextContent = {
  type: "text";
  text: string;
  annotations?: Annotations;
  _meta?: MetaObject;
};
type ImageContent = {
  type: "image";
  data: string;
  mimeType: string;
  annotations?: Annotations;
  _meta?: MetaObject;
};
type AudioContent = {
  type: "audio";
  data: string;
  mimeType: string;
  annotations?: Annotations;
  _meta?: MetaObject;
};
type ResourceLink = {
  icons?: Icon[];
  name: string;
  title?: string;
  uri: string;
  description?: string;
  mimeType?: string;
  annotations?: Annotations;
  size?: number;
  _meta?: MetaObject;
  type: "resource_link";
};
type EmbeddedResource = {
  type: "resource";
  resource: TextResourceContents | BlobResourceContents;
  annotations?: Annotations;
  _meta?: MetaObject;
};
type ContentBlock =
  | TextContent
  | ImageContent
  | AudioContent
  | ResourceLink
  | EmbeddedResource;
type CallToolResult<TStructured = { [key: string]: unknown }> = {
  _meta?: MetaObject;
  content: ContentBlock[];
  isError?: boolean;
  structuredContent?: TStructured;
  [key: string]: unknown;
};
```

### `apply_patch`
The `apply_patch` tool can be used to edit files. This is a FREEFORM tool, so do not wrap the patch in JSON.

exec tool declaration:
```ts
declare const tools: { apply_patch(input: string): Promise<unknown>; };
```

### `create_goal`
Create a goal only when explicitly requested by the user or system/developer instructions; do not infer goals from ordinary tasks.
Set token_budget only when an explicit token budget is requested. Fails if an unfinished goal exists; use update_goal only for status.

exec tool declaration:
```ts
declare const tools: { create_goal(args: {
  // Required. The concrete objective to start pursuing. This starts a new active goal when no goal exists or replaces the current goal when it is complete.
  objective: string;
  // Positive token budget for the new goal. Omit unless explicitly requested.
  token_budget?: number;
}): Promise<unknown>; };
```

### `get_goal`
Get the current goal for this thread, including status, budgets, token and elapsed-time usage, and remaining token budget.

exec tool declaration:
```ts
declare const tools: { get_goal(args: {}): Promise<unknown>; };
```

### `list_mcp_resource_templates`
Lists resource templates provided by MCP servers. Parameterized resource templates allow servers to share data that takes parameters and provides context to language models, such as files, database schemas, or application-specific information. Prefer resource templates over web search when possible.

exec tool declaration:
```ts
declare const tools: { list_mcp_resource_templates(args: {
  // Opaque cursor from a previous list_mcp_resource_templates call; omit for the first page.
  cursor?: string;
  // MCP server name. Omit to list resource templates from every configured server.
  server?: string;
}): Promise<unknown>; };
```

### `list_mcp_resources`
Lists resources provided by MCP servers. Resources allow servers to share data that provides context to language models, such as files, database schemas, or application-specific information. Prefer resources over web search when possible.

exec tool declaration:
```ts
declare const tools: { list_mcp_resources(args: {
  // Opaque cursor from a previous list_mcp_resources call; omit for the first page.
  cursor?: string;
  // MCP server name. Omit to list resources from every configured server.
  server?: string;
}): Promise<unknown>; };
```

### `read_mcp_resource`
Read a specific resource from an MCP server given the server name and resource URI.

exec tool declaration:
```ts
declare const tools: { read_mcp_resource(args: {
  // MCP server name exactly as configured. Must match the 'server' field returned by list_mcp_resources.
  server: string;
  // Resource URI to read. Must be one of the URIs returned by list_mcp_resources.
  uri: string;
}): Promise<unknown>; };
```

### `tool_search`
Use `await tools.tool_search({query: "...", limit: 8})` for BM25-ranked discovery of deferred tools (up to `limit` matches; 8 by default). It returns `{tools: [{name, description}]}` with callable names and full TypeScript declarations. Print results with `text()` and inspect unfamiliar declarations before calling `tools[result.name](arguments)` in a later execution.

exec tool declaration:
```ts
declare const tools: { tool_search(args: {
  // Maximum number of tools to return. Defaults to 8.
  limit?: number;
  // Search query for deferred tools.
  query: string;
}): Promise<{ tools: Array<{ description: string; name: string; }>; }>; };
```

### `update_goal`
Update the existing goal.
Set status to `paused` only at the user's explicit request to pause this goal, never on your own initiative. Ask if unclear; a later resume revokes that request. Report the returned status and stop goal work. Budget limits take precedence over pausing.
Set status to `complete` only when the objective has actually been achieved and no required work remains.
Set status to `blocked` only when the same blocking condition has repeated for at least three consecutive goal turns, counting the original/user-triggered turn and any automatic continuations, and the agent cannot make meaningful progress without user input or an external-state change.
If the user resumes a goal that was previously marked `blocked`, treat the resumed run as a fresh blocked audit. If the same blocking condition then repeats for at least three consecutive resumed goal turns, set status to `blocked` again.
Once the blocked threshold is satisfied, do not keep reporting that you are still blocked while leaving the goal active; set status to `blocked`.
Do not use `blocked` merely because the work is hard, slow, uncertain, incomplete, or would benefit from clarification.
Do not mark a goal complete merely because its budget is nearly exhausted or because you are stopping work.
You cannot use this tool to resume, budget-limit, or usage-limit a goal; those status changes are controlled by the user or system.
When marking a budgeted goal achieved with status `complete`, report the final token usage from the tool result to the user.

exec tool declaration:
```ts
declare const tools: { update_goal(args: {
  // Required. `paused` requires an explicit user request. Set to `complete` only when the objective is achieved and no required work remains. Set to `blocked` only after the same blocking condition has recurred for at least three consecutive goal turns and the agent is at an impasse. After a previously blocked goal is resumed, the resumed run starts a fresh blocked audit.
  status: "complete" | "blocked" | "paused";
}): Promise<unknown>; };
```

### `view_image`
View a local image file from the filesystem when visual inspection is needed. Use this for images already available on disk.

exec tool declaration:
```ts
declare const tools: { view_image(args: {
  // Image detail level. Defaults to `high`; use `original` to preserve exact resolution.
  detail?: "high" | "original";
  // Local filesystem path to an image file.
  path: string;
}): Promise<{
  // Image detail hint returned by view_image. Returns `high` for default resized behavior or `original` when original resolution is preserved.
  detail: "high" | "original";
  // Data URL for the loaded image.
  image_url: string;
}>; };
```

## clock
Tools for reading and waiting on time.

### `clock__curr_time`
Return the current time in UTC.

exec tool declaration:
```ts
declare const tools: { clock__curr_time(args: {}): Promise<{
  // Current UTC time formatted as YYYY-MM-DD HH:MM:SS UTC.
  current_time: string;
}>; };
```

## image_gen
Tools in the image_gen namespace.

### `image_gen__imagegen`
The `image_gen.imagegen` tool enables image generation from descriptions and editing of existing images based on specific instructions. Use it when:

- The user requests an image based on a scene description, such as a diagram, portrait, comic, meme, or any other visual.
- The user wants to modify an attached or previously generated image with specific changes, including adding or removing elements, altering colors, improving quality/resolution, or transforming the style (e.g., cartoon, oil painting).

Guidelines:
- imagegen needs a few minutes to finish. In code-mode, use the first-line @exec directive to give the initial call 120 seconds and the same yield for any waits that follow. Once it finishes, return the image with generatedImage(result).
- Avoid printing the full result or its base64 image data with `text()` or `notify()`; print only small metadata when needed.
- Set `transparent_background` to true when the request calls for a transparent background, including background removal or a cutout; set it to false otherwise. For edits, preserve existing transparency unless the user asks to change it.
- Omit both `referenced_image_paths` and `num_last_images_to_include` when generating a brand new image.
- For edits, use `referenced_image_paths` when every target image has a local file path.
- If you have not seen a local image yet, use `view_image` to inspect it before editing.
- Use `num_last_images_to_include` only when at least one target image has no local file path.
- Set `num_last_images_to_include` to the smallest number of recent conversation images that includes every target image, up to 5.
- Never provide both `referenced_image_paths` and `num_last_images_to_include`.
- If neither mechanism can include every target image, ask the user to attach the missing images again.
- Directly generate the image without reconfirmation or clarification unless required images must be attached again.
- Always use this tool for image editing unless the user explicitly requests otherwise. Do not use the `python` tool for image editing unless specifically instructed.


exec tool declaration:
```ts
declare const tools: { image_gen__imagegen(args: {
  num_last_images_to_include?: number | null;
  prompt: string;
  referenced_image_paths?: Array<string> | null;
  // Whether the output should have a transparent background. Defaults to false.
  transparent_background?: boolean;
}): Promise<unknown>; };
```

## web
Tools in the web namespace.

### `web__run`
Tool for accessing the internet.


---

## Examples of different commands available in this tool

Examples of different commands available in this tool:
* `search_query`: {"search_query": [{"q": "What is the capital of France?"}, {"q": "What is the capital of belgium?"}]}. Searches the internet for a given query (and optionally with a domain or recency filter)
* `image_query`: {"image_query":[{"q": "waterfalls"}]}.
* `open`: {"open": [{"ref_id": "turn0search0"}, {"ref_id": "https://www.openai.com", "lineno": 120}]}
* `click`: {"click": [{"ref_id": "turn0fetch3", "id": 17}]}
* `find`: {"find": [{"ref_id": "turn0fetch3", "pattern": "Annie Case"}]}
* `screenshot`: {"screenshot": [{"ref_id": "turn1view0", "pageno": 0}, {"ref_id": "turn1view0", "pageno": 3}]}
* `finance`: {"finance":[{"ticker":"AMD","type":"equity","market":"USA"}]}, {"finance":[{"ticker":"BTC","type":"crypto","market":""}]}
* `weather`: {"weather":[{"location":"San Francisco, CA"}]}
* `sports`: {"sports":[{"fn":"standings","league":"nfl"}, {"fn":"schedule","league":"nba","team":"GSW","date_from":"2025-02-24"}]}
* `time`: {"time":[{"utc_offset":"+03:00"}]}

---

## Usage hints
To use this tool efficiently:
* Use multiple commands and queries in one call to get more results faster; e.g. {"search_query": [{"q": "bitcoin news"}], "finance":[{"ticker":"BTC","type":"crypto","market":""}], "find": [{"ref_id": "turn0search0", "pattern": "Annie Case"}, {"ref_id": "turn0search1", "pattern": "John Smith"}]}
* Use "response_length" to control the number of results returned by this tool, omit it if you intend to pass "short" in
* Only write required parameters; do not write empty lists or nulls where they could be omitted.
* `search_query` must have length at most 4 in each call. If it has length > 3, response_length must be medium or long
* If you find yourself in a situation where you accidentally call the `web.run` tool, it's best just to send an empty query: {"search_query": [{"q": ""}]}.

---

## Decision boundary

If the user makes an explicit request to search the internet, find latest information, look up, etc (or to not do so), you must obey their request.
When you make an assumption, always consider whether it is temporally stable; i.e. whether there's even a small (>10%) chance it has changed. If it is unstable, you must verify with browsing the internet for verification.

<situations_where_you_must_browse_the_internet>
Below is a list of scenarios where browsing the internet MUST be used. PAY CLOSE ATTENTION: you MUST browse the internet in these cases. If you're unsure or on the fence, you MUST bias towards browsing the internet.
- The information could have changed recently: for example news; prices; laws; schedules; product specs; sports scores; economic indicators; political/public/company figures (e.g. the question relates to 'the president of country A' or 'the CEO of company B', which might change over time); rules; regulations; standards; software libraries that could be updated; exchange rates; recommendations (i.e., recommendations about various topics or things might be informed by what currently exists / is popular / is safe / is unsafe / is in the zeitgeist / etc.); and many many many more categories -- again, if you're on the fence, you MUST browse the internet!
  - For news queries, prioritize more recent events, ensuring you compare publish dates and the date that the event happened.
- The user is seeking recommendations that could lead them to spend substantial time or money -- researching products, restaurants, travel plans, etc.
- The user wants (or would benefit from) direct quotes, links, or precise source attribution.
- A specific page, paper, dataset, PDF, or site is referenced and you haven't been given its contents.
- You're unsure about a fact, the topic is niche or emerging, or you suspect there's at least a 10% chance you will incorrectly recall it
- High-stakes accuracy matters (medical, legal, financial guidance). For these you generally should search by default because this information is highly temporally unstable
- The user explicitly says to search, browse, verify, or look it up.
</situations_where_you_must_browse_the_internet>

---

## Citations

Results from `web.run` include internal reference IDs such as `turn2search5`. Use
those reference IDs only in calls to `web.run`; do not expose them in the final
response.

Cite sources in the final response using Markdown links:

- Cite a single source as `[descriptive source title](https://example.com/page)`.
- Cite multiple sources with separate Markdown links, for example
  `[first source](https://example.com/one), [second source](https://example.com/two)`.
- Link directly to the page that supports the claim. Do not link to search result
  pages or use bare URLs.

Formatting of citations:

- Place each citation as near as possible to the claim it supports, normally at
  the end of the sentence or paragraph and after punctuation.
- Do not place citations inside code fences.
- Do not put citations on a line by themselves or collect all citations at the
  end of the response.

If you browse the internet, cite statements supported by web sources. Each cited
source must directly support the associated claim. Prefer primary and
authoritative sources, and use sources from different domains when the response
benefits from multiple perspectives.

---

## Special cases
If these conflict with any other instructions, these should take precedence.

<special_cases>
- When the user asks for information about how to use OpenAI products, (ChatGPT, the OpenAI API, etc.), you should check the code in local env and only browse as fallback, when you browse restrict your sources to official OpenAI websites using the domains filter, unless otherwise requested.
- When using search to answer technical questions, you must only rely on primary sources (research papers, official documentation, etc.)
- Clearly indicate when you are making an inference from sources.
</special_cases>

---

## Word limits
Responses may not excessively quote or draw on a specific source. There are several limits here:
- **Limit on verbatim quotes:**
  - You may not quote more than 25 words verbatim from any single non-lyrical source, unless the source is reddit.
  - For song lyrics, verbatim quotes must be limited to at most 10 words.
  - Long quotes from reddit are allowed, as long as you indicate that those are direct quotes via a markdown blockquote starting with ">", copy verbatim, and link the source.
- **Word limits:**
  - Each webpage source in the sources has a word limit label formatted like "[wordlim N]", in which N is the maximum number of words in the whole response that are attributed to that source. If omitted, the word limit is 200 words.
  - Non-contiguous words derived from a given source must be counted to the word limit.
  - The summarization limit N is a maximum for each source.
  - When using multiple sources, their summarization limits add together. However, each article used must be relevant to the response.
- **Copyright compliance:**
  - You must avoid providing full articles, long verbatim passages, or extensive direct quotes due to copyright concerns.
  - If the user asked for a verbatim quote, the response should provide a short compliant excerpt and then answer with paraphrases and summaries.
  - Again, this limit does not apply to reddit content, as long as it's appropriately indicated that those are direct quotes and you link to the source.


exec tool declaration:
```ts
declare const tools: { web__run(args: {
  // Open links from previously opened pages.
  click?: Array<{
  // Numbered link id to open.
  id: number;
  // Reference id containing the numbered link.
  ref_id: string;
}>;
  // Look up prices for the given stock symbols.
  finance?: Array<{
  // ISO 3166-1 alpha-3 country code, "OTC", or "" for cryptocurrency.
  market?: string;
  // Ticker symbol to look up.
  ticker: string;
  // Asset type to look up.
  type: "equity" | "fund" | "crypto" | "index";
}>;
  // Find text patterns in pages.
  find?: Array<{
  // Text pattern to find.
  pattern: string;
  // Reference id or URL to search within.
  ref_id: string;
}>;
  // Query the image search engine for a given list of queries.
  image_query?: Array<{
  // Whether to filter by a specific list of domains.
  domains?: Array<string>;
  // Search query.
  q: string;
  // Whether to filter by recency, as a number of recent days.
  recency?: number;
}>;
  // Open pages by reference id or URL.
  open?: Array<{
  // Line number to position the page at.
  lineno?: number;
  // Reference id or URL to open.
  ref_id: string;
}>;
  // Set the length of the response to be returned.
  response_length?: "short" | "medium" | "long";
  // Take screenshots of PDF pages.
  screenshot?: Array<{
  // Zero-indexed PDF page number.
  pageno: number;
  // Reference id or URL to screenshot.
  ref_id: string;
}>;
  // Query the internet search engine for a given list of queries.
  search_query?: Array<{
  // Whether to filter by a specific list of domains.
  domains?: Array<string>;
  // Search query.
  q: string;
  // Whether to filter by recency, as a number of recent days.
  recency?: number;
}>;
  // Look up sports schedules and standings.
  sports?: Array<{
  // Start date in YYYY-MM-DD format.
  date_from?: string;
  // End date in YYYY-MM-DD format.
  date_to?: string;
  // Sports function to call.
  fn: "schedule" | "standings";
  // League to look up.
  league: "nba" | "wnba" | "nfl" | "nhl" | "mlb" | "epl" | "ncaamb" | "ncaawb" | "ipl";
  // Locale for the lookup.
  locale?: string;
  // Number of games to return.
  num_games?: number;
  // Opponent to use with `team` when narrowing the lookup.
  opponent?: string;
  // Team to look up, using the common 3 or 4 letter alias used in broadcasts.
  team?: string;
  // Tool name for sports requests.
  tool?: "sports";
}>;
  // Get time for the given UTC offsets.
  time?: Array<{
  // UTC offset formatted like "+03:00".
  utc_offset: string;
}>;
  // Look up weather forecasts.
  weather?: Array<{
  // Number of days to return. Defaults to 7.
  duration?: number;
  // Location in "Country, Area, City" format.
  location: string;
  // Start date in YYYY-MM-DD format. Defaults to today.
  start?: string;
}>;
}): Promise<unknown>; };