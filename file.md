//llm.js
// Provider layer. The agent works internally with Anthropic-style messages
// (content blocks: text / tool_use / tool_result). This file sends them to either:
//   - "anthropic": Anthropic Messages API (or any Anthropic-compatible endpoint), or
//   - "openai":    any OpenAI-compatible /chat/completions endpoint with tool calling
//                  (OpenAI, Azure OpenAI, OpenRouter, Together, Groq, vLLM, Ollama, LM Studio, LiteLLM, ...)
// Settings come from chrome.storage.local: provider, baseUrl, apiKey, model, headers (JSON string).

const sleepMs = (ms) => new Promise((r) => setTimeout(r, ms));

function parseExtraHeaders(str) {
  if (!str || !str.trim()) return {};
  try {
    const h = JSON.parse(str);
    if (h && typeof h === "object" && !Array.isArray(h)) return h;
  } catch (e) {}
  throw new Error('"Extra headers" must be a JSON object, e.g. {"api-key": "..."}');
}

// ---- Anthropic-style -> OpenAI-style ----
function toOpenAIMessages(system, messages) {
  const out = [{ role: "system", content: system }];
  for (const m of messages) {
    const blocks = Array.isArray(m.content) ? m.content : [{ type: "text", text: m.content }];
    if (m.role === "assistant") {
      const text = blocks.filter((b) => b.type === "text").map((b) => b.text).join("\n");
      const calls = blocks
        .filter((b) => b.type === "tool_use")
        .map((b) => ({ id: b.id, type: "function", function: { name: b.name, arguments: JSON.stringify(b.input || {}) } }));
      const msg = { role: "assistant", content: text || null };
      if (calls.length) msg.tool_calls = calls;
      out.push(msg);
    } else {
      for (const b of blocks) {
        if (b.type === "tool_result") {
          const c = typeof b.content === "string" ? b.content : JSON.stringify(b.content);
          out.push({ role: "tool", tool_call_id: b.tool_use_id, content: (b.is_error ? "Error: " : "") + c });
        }
      }
      const text = blocks.filter((b) => b.type === "text").map((b) => b.text).join("\n");
      if (text) out.push({ role: "user", content: text });
    }
  }
  return out;
}

const toOpenAITools = (tools) =>
  tools.map((t) => ({ type: "function", function: { name: t.name, description: t.description, parameters: t.input_schema } }));

// ---- OpenAI-style -> Anthropic-style ----
function fromOpenAIResponse(data) {
  const msg = data && data.choices && data.choices[0] && data.choices[0].message;
  if (!msg) throw new Error("Unexpected response from provider: " + JSON.stringify(data).slice(0, 300));
  const content = [];
  if (typeof msg.content === "string" && msg.content.trim()) content.push({ type: "text", text: msg.content });
  else if (Array.isArray(msg.content)) {
    const t = msg.content.map((p) => p.text || "").join("").trim();
    if (t) content.push({ type: "text", text: t });
  }
  (msg.tool_calls || []).forEach((c, i) => {
    let input = {};
    try { input = JSON.parse(c.function.arguments || "{}"); } catch (e) {}
    content.push({ type: "tool_use", id: c.id || "call_" + Date.now() + "_" + i, name: c.function.name, input });
  });
  return { content };
}

// ---- Custom provider: user-defined request template + response path, prompt-based tool use ----
const DEFAULT_CUSTOM_TEMPLATE = '{"model":"{{model}}","messages":"{{messages}}","max_tokens":"{{max_tokens}}","stream":false}';

function fillString(str, vars) {
  return String(str).replace(/\{\{(\w+)\}\}/g, (m, k) => {
    if (!(k in vars)) return m;
    const v = vars[k];
    return typeof v === "string" || typeof v === "number" ? String(v) : JSON.stringify(v);
  });
}

// A string that is exactly "{{name}}" is replaced by the raw value (array / number / string).
function fillTemplate(node, vars) {
  if (typeof node === "string") {
    const m = node.match(/^\{\{(\w+)\}\}$/);
    if (m && m[1] in vars) return vars[m[1]];
    return fillString(node, vars);
  }
  if (Array.isArray(node)) return node.map((n) => fillTemplate(n, vars));
  if (node && typeof node === "object") {
    return Object.fromEntries(Object.entries(node).map(([k, v]) => [k, fillTemplate(v, vars)]));
  }
  return node;
}

const REMINDER =
  '\n\n[Reply format reminder: to perform an action, reply with ONLY a JSON object such as {"tool":"click","input":{"id":12}} - no explanation, no markdown. Do not describe what you plan to do; call the tool. If the task is finished, or you must ask the user something, answer in plain text.]';

function toolPrompt(tools) {
  return (
    "You control the user's browser tab through tools, so you CAN click, type and change settings on the page. Never say you cannot interact with the page and never just explain how the user could do it: do it with a tool.\n" +
    "To use a tool, reply with ONLY one JSON object and nothing else, like:\n" +
    '{"tool": "click", "input": {"id": 12}}\n' +
    '{"tool": "type_text", "input": {"id": 5, "text": "hello"}}\n' +
    "Use exactly one tool per reply, then wait for the result (it includes the updated page). " +
    "When the task is finished, or you need to ask the user something, reply with plain text (no JSON).\n" +
    "Available tools:\n" +
    tools.map((t) => `- ${t.name}: ${t.description} Input schema: ${JSON.stringify(t.input_schema)}`).join("\n")
  );
}

function toPlainMessages(messages) {
  return messages.map((m) => {
    const blocks = Array.isArray(m.content) ? m.content : [{ type: "text", text: m.content }];
    const parts = [];
    for (const b of blocks) {
      if (b.type === "text") parts.push(b.text);
      else if (b.type === "tool_use") parts.push(JSON.stringify({ tool: b.name, input: b.input || {} }));
      else if (b.type === "tool_result") {
        const c = typeof b.content === "string" ? b.content : JSON.stringify(b.content);
        parts.push("Tool result" + (b.is_error ? " (error)" : "") + ":\n" + c);
      }
    }
    return { role: m.role, content: parts.join("\n\n") };
  });
}

function flattenPrompt(system, chat) {
  const label = { user: "User", assistant: "Assistant" };
  return system + "\n\n" + chat.map((m) => `${label[m.role] || m.role}: ${m.content}`).join("\n\n") + "\n\nAssistant:";
}

function getByPath(obj, path) {
  return path
    .replace(/\[(\d+)\]/g, ".$1")
    .split(".")
    .filter(Boolean)
    .reduce((o, k) => (o == null ? o : o[k]), obj);
}

// Turn a value into text: string, or an array of parts like [{type:"text", text:"..."}].
function asText(v) {
  if (typeof v === "string") return v;
  if (Array.isArray(v)) {
    const t = v.map((p) => (typeof p === "string" ? p : p && typeof p.text === "string" ? p.text : "")).join("");
    return t || null;
  }
  return null;
}

const KNOWN_PATHS = [
  "choices.0.message.content", "choices.0.text", "choices.0.delta.content",
  "message.content", "output.choices.0.message.content", "output.text", "output.output_text",
  "data.choices.0.message.content", "data.output.text", "data.text", "data.content", "data.response", "data.reply", "data.answer", "data.message.content",
  "content.0.text", "content", "output_text", "response", "response.text", "text", "completion",
  "result.response", "result.text", "result.content", "result.output", "result.answer", "result",
  "candidates.0.content.parts.0.text", "generated_text", "0.generated_text", "outputs.0.text", "results.0.text", "results.0.generated_text",
  "answer", "reply", "output", "message", "data",
];
const STREAM_PATHS = [
  "choices.0.delta.content", "choices.0.message.content", "choices.0.text", "message.content", "response",
  "delta.text", "output.text", "output.choices.0.message.content", "text", "content", "token.text", "candidates.0.content.parts.0.text",
];
const SKIP_KEYS = /^(id|model|object|role|type|created|created_at|finish_reason|done|done_reason|usage|index|name|status|code|logprobs|system_fingerprint|reasoning_content|reasoning|thinking|request_id|task_id|error|tool_calls)$/i;

function findLongestString(node, path, depth, best) {
  if (depth > 7 || node == null) return best;
  if (typeof node === "string") {
    if (node.trim() && (!best || node.length > best.text.length)) return { text: node, path };
    return best;
  }
  if (Array.isArray(node)) {
    node.forEach((v, i) => { best = findLongestString(v, path ? path + "." + i : String(i), depth + 1, best); });
    return best;
  }
  if (typeof node === "object") {
    for (const [k, v] of Object.entries(node)) {
      if (SKIP_KEYS.test(k)) continue;
      best = findLongestString(v, path ? path + "." + k : k, depth + 1, best);
    }
  }
  return best;
}

function extractFromObject(d, paths) {
  for (const p of paths) {
    const v = asText(getByPath(d, p));
    if (v && v.trim()) return { text: v, path: p };
  }
  return null;
}

// Streamed replies: Server-Sent Events ("data: {...}") or newline-delimited JSON (Ollama default).
function extractFromStream(str, userPath) {
  let acc = "", parsed = 0, path = null;
  for (let line of str.split(/\r?\n/)) {
    line = line.trim().replace(/^data:\s*/, "");
    if (!line || line === "[DONE]") continue;
    let o;
    try { o = JSON.parse(line); } catch (e) { continue; }
    parsed++;
    const paths = userPath ? [userPath, ...STREAM_PATHS] : STREAM_PATHS;
    for (const p of paths) {
      const v = asText(getByPath(o, p));
      if (v != null) { acc += v; path = path || p; break; }
    }
  }
  return parsed > 0 && acc.trim() ? { text: acc, path: (path || "") + "  (streamed reply)" } : null;
}

// Find the reply text. Uses the configured path first, then auto-detects.
function locateReply(data, userPath) {
  const up = userPath && userPath.trim();
  let note = "";
  if (typeof data === "string") {
    const st = extractFromStream(data, up);
    if (st) return { ...st, note };
    if (data.trim()) return { text: data, path: "(plain-text response)", note };
    throw new Error("The provider returned an empty response.");
  }
  if (up) {
    const v = asText(getByPath(data, up));
    if (v != null) return { text: v, path: up, note };
    note = `your path "${up}" matched nothing in the response, so it was auto-detected instead`;
  }
  const known = extractFromObject(data, KNOWN_PATHS);
  if (known) return { ...known, note };
  const guess = findLongestString(data, "", 0, null);
  if (guess) return { ...guess, note: (note ? note + "; " : "") + "guessed the longest text field - set it explicitly in Response text path if this is wrong" };
  throw new Error('Could not find any reply text in the response. Set "Response text path" in Settings. Response was: ' + JSON.stringify(data).slice(0, 600));
}

function stripThinking(t) {
  const noBlocks = t.replace(/<think(?:ing)?>[\s\S]*?<\/think(?:ing)?>/gi, "");
  const afterClose = noBlocks.replace(/^[\s\S]*<\/think(?:ing)?>/i, ""); // unmatched closing tag
  return (afterClose.trim() || noBlocks.trim() || t.trim());
}

// Tolerant parser for "JSON-ish" text that small models produce: unquoted keys, single quotes,
// trailing commas, bare words, True/False/None. Throws if the text is not fully consumed.
function relaxedParse(src) {
  let i = 0;
  const ws = () => { while (i < src.length && /\s/.test(src[i])) i++; };
  const fail = () => { throw new Error("bad json-ish"); };
  const ESC = { n: "\n", t: "\t", r: "\r", b: "\b", f: "\f" };
  function str() {
    const q = src[i++];
    let out = "";
    while (i < src.length) {
      const c = src[i++];
      if (c === q) return out;
      if (c === "\\") {
        const n = src[i++];
        if (n === "u") { out += String.fromCharCode(parseInt(src.slice(i, i + 4), 16)); i += 4; }
        else out += ESC[n] !== undefined ? ESC[n] : n;
      } else out += c;
    }
    return fail();
  }
  function key() {
    ws();
    if (src[i] === '"' || src[i] === "'") return str();
    const m = /^[A-Za-z_$][\w$-]*/.exec(src.slice(i));
    if (!m) fail();
    i += m[0].length;
    return m[0];
  }
  function value() {
    ws();
    const c = src[i];
    if (c === "{") return obj();
    if (c === "[") return arr();
    if (c === '"' || c === "'") return str();
    const n = /^-?\d+(\.\d+)?([eE][+-]?\d+)?/.exec(src.slice(i));
    if (n) { i += n[0].length; return parseFloat(n[0]); }
    const w = /^[A-Za-z_$][\w$]*/.exec(src.slice(i));
    if (w) {
      i += w[0].length;
      const l = w[0].toLowerCase();
      if (l === "true") return true;
      if (l === "false") return false;
      if (l === "null" || l === "none" || l === "undefined") return null;
      return w[0];
    }
    return fail();
  }
  function obj() {
    i++;
    const o = {};
    ws();
    if (src[i] === "}") { i++; return o; }
    for (;;) {
      const k = key();
      ws();
      if (src[i++] !== ":") fail();
      o[k] = value();
      ws();
      if (src[i] === ",") { i++; ws(); if (src[i] === "}") { i++; return o; } continue; }
      if (src[i] === "}") { i++; return o; }
      fail();
    }
  }
  function arr() {
    i++;
    const a = [];
    ws();
    if (src[i] === "]") { i++; return a; }
    for (;;) {
      a.push(value());
      ws();
      if (src[i] === ",") { i++; ws(); if (src[i] === "]") { i++; return a; } continue; }
      if (src[i] === "]") { i++; return a; }
      fail();
    }
  }
  const v = value();
  ws();
  if (i < src.length) fail();
  return v;
}

function parseLoose(x) {
  try { return JSON.parse(x); } catch (e) { return relaxedParse(x); }
}

function jsonObjectsIn(text) {
  const out = [];
  // "tool: click, input: {id: 3}" with the outer braces missing
  if (/^\s*["']?(tool|tool_name|name|action)["']?\s*:/i.test(text)) {
    try { return [parseLoose("{" + text.trim().replace(/[,;]\s*$/, "") + "}")]; } catch (e) {}
  }
  for (let i = 0; i < text.length; i++) {
    if (text[i] !== "{") continue;
    let depth = 0, quote = null, esc = false;
    for (let j = i; j < text.length; j++) {
      const c = text[j];
      if (quote) { if (esc) esc = false; else if (c === "\\") esc = true; else if (c === quote) quote = null; continue; }
      if (c === '"' || c === "'") quote = c;
      else if (c === "{") depth++;
      else if (c === "}") {
        depth--;
        if (depth === 0) {
          try { out.push(parseLoose(text.slice(i, j + 1))); i = j; } catch (e) {}
          break;
        }
      }
    }
  }
  return out;
}

function asToolCall(o, tools) {
  if (!o || typeof o !== "object" || Array.isArray(o)) return null;
  const fn = o.function && typeof o.function === "object" ? o.function : null;
  const name = o.tool || o.tool_name || o.name || o.action || (fn && fn.name);
  if (typeof name !== "string") return null;
  const norm = String(name).toLowerCase().replace(/[\s-]+/g, "_");
  const SYN = {
    click: ["click_element", "left_click", "tap", "press", "click_button", "click_on", "click_link", "double_click"],
    type_text: ["type", "input", "input_text", "fill", "fill_in", "fill_input", "enter_text", "write", "set_text", "send_keys", "type_into", "set_value"],
    select_option: ["select", "choose", "choose_option", "select_dropdown", "set_select"],
    scroll: ["scroll_down", "scroll_up", "scroll_page", "page_down", "page_up"],
    press_key: ["key", "keypress", "key_press", "send_key", "hotkey"],
    navigate: ["open_url", "goto", "go_to", "visit", "open", "navigate_to", "load_url", "open_page"],
    wait: ["sleep", "pause", "wait_for"],
    read_page: ["read", "get_text", "get_page", "read_text", "page_text"],
  };
  let t = tools.find((x) => x.name === name) || tools.find((x) => x.name === norm);
  if (!t) { const canon = Object.keys(SYN).find((k) => SYN[k].includes(norm)); if (canon) t = tools.find((x) => x.name === canon); }
  if (!t) return null;
  let input = o.input ?? o.arguments ?? o.args ?? o.parameters ?? o.params ?? (fn && fn.arguments);
  if (typeof input === "string") { try { input = JSON.parse(input); } catch (e) { input = null; } }
  if (!input || typeof input !== "object") {
    input = { ...o };
    ["tool", "tool_name", "name", "action", "function"].forEach((k) => delete input[k]);
  }
  input = { ...input };
  if (input.id == null) {
    const alt = input.element_id ?? input.elementId ?? input.element ?? input.index ?? input.ref ?? input.target;
    if (alt != null) input.id = alt;
  }
  if (typeof input.id === "string") { const m = input.id.match(/\d+/); if (m) input.id = +m[0]; }
  if (t.name === "type_text" && input.text == null) input.text = input.value ?? input.content ?? input.input;
  if (t.name === "select_option" && input.option == null) input.option = input.value ?? input.text;
  if (t.name === "press_key" && input.key == null) input.key = input.value;
  if (t.name === "scroll" && input.direction == null) input.direction = /up/.test(norm) ? "up" : "down";
  return { name: t.name, input };
}

function extractToolCall(text, tools) {
  const cands = [];
  for (const o of jsonObjectsIn(text)) {
    cands.push(o);
    if (Array.isArray(o.tool_calls)) cands.push(...o.tool_calls);
    if (Array.isArray(o.calls)) cands.push(...o.calls);
    if (o.tool_call && typeof o.tool_call === "object") cands.push(o.tool_call);
  }
  for (const c of cands) {
    const tc = asToolCall(c, tools);
    if (tc) return tc;
  }
  return null;
}

const looksLikeBrokenCall = (t) => /["']?\b(tool|tool_name|tool_call|arguments)\b["']?\s*:|<tool_call>|\btool_call\b/i.test(t);

function parseCustomResponse(data, responsePath, tools) {
  const loc = locateReply(data, responsePath);
  let text = loc.text;
  const raw = text;
  if (/<think(?:ing)?>/i.test(text) && !/<\/think(?:ing)?>/i.test(text)) {
    throw new Error(
      "The model ran out of tokens while \"thinking\" and never produced an action. Raise max_tokens in the request template, " +
      "or disable thinking (for Qwen3 put /no_think in Settings > Prompt suffix)."
    );
  }
  text = stripThinking(text);
  if (tools.length) {
    const tc = extractToolCall(text, tools);
    if (tc) {
      return { raw, path: loc.path, note: loc.note, content: [{ type: "tool_use", id: "call_" + Date.now() + "_" + Math.random().toString(36).slice(2, 7), name: tc.name, input: tc.input }] };
    }
  }
  const res = { raw, path: loc.path, note: loc.note, content: [{ type: "text", text }] };
  if (tools.length && looksLikeBrokenCall(text)) {
    res.repairHint =
      'Your last reply was not a valid tool call. Reply with ONLY one JSON object like {"tool":"click","input":{"id":12}} using a tool name from the list and ids from the latest page snapshot. No other text.';
  }
  return res;
}

async function callLLMOnce({ system, tools = [], messages, maxTokens = 1500 }) {
  const s = await chrome.storage.local.get(["provider", "baseUrl", "apiKey", "model", "headers", "bodyTemplate", "responsePath", "promptSuffix"]);
  const provider = s.provider || "anthropic";
  const extra = parseExtraHeaders(s.headers);
  let url, headers, body, parse;

  if (provider === "custom") {
    if (!s.baseUrl) throw new Error("Set the request URL in Settings.");
    let tpl;
    try { tpl = JSON.parse(s.bodyTemplate && s.bodyTemplate.trim() ? s.bodyTemplate : DEFAULT_CUSTOM_TEMPLATE); }
    catch (e) { throw new Error("Request body template must be valid JSON."); }
    const sys = system + (tools.length ? "\n\n" + toolPrompt(tools) : "");
    const chat = toPlainMessages(messages);
    if (tools.length && chat.length && chat[chat.length - 1].role === "user") chat[chat.length - 1].content += REMINDER + (s.promptSuffix ? "\n" + s.promptSuffix : "");
    // If the template never mentions the system prompt, the tool instructions would never reach the model
    // (the usual "tools aren't passed" problem). Fold them into the first user message instead.
    const tplText = JSON.stringify(tpl);
    let msgs = chat;
    if (!/\{\{(system|prompt|chat)\}\}/.test(tplText) && chat.length) {
      msgs = chat.map((m) => ({ ...m }));
      const i = msgs.findIndex((m) => m.role === "user");
      msgs[i < 0 ? 0 : i].content = sys + "\n\n---\n\n" + msgs[i < 0 ? 0 : i].content;
    }
    const vars = { model: s.model || "", apiKey: s.apiKey || "", system: sys, messages: msgs,
      chat: [{ role: "system", content: sys }, ...chat], tools: toOpenAITools(tools), prompt: flattenPrompt(sys, chat), max_tokens: tools.length ? Math.max(maxTokens, 4096) : maxTokens };
    url = fillString(s.baseUrl, vars);
    headers = { "content-type": "application/json" };
    for (const [k, v] of Object.entries(extra)) headers[k] = fillString(v, vars);
    body = fillTemplate(tpl, vars);
    parse = (d) => parseCustomResponse(d, s.responsePath, tools);
  } else if (provider === "openai") {
    if (!s.model) throw new Error("Set a model name in Settings.");
    const base = (s.baseUrl || "https://api.openai.com/v1").replace(/\/+$/, "");
    url = /\/chat\/completions$/.test(base) ? base : base + "/chat/completions";
    headers = { "content-type": "application/json", ...(s.apiKey ? { authorization: "Bearer " + s.apiKey } : {}), ...extra };
    body = { model: s.model, messages: toOpenAIMessages(system, messages), max_tokens: maxTokens };
    if (tools.length) body.tools = toOpenAITools(tools);
    parse = fromOpenAIResponse;
  } else {
    if (!s.apiKey) throw new Error("No API key set. Open Settings and add your API key.");
    const base = (s.baseUrl || "https://api.anthropic.com").replace(/\/+$/, "");
    url = /\/v1\/messages$/.test(base) ? base : base + "/v1/messages";
    headers = {
      "content-type": "application/json",
      "x-api-key": s.apiKey,
      "anthropic-version": "2023-06-01",
      "anthropic-dangerous-direct-browser-access": "true",
      ...extra,
    };
    body = { model: s.model || "claude-sonnet-5-5", max_tokens: maxTokens, system, messages };
    if (tools.length) body.tools = tools;
    parse = (d) => ({ content: d.content });
  }

  for (let attempt = 0; ; attempt++) {
    const resp = await fetch(url, { method: "POST", headers, body: JSON.stringify(body) });
    if (resp.ok) {
      const raw = await resp.text();
      let data;
      try { data = JSON.parse(raw); } catch (e) { data = raw; }
      return parse(data);
    }
    const errText = await resp.text();
    // Newer OpenAI-style models want max_completion_tokens instead of max_tokens.
    if (resp.status === 400 && body.max_tokens && /max_completion_tokens/.test(errText)) {
      body.max_completion_tokens = body.max_tokens;
      delete body.max_tokens;
      continue;
    }
    if ((resp.status === 429 || resp.status >= 500) && attempt < 2) { await sleepMs(2000 * (attempt + 1)); continue; }
    throw new Error(`Provider error ${resp.status}: ${errText.slice(0, 500)}`);
  }
}

// Public entry. For the custom provider, if the model attempted a tool call but produced something
// unparseable, ask it once to resend a valid one.
async function callLLM(opts) {
  const r = await callLLMOnce(opts);
  if (r.repairHint && opts.tools && opts.tools.length) {
    return callLLMOnce({
      ...opts,
      messages: [
        ...opts.messages,
        { role: "assistant", content: [{ type: "text", text: r.raw }] },
        { role: "user", content: [{ type: "text", text: r.repairHint }] },
      ],
    });
  }
  return r;
}











//lang-en.json
// English (source language). Every other lang-*.js file must contain exactly these keys and the same {placeholders}.
I18N.en = {
  "lang.label": "Language",
  "lang.help": "Changes the language of the whole extension and the language the assistant replies in.",
  "hdr.newChat": "New chat",
  "hdr.debug": "Copy debug log",
  "hdr.settings": "Settings",
  "hdr.currentPage": "Current page",
  "hint.intro": "Ask about the page, or tell me what to do on it. For example:",
  "chip.1": "What tasks are assigned to John?",
  "chip.2": "Create a new record using the details I give you",
  "chip.3": "Book a ticket from Pune to Mumbai for tomorrow",
  "hint.safety": "I'll ask for your approval before submitting, paying, booking, deleting or sending anything, and I never type passwords, card numbers or OTPs.",
  "hint.tip": "Tip: add a time and I'll do it later, e.g. “in 5 minutes, submit this form”.",
  "opt.step": "Approve every action",
  "opt.auto": "Auto-approve actions",
  "opt.debug": "Show model replies (debug)",
  "input.ph": "Ask or instruct… (Enter to send, Shift+Enter for new line)",
  "btn.send": "Send",
  "btn.stop": "Stop",
  "btn.approve": "Approve",
  "btn.deny": "Deny",
  "appr.title": "Approve? {action}",
  "appr.approved": "Approved: {action}",
  "appr.denied": "Denied: {action}",
  "why.step": "“Approve every action” is on.",
  "why.final": "This looks like a final or irreversible action.",
  "why.submit": "This types and submits a form.",
  "why.enter": "Pressing Enter can submit a form.",
  "why.site": "This opens a different website.",
  "why.schedule": "This will run later, on this page, without you watching. Auto-approve is OFF for it, so it will pause and ask you before final actions.",
  "d.page": "Page",
  "d.fields": "Fields filled during this task",
  "d.none": "(none)",
  "d.willDo": "What it will do",
  "act.type": "type “{text}” into {target}",
  "act.typeSubmit": "type “{text}” into {target} and submit",
  "act.select": "select “{option}” in {target}",
  "act.click": "click {target}",
  "act.press": "press {key}",
  "act.open": "open {url}",
  "act.later": "schedule for later: “{text}”",
  "act.scheduleAt": "schedule for {when}",
  "log.auto": "✔ auto-approved: {action}",
  "note.stopped": "Stopped.",
  "note.newChat": "New chat. Ask about the current page or tell me what to do.",
  "note.noControls": "I can't see any clickable controls on this page{iframes}. It may still be loading, or the app may run inside an iframe.",
  "note.iframes": " (it contains {n} iframe(s); content inside iframes isn't visible to me)",
  "note.stepLimit": "Reached the {n}-step limit. Tell me to continue if you want me to keep going.",
  "note.notAction": "This looks like instructions rather than an action: the model did not call a tool. Tick “Show model replies”, or use Copy debug log and send it to the developer.",
  "note.debugCopied": "Debug log copied (no API key included). Paste it to the developer, after removing anything private.",
  "note.copyFailed": "Could not copy automatically.",
  "err.unreadable": "This page can't be read or controlled (browser-internal pages like chrome:// or the Web Store are blocked). Switch to a normal web page.",
  "run.title": "Scheduled task",
  "run.autoOn": "Running unattended with auto-approve ON.",
  "run.autoOff": "Running unattended. I will pause and ask you before final actions.",
  "run.cannotStart": "Could not start the scheduled task.",
  "run.window": "Page Agent: scheduled task",
  "confirm.auto": "Auto-approve lets the agent submit, book, pay, save, send and delete WITHOUT asking you first.\n\nPasswords, card numbers and OTPs are still never typed by the agent, and you can press Stop at any time.\n\nTurn on auto-approve?",
  "tasks.title": "Scheduled tasks ({n} active)",
  "tasks.clear": "clear finished",
  "tasks.at": "at {time}",
  "tasks.starting": "starting…",
  "tasks.in": "in {t}",
  "tasks.auto": "auto-approve",
  "tasks.waiting": "Waiting for your approval: {title}",
  "tasks.open": "Open task window",
  "tasks.cancel": "Cancel",
  "tasks.stop": "Stop",
  "tasks.result": "Result",
  "tasks.log": "Log",
  "st.scheduled": "Scheduled",
  "st.launching": "Starting",
  "st.running": "Running",
  "st.needs_approval": "Needs approval",
  "st.done": "Done",
  "st.failed": "Failed",
  "st.cancelled": "Stopped",
  "st.missed": "Missed",
  "st.interrupted": "Interrupted",
  "set.title": "Settings",
  "set.provider": "Provider type",
  "prov.anthropic": "Anthropic Messages API (or compatible)",
  "prov.openai": "OpenAI-compatible (/chat/completions)",
  "prov.custom": "Custom (my own request/response format)",
  "prov.help.anthropic": "Anthropic's API, or a proxy that uses the same /v1/messages format with tool use.",
  "prov.help.openai": "Any server with POST {base}/chat/completions and tool calling, e.g. https://your-host/v1. The model must support tool calling.",
  "prov.help.custom": "Any HTTP JSON API. You define the request body and where the reply text is in the response. Tools work through a JSON-in-text protocol, so the model only needs to follow instructions.",
  "set.baseUrl": "Base URL",
  "set.requestUrl": "Request URL (full endpoint, POST)",
  "set.urlHelp": "Leave empty for the official endpoint of the selected type.",
  "set.urlHelpCustom": "Required. {{model}} and {{apiKey}} can be used in the URL.",
  "set.apiKey": "API key",
  "set.apiKeyPh": "optional for local models",
  "set.apiKeyHelp": "Stored only in this browser (chrome.storage.local) and sent only to the URL above.",
  "set.model": "Model name",
  "set.modelPh": "your provider's model id",
  "set.headers": "Extra headers (optional, JSON)",
  "set.headersHelp": "For providers that use a different auth header or need custom headers. {{apiKey}} and {{model}} work in the Custom type.",
  "set.bodyTpl": "Request body template (JSON)",
  "set.bodyTplHelp": "Placeholders: \"{{model}}\", \"{{system}}\", \"{{messages}}\" (list of {role, content}), \"{{prompt}}\" (everything as one text), \"{{max_tokens}}\" (number), \"{{chat}}\" (system message + messages, for OpenAI-style APIs), \"{{tools}}\" (tool definitions in OpenAI format, only if your API supports native tools). If the template has none of {{system}}, {{chat}} or {{prompt}}, the instructions and tools are added to the first user message automatically. A value that is exactly a placeholder gets the real value; placeholders inside longer text are inserted as text.",
  "set.respPath": "Response text path",
  "set.respPathPh": "e.g. choices.0.message.content or data.reply (empty = auto-detect)",
  "set.respPathHelp": "Where the model's reply text is in the JSON response. If the response is plain text, leave empty.",
  "set.suffix": "Prompt suffix (optional, custom provider)",
  "set.suffixPh": "e.g. /no_think (Qwen3: turns off long reasoning)",
  "set.suffixHelp": "Added to the end of every message sent to the model, e.g. switches like /no_think.",
  "set.compact": "Compact page snapshots (for small-context models)",
  "set.compactHelp": "Sends fewer page elements and less text per step. Turn on if your model has a small context window (Ollama's default is only 2-4k tokens: also raise num_ctx to 16k+).",
  "btn.save": "Save",
  "btn.test": "Save & test connection",
  "set.saved": "Saved.",
  "set.testing": "Testing…",
  "set.connected": "Connected. Model replied: {reply}",
  "set.emptyReply": "(empty reply)",
  "set.foundAt": "Reply text was found at: {path}",
  "set.pathTip": "Tip: paste this into “Response text path” to lock it in.",
  "err.tplJson": "Request body template must be valid JSON.",
  "bg.finished": "Task finished",
  "bg.failed": "Task failed",
  "bg.stopped": "Task stopped",
  "bg.missed": "Task missed",
  "bg.interrupted": "Task interrupted",
  "bg.approval": "Approval needed",
  "bg.cancelledBefore": "Cancelled before it ran.",
  "bg.stoppedByYou": "Stopped by you.",
  "bg.done": "Finished.",
  "bg.noStart": "The task window did not start.",
  "bg.couldNotStart": "Could not start: {err}",
  "bg.missedMsg": "It was due at {when} but the browser was not running within {min} minutes of that time, so it was not run.",
  "bg.winClosed": "The task window was closed before the task finished.",
  "bg.restarted": "The browser was closed or restarted while this task was running.",
};






//lang-ko.json
// Korean. Must contain exactly the same keys and {placeholders} as lang-en.js.
I18N.ko = {
  "lang.label": "언어",
  "lang.help": "확장 프로그램 전체의 언어와 어시스턴트가 답변하는 언어를 바꿉니다.",
  "hdr.newChat": "새 대화",
  "hdr.debug": "디버그 로그 복사",
  "hdr.settings": "설정",
  "hdr.currentPage": "현재 페이지",
  "hint.intro": "페이지에 대해 질문하거나, 페이지에서 할 일을 알려 주세요. 예를 들어:",
  "chip.1": "John에게 배정된 작업은 무엇인가요?",
  "chip.2": "내가 알려 주는 정보로 새 레코드를 만들어 줘",
  "chip.3": "내일 푸네에서 뭄바이로 가는 티켓을 예약해 줘",
  "hint.safety": "제출, 결제, 예약, 삭제, 전송을 하기 전에는 반드시 승인을 요청하며, 비밀번호, 카드 번호, OTP는 절대 입력하지 않습니다.",
  "hint.tip": "팁: 시간을 함께 말하면 나중에 실행합니다. 예: “5분 후에 이 양식을 제출해 줘”.",
  "opt.step": "모든 작업 승인",
  "opt.auto": "작업 자동 승인",
  "opt.debug": "모델 응답 표시(디버그)",
  "input.ph": "질문하거나 지시하세요… (Enter로 전송, Shift+Enter로 줄바꿈)",
  "btn.send": "보내기",
  "btn.stop": "중지",
  "btn.approve": "승인",
  "btn.deny": "거부",
  "appr.title": "승인하시겠습니까? {action}",
  "appr.approved": "승인됨: {action}",
  "appr.denied": "거부됨: {action}",
  "why.step": "“모든 작업 승인”이 켜져 있습니다.",
  "why.final": "최종 단계이거나 되돌릴 수 없는 작업으로 보입니다.",
  "why.submit": "양식에 입력하고 제출합니다.",
  "why.enter": "Enter 키를 누르면 양식이 제출될 수 있습니다.",
  "why.site": "다른 웹사이트를 엽니다.",
  "why.schedule": "나중에 이 페이지에서 사용자가 보지 않는 상태로 실행됩니다. 자동 승인은 꺼져 있으므로 최종 작업 전에 일시 중지하고 물어봅니다.",
  "d.page": "페이지",
  "d.fields": "이 작업 중 입력한 필드",
  "d.none": "(없음)",
  "d.willDo": "수행할 작업",
  "act.type": "{target}에 “{text}” 입력",
  "act.typeSubmit": "{target}에 “{text}” 입력 후 제출",
  "act.select": "{target}에서 “{option}” 선택",
  "act.click": "{target} 클릭",
  "act.press": "{key} 키 누르기",
  "act.open": "{url} 열기",
  "act.later": "나중에 실행 예약: “{text}”",
  "act.scheduleAt": "{when}에 실행 예약",
  "log.auto": "✔ 자동 승인됨: {action}",
  "note.stopped": "중지되었습니다.",
  "note.newChat": "새 대화입니다. 현재 페이지에 대해 질문하거나 할 일을 알려 주세요.",
  "note.noControls": "이 페이지에서 클릭할 수 있는 컨트롤이 보이지 않습니다{iframes}. 아직 로딩 중이거나 앱이 iframe 안에서 실행 중일 수 있습니다.",
  "note.iframes": " (iframe {n}개가 있으며, iframe 안의 내용은 볼 수 없습니다)",
  "note.stepLimit": "{n}단계 제한에 도달했습니다. 계속하려면 계속하라고 말씀해 주세요.",
  "note.notAction": "작업이 아니라 설명처럼 보입니다. 모델이 도구를 호출하지 않았습니다. “모델 응답 표시”를 켜거나 디버그 로그를 복사해 개발자에게 보내 주세요.",
  "note.debugCopied": "디버그 로그를 복사했습니다(API 키는 포함되지 않음). 개인 정보를 지운 뒤 개발자에게 붙여넣어 전달하세요.",
  "note.copyFailed": "자동으로 복사하지 못했습니다.",
  "err.unreadable": "이 페이지는 읽거나 제어할 수 없습니다(chrome:// 같은 브라우저 내부 페이지와 웹 스토어는 차단됩니다). 일반 웹 페이지로 이동하세요.",
  "run.title": "예약된 작업",
  "run.autoOn": "자동 승인을 켠 상태로 무인 실행 중입니다.",
  "run.autoOff": "무인 실행 중입니다. 최종 작업 전에 일시 중지하고 물어보겠습니다.",
  "run.cannotStart": "예약된 작업을 시작하지 못했습니다.",
  "run.window": "Page Agent: 예약된 작업",
  "confirm.auto": "자동 승인을 켜면 에이전트가 먼저 묻지 않고 제출, 예약, 결제, 저장, 전송, 삭제를 수행합니다.\n\n비밀번호, 카드 번호, OTP는 여전히 에이전트가 입력하지 않으며, 언제든 중지를 누를 수 있습니다.\n\n자동 승인을 켜시겠습니까?",
  "tasks.title": "예약된 작업 (진행 중 {n}개)",
  "tasks.clear": "완료된 항목 지우기",
  "tasks.at": "{time}에",
  "tasks.starting": "시작 중…",
  "tasks.in": "{t} 후",
  "tasks.auto": "자동 승인",
  "tasks.waiting": "승인 대기 중: {title}",
  "tasks.open": "작업 창 열기",
  "tasks.cancel": "취소",
  "tasks.stop": "중지",
  "tasks.result": "결과",
  "tasks.log": "로그",
  "st.scheduled": "예약됨",
  "st.launching": "시작 중",
  "st.running": "실행 중",
  "st.needs_approval": "승인 필요",
  "st.done": "완료",
  "st.failed": "실패",
  "st.cancelled": "중지됨",
  "st.missed": "놓침",
  "st.interrupted": "중단됨",
  "set.title": "설정",
  "set.provider": "제공자 유형",
  "prov.anthropic": "Anthropic Messages API (또는 호환)",
  "prov.openai": "OpenAI 호환 (/chat/completions)",
  "prov.custom": "사용자 지정 (직접 정의하는 요청/응답 형식)",
  "prov.help.anthropic": "Anthropic API 또는 도구 사용이 가능한 동일한 /v1/messages 형식의 프록시입니다.",
  "prov.help.openai": "POST {base}/chat/completions와 도구 호출을 지원하는 모든 서버입니다. 예: https://your-host/v1. 모델이 도구 호출을 지원해야 합니다.",
  "prov.help.custom": "모든 HTTP JSON API입니다. 요청 본문과 응답에서 답변 텍스트의 위치를 직접 정의합니다. 도구는 텍스트 속 JSON 프로토콜로 동작하므로 모델은 지시를 따르기만 하면 됩니다.",
  "set.baseUrl": "기본 URL",
  "set.requestUrl": "요청 URL (전체 엔드포인트, POST)",
  "set.urlHelp": "비워 두면 선택한 유형의 공식 엔드포인트를 사용합니다.",
  "set.urlHelpCustom": "필수입니다. URL에 {{model}}과 {{apiKey}}를 사용할 수 있습니다.",
  "set.apiKey": "API 키",
  "set.apiKeyPh": "로컬 모델은 선택 사항",
  "set.apiKeyHelp": "이 브라우저(chrome.storage.local)에만 저장되며 위의 URL로만 전송됩니다.",
  "set.model": "모델 이름",
  "set.modelPh": "제공자의 모델 ID",
  "set.headers": "추가 헤더 (선택, JSON)",
  "set.headersHelp": "다른 인증 헤더를 쓰거나 사용자 지정 헤더가 필요한 제공자용입니다. 사용자 지정 유형에서는 {{apiKey}}와 {{model}}을 사용할 수 있습니다.",
  "set.bodyTpl": "요청 본문 템플릿 (JSON)",
  "set.bodyTplHelp": "자리 표시자: \"{{model}}\", \"{{system}}\", \"{{messages}}\" ({role, content} 목록), \"{{prompt}}\" (전체를 하나의 텍스트로), \"{{max_tokens}}\" (숫자), \"{{chat}}\" (시스템 메시지 + 메시지, OpenAI 방식 API용), \"{{tools}}\" (OpenAI 형식의 도구 정의, API가 네이티브 도구를 지원할 때만). 템플릿에 {{system}}, {{chat}}, {{prompt}}가 하나도 없으면 지침과 도구가 첫 번째 사용자 메시지에 자동으로 추가됩니다. 값이 자리 표시자 하나로만 되어 있으면 실제 값으로 바뀌고, 긴 텍스트 안의 자리 표시자는 텍스트로 삽입됩니다.",
  "set.respPath": "응답 텍스트 경로",
  "set.respPathPh": "예: choices.0.message.content 또는 data.reply (비우면 자동 감지)",
  "set.respPathHelp": "JSON 응답에서 모델의 답변 텍스트가 있는 위치입니다. 응답이 일반 텍스트이면 비워 두세요.",
  "set.suffix": "프롬프트 접미사 (선택, 사용자 지정 제공자)",
  "set.suffixPh": "예: /no_think (Qwen3: 긴 추론 끄기)",
  "set.suffixHelp": "모델로 보내는 모든 메시지 끝에 추가됩니다. 예: /no_think 같은 스위치.",
  "set.compact": "페이지 스냅샷 간소화 (작은 컨텍스트 모델용)",
  "set.compactHelp": "단계마다 보내는 페이지 요소와 텍스트를 줄입니다. 모델의 컨텍스트 창이 작을 때 켜세요(Ollama 기본값은 2-4k 토큰뿐이므로 num_ctx도 16k 이상으로 올리세요).",
  "btn.save": "저장",
  "btn.test": "저장 및 연결 테스트",
  "set.saved": "저장되었습니다.",
  "set.testing": "테스트 중…",
  "set.connected": "연결되었습니다. 모델 응답: {reply}",
  "set.emptyReply": "(빈 응답)",
  "set.foundAt": "응답 텍스트 위치: {path}",
  "set.pathTip": "팁: 이 값을 “응답 텍스트 경로”에 붙여넣어 고정하세요.",
  "err.tplJson": "요청 본문 템플릿은 올바른 JSON이어야 합니다.",
  "bg.finished": "작업 완료",
  "bg.failed": "작업 실패",
  "bg.stopped": "작업 중지됨",
  "bg.missed": "작업을 놓침",
  "bg.interrupted": "작업 중단됨",
  "bg.approval": "승인 필요",
  "bg.cancelledBefore": "실행되기 전에 취소되었습니다.",
  "bg.stoppedByYou": "사용자가 중지했습니다.",
  "bg.done": "완료되었습니다.",
  "bg.noStart": "작업 창이 시작되지 않았습니다.",
  "bg.couldNotStart": "시작하지 못했습니다: {err}",
  "bg.missedMsg": "{when}에 실행될 예정이었지만 그 시각으로부터 {min}분 이내에 브라우저가 실행 중이지 않아 실행되지 않았습니다.",
  "bg.winClosed": "작업이 끝나기 전에 작업 창이 닫혔습니다.",
  "bg.restarted": "이 작업이 실행되는 동안 브라우저가 닫히거나 다시 시작되었습니다.",
};











//manifest.json
{
  "manifest_version": 3,
  "name": "Page Agent",
  "version": "0.8.2",
  "description": "Ask questions about the current page, or tell it to do things (fill forms, create records, book tickets), now or later, with approval before final actions.",
  "permissions": [
    "tabs",
    "scripting",
    "storage",
    "sidePanel",
    "alarms",
    "notifications"
  ],
  "host_permissions": [
    "<all_urls>",
    "https://api.anthropic.com/*"
  ],
  "background": {
    "service_worker": "background.js"
  },
  "side_panel": {
    "default_path": "sidepanel.html"
  },
  "options_page": "options.html",
  "action": {
    "default_title": "Page Agent",
    "default_icon": {
      "16": "icons/icon16.png",
      "32": "icons/icon32.png",
      "48": "icons/icon48.png"
    }
  },
  "icons": {
    "16": "icons/icon16.png",
    "32": "icons/icon32.png",
    "48": "icons/icon48.png",
    "128": "icons/icon128.png"
  }
}
