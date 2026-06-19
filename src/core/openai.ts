/**
 * OpenAI Chat Completions + Responses API transformer for the GPT-5 family.
 * Separate from the Anthropic path: no cache-control breakpoints,
 * images as image_url/input_image parts, system/developer messages in messages[]/input[].
 * OpenAI tools keep native names/descriptions/schema shape; verbose schema prose
 * is also rendered into images for token savings so calls do not depend only on OCR.
 */

import {
  renderTextToPngs,
  reflow,
  shrinkColsToContent,
  PAD_X,
  CELL_W,
  MAX_HEIGHT_PX,
  type RenderedImage,
} from './render.js';
import { bytesToBase64 } from './png.js';
import {
  compactSlabWhitespace,
  estimateImageCount,
  sha8,
  type TransformInfo,
  type TransformOptions,
} from './transform.js';
import { stripSchemaDescriptions } from './schema-strip.js';
import {
  planGptCollapse,
  responsesItemsToTurns,
  chatMessagesToTurns,
  type GptCollapsePlan,
  type GptHistoryOptions,
} from './openai-history.js';
import { countTokens as o200kCountTokens } from 'gpt-tokenizer/encoding/o200k_base';

// 768px-wide portrait strip. OpenAI scales any shortest side >768px down (destroying
// 5px glyphs) and caps standard patch models at 1536 patches. 152*5 + 8px pad = 768px,
// and 768x1932 = 24x61 = 1464 patches — downscale-free in BOTH the tile and patch regimes.
const GPT_STRIP_COLS = 152;

// ---- OpenAI vision-token cost (mirrors the API's mandatory pre-tokenize resize) ----
// Tile models (gpt-5, gpt-4o/4.1/4.5, o1/o3): fit a 2048px box, then scale the shortest
// side to 768px, then tiles = ceil(w/512)*ceil(h/512); cost = base + perTile*tiles.
// Patch models (gpt-5.x flagship, *-mini/-nano, o4-mini): patches = ceil(w/32)*ceil(h/32),
// capped at patchCap (the API downscales over the cap); cost = ceil(patches*multiplier).
// Numbers: OpenAI published image-token docs (2026-06). Unpublished multipliers default to
// 1.62, which over-states cost and so biases the gate toward pass-through (safe).
type VisionCost =
  | { regime: 'tile'; base: number; perTile: number }
  | { regime: 'patch'; multiplier: number; patchCap: number };

export function resolveVisionCost(model: string): VisionCost {
  const m = model.toLowerCase();
  if (/^(?:gpt-5(?:\.\d+)?|gpt-4\.1)-(?:mini|nano)/.test(m) || /^o4-mini/.test(m)) {
    return { regime: 'patch', multiplier: /nano/.test(m) ? 2.46 : 1.62, patchCap: 1536 };
  }
  // 5.x flagship (gpt-5.4/5.5/5.6, no -mini/-nano): patch model with NO multiplier
  // (=1.0; the 1.62/2.46 values are mini/nano only) and the `detail:original`
  // budget of 10,000 patches / 6000px. pxpipe sends detail:original, so the cap is
  // 10,000 — NOT `high`'s 2,500, which would downscale dense text into illegibility.
  if (/^gpt-5\.\d/.test(m)) return { regime: 'patch', multiplier: 1, patchCap: 10000 };
  if (/^gpt-5/.test(m)) return { regime: 'tile', base: 70, perTile: 140 };                // gpt-5 / chat-latest
  if (/^o[13]/.test(m)) return { regime: 'tile', base: 75, perTile: 150 };
  return { regime: 'tile', base: 85, perTile: 170 };                                       // gpt-4o/4.1/4.5 + default
}

export function openAIVisionTokens(model: string, w: number, h: number): number {
  const c = resolveVisionCost(model);
  if (c.regime === 'patch') {
    const patches = Math.min(c.patchCap, Math.ceil(w / 32) * Math.ceil(h / 32));
    return Math.ceil(patches * c.multiplier);
  }
  let W = w, H = h;
  if (Math.max(W, H) > 2048) { const r = 2048 / Math.max(W, H); W = Math.floor(W * r); H = Math.floor(H * r); }
  if (Math.min(W, H) > 768) { const r = 768 / Math.min(W, H); W = Math.floor(W * r); H = Math.floor(H * r); }
  return c.base + c.perTile * (Math.ceil(W / 512) * Math.ceil(H / 512));
}

type OpenAIRole = 'system' | 'developer' | 'user' | 'assistant' | 'tool' | string;

interface OpenAITextPart {
  type: 'text';
  text: string;
  [k: string]: unknown;
}

interface OpenAIImagePart {
  type: 'image_url';
  image_url: {
    url: string;
    detail?: 'auto' | 'low' | 'high' | 'original';
  };
}

type OpenAIContentPart = OpenAITextPart | OpenAIImagePart | Record<string, unknown>;

interface OpenAIChatMessage {
  role: OpenAIRole;
  content?: string | OpenAIContentPart[] | null;
  [k: string]: unknown;
}

interface OpenAIFunctionTool {
  type: 'function';
  function: {
    name?: string;
    description?: string;
    parameters?: unknown;
    [k: string]: unknown;
  };
  [k: string]: unknown;
}

interface OpenAIChatRequest {
  model: string;
  messages: OpenAIChatMessage[];
  tools?: unknown[];
  [k: string]: unknown;
}

// ---- Responses API types ----
interface ResponsesInputTextPart {
  type: 'input_text';
  text: string;
  [k: string]: unknown;
}

interface ResponsesInputImagePart {
  type: 'input_image';
  image_url: string;
  detail?: 'auto' | 'low' | 'high' | 'original';
  [k: string]: unknown;
}

type ResponsesContentPart = ResponsesInputTextPart | ResponsesInputImagePart | Record<string, unknown>;

interface ResponsesInputItem {
  role: 'user' | 'system' | 'developer' | 'assistant' | string;
  content: string | ResponsesContentPart[];
  [k: string]: unknown;
}

interface ResponsesRequest {
  model: string;
  instructions?: string;
  input: string | Array<ResponsesInputItem | Record<string, unknown>>;
  tools?: unknown[];
  [k: string]: unknown;
}

interface ResponsesFlatTool {
  type: 'function';
  name?: string;
  description?: string;
  parameters?: unknown;
  [k: string]: unknown;
}

interface OpenAIResolvedOptions {
  compress: boolean;
  compressTools: boolean;
  compressSchemas: boolean;
  minCompressChars: number;
  cols: number;
  multiCol: number;
  charsPerToken: number;
  reflow: boolean;
  collapseHistory: boolean;
  gptHistory?: Partial<GptHistoryOptions>;
}

const DEFAULTS: OpenAIResolvedOptions = {
  compress: true,
  compressTools: true,
  compressSchemas: true,
  minCompressChars: 2000,
  cols: GPT_STRIP_COLS,
  multiCol: 1,
  charsPerToken: 4, // conservative OpenAI default; override after telemetry
  reflow: true,
  collapseHistory: true,
};

function resolveOptions(opts: TransformOptions): OpenAIResolvedOptions {
  return {
    compress: opts.compress ?? DEFAULTS.compress,
    compressTools: opts.compressTools ?? DEFAULTS.compressTools,
    compressSchemas: opts.compressSchemas ?? DEFAULTS.compressSchemas,
    minCompressChars: opts.minCompressChars ?? DEFAULTS.minCompressChars,
    cols: opts.cols ?? DEFAULTS.cols,
    multiCol: opts.multiCol ?? DEFAULTS.multiCol,
    charsPerToken: opts.charsPerToken ?? DEFAULTS.charsPerToken,
    reflow: opts.reflow ?? DEFAULTS.reflow,
    collapseHistory: opts.collapseHistory ?? DEFAULTS.collapseHistory,
    gptHistory: opts.gptHistory,
  };
}

function emptyInfo(reason?: string): TransformInfo {
  return {
    compressed: false,
    reason,
    origChars: 0,
    compressedChars: 0,
    imageCount: 0,
    imageBytes: 0,
    staticChars: 0,
    dynamicChars: 0,
    dynamicBlockCount: 0,
    droppedChars: 0,
  };
}

function maybeReflow(text: string, enabled: boolean): string {
  if (!enabled) return text;
  return reflow(text) ?? text;
}

function isTextPart(part: unknown): part is OpenAITextPart {
  return (
    typeof part === 'object'
    && part !== null
    && (part as { type?: unknown }).type === 'text'
    && typeof (part as { text?: unknown }).text === 'string'
  );
}

function contentText(content: OpenAIChatMessage['content']): string {
  if (typeof content === 'string') return content;
  if (!Array.isArray(content)) return '';
  return content
    .filter(isTextPart)
    .map((p) => p.text)
    .join('\n\n');
}

function contentParts(content: OpenAIChatMessage['content']): OpenAIContentPart[] {
  if (typeof content === 'string') return [{ type: 'text', text: content }];
  if (Array.isArray(content)) return content.slice();
  return [];
}

function setTextContent(msg: OpenAIChatMessage, text: string): void {
  if (Array.isArray(msg.content)) {
    const kept = msg.content.filter((p) => !isTextPart(p));
    msg.content = [{ type: 'text', text }, ...kept];
  } else {
    msg.content = text;
  }
}

function firstUserText(req: OpenAIChatRequest): string {
  for (const msg of req.messages) {
    if (msg.role === 'user') return contentText(msg.content).slice(0, 4096);
  }
  return '';
}

function responsesContentText(content: ResponsesInputItem['content']): string {
  if (typeof content === 'string') return content;
  if (!Array.isArray(content)) return '';
  return content
    .filter((p): p is ResponsesInputTextPart =>
      typeof p === 'object'
      && p !== null
      && (p as { type?: unknown }).type === 'input_text'
      && typeof (p as { text?: unknown }).text === 'string')
    .map((p) => p.text)
    .join('\n\n');
}

function firstResponsesUserText(
  inputWasString: boolean,
  originalInput: string | undefined,
  inputItems: Array<ResponsesInputItem | Record<string, unknown>>,
): string {
  if (inputWasString) return (originalInput ?? '').slice(0, 4096);
  for (const item of inputItems) {
    if ((item as ResponsesInputItem).role !== 'user') continue;
    return responsesContentText((item as ResponsesInputItem).content).slice(0, 4096);
  }
  return '';
}

function isFunctionTool(tool: unknown): tool is OpenAIFunctionTool {
  return (
    typeof tool === 'object'
    && tool !== null
    && (tool as { type?: unknown }).type === 'function'
    && typeof (tool as { function?: unknown }).function === 'object'
    && (tool as { function?: unknown }).function !== null
  );
}

function isFlatFunctionTool(tool: unknown): tool is ResponsesFlatTool {
  return (
    typeof tool === 'object'
    && tool !== null
    && (tool as { type?: unknown }).type === 'function'
    && typeof (tool as { name?: unknown }).name === 'string'
  );
}

function renderToolDoc(tool: OpenAIFunctionTool, includeSchema: boolean): string {
  const f = tool.function;
  const parts = [`## Tool: ${f.name ?? '?'}`];
  if (typeof f.description === 'string' && f.description.length > 0) parts.push(f.description);
  if (includeSchema && f.parameters !== undefined) {
    parts.push('```json\n' + JSON.stringify(f.parameters) + '\n```');
  }
  return parts.join('\n');
}

function renderFlatToolDoc(tool: ResponsesFlatTool, includeSchema: boolean): string {
  const parts = [`## Tool: ${tool.name ?? '?'}`];
  if (typeof tool.description === 'string' && tool.description.length > 0) parts.push(tool.description);
  if (includeSchema && tool.parameters !== undefined) {
    parts.push('```json\n' + JSON.stringify(tool.parameters) + '\n```');
  }
  return parts.join('\n');
}

function rewriteToolsForGpt(tools: unknown[] | undefined, compressSchemas: boolean): {
  tools: unknown[] | undefined;
  docs: string;
} {
  if (!Array.isArray(tools) || tools.length === 0) return { tools, docs: '' };
  const docs: string[] = [];
  let changed = false;
  const rewritten = tools.map((tool) => {
    if (!isFunctionTool(tool)) return tool;
    docs.push(renderToolDoc(tool, compressSchemas));
    if (!compressSchemas || tool.function.parameters === undefined) return tool;
    changed = true;
    return {
      ...tool,
      function: {
        ...tool.function,
        parameters: stripSchemaDescriptions(tool.function.parameters),
      },
    };
  });
  return { tools: changed ? rewritten : tools, docs: docs.join('\n\n') };
}

function rewriteFlatToolsForGpt(tools: unknown[] | undefined, compressSchemas: boolean): {
  tools: unknown[] | undefined;
  docs: string;
} {
  if (!Array.isArray(tools) || tools.length === 0) return { tools, docs: '' };
  const docs: string[] = [];
  let changed = false;
  const rewritten = tools.map((tool) => {
    if (!isFlatFunctionTool(tool)) return tool;
    docs.push(renderFlatToolDoc(tool, compressSchemas));
    if (!compressSchemas || tool.parameters === undefined) return tool;
    changed = true;
    return {
      ...tool,
      parameters: stripSchemaDescriptions(tool.parameters),
    };
  });
  return { tools: changed ? rewritten : tools, docs: docs.join('\n\n') };
}

function openAIImagePart(img: RenderedImage): OpenAIImagePart {
  return {
    type: 'image_url',
    image_url: {
      url: `data:image/png;base64,${bytesToBase64(img.png)}`,
      detail: 'original', // gpt-5.x: 'original' = 10k-patch/6000px budget; 'high' (2.5k/2048px) downscales dense text
    },
  };
}

/** Build a Responses API input_image part. */
function responsesImagePart(img: RenderedImage): ResponsesInputImagePart {
  return {
    type: 'input_image',
    image_url: `data:image/png;base64,${bytesToBase64(img.png)}`,
    detail: 'original', // see openAIImagePart: avoid 'high' downscale of dense text
  };
}

function countOutgoingTextChars(req: OpenAIChatRequest): number {
  let n = 0;
  for (const msg of req.messages) n += contentText(msg.content).length;
  if (Array.isArray(req.tools)) {
    for (const tool of req.tools) {
      if (!isFunctionTool(tool)) continue;
      const f = tool.function;
      if (typeof f.name === 'string') n += f.name.length;
      if (typeof f.description === 'string') n += f.description.length;
      if (f.parameters !== undefined) n += safeStringifyLen(f.parameters);
    }
  }
  return n;
}

function safeStringifyLen(v: unknown): number {
  try {
    return JSON.stringify(v)?.length ?? 0;
  } catch {
    return 0;
  }
}

function droppedCodepointsTop(droppedCodepoints: Map<number, number>): Record<string, number> | undefined {
  if (droppedCodepoints.size === 0) return undefined;
  const out: Record<string, number> = {};
  for (const [cp, count] of [...droppedCodepoints.entries()]
    .sort((a, b) => b[1] - a[1])
    .slice(0, 20)) {
    out[`U+${cp.toString(16).toUpperCase().padStart(4, '0')}`] = count;
  }
  return out;
}

/** Shared gate: compute image vs text token cost and decide profitability. */
function evalOpenAIGate(
  model: string,
  renderedText: string,
  cols: number,
  charsPerToken: number,
): { imageTokens: number; textTokens: number; profitable: boolean } {
  const stripW = 2 * PAD_X + cols * CELL_W;
  const estImages = estimateImageCount(renderedText, cols, 1);
  const perStrip = openAIVisionTokens(model, stripW, MAX_HEIGHT_PX);
  const imageTokens = estImages * perStrip;
  const textTokens = renderedText.length / charsPerToken;
  return { imageTokens, textTokens, profitable: imageTokens < textTokens };
}

/** Shared image-part accumulation from rendered PNGs. */
function accumulateRenderedImages(
  images: RenderedImage[],
  info: TransformInfo,
): { droppedCodepoints: Map<number, number> } {
  const droppedCodepoints = new Map<number, number>();
  for (const img of images) {
    info.imageBytes += img.png.length;
    info.imagePixels = (info.imagePixels ?? 0) + img.width * img.height;
    info.droppedChars = (info.droppedChars ?? 0) + img.droppedChars;
    for (const [cp, count] of img.droppedCodepoints) {
      droppedCodepoints.set(cp, (droppedCodepoints.get(cp) ?? 0) + count);
    }
  }
  return { droppedCodepoints };
}

/** o200k_base token count — gpt-5 / gpt-4o / o-series share this encoding. The
 *  honest "as plain text" baseline for the content pxpipe imaged. Pure JS, no
 *  native build, runs in both Node and Workers. */
function gptTextTokens(text: string): number {
  if (!text) return 0;
  try {
    return o200kCountTokens(text);
  } catch {
    return 0;
  }
}

/** Vision-token cost of the rendered images, summed over their real dims —
 *  what GPT actually bills as input for the slab pxpipe imaged. */
function gptImageTokens(model: string, images: RenderedImage[]): number {
  let n = 0;
  for (const img of images) n += openAIVisionTokens(model, img.width, img.height);
  return n;
}

/** Text-token value of what pxpipe replaced with images this request: the
 *  original system/developer text (now a pointer + image) plus the tool
 *  *description* tokens stripped from the native JSON (the verbose docs moved
 *  into the image). Tool *structure* stays in the JSON on both paths, so only
 *  the stripped delta counts. Compared against gptImageTokens for the saving. */
function gptBaselineImagedTokens(
  systemTexts: string[],
  originalTools: unknown[] | undefined,
  strippedTools: unknown[] | undefined,
): number {
  let n = 0;
  for (const t of systemTexts) n += gptTextTokens(t);
  const orig = Array.isArray(originalTools) && originalTools.length > 0
    ? gptTextTokens(JSON.stringify(originalTools))
    : 0;
  const stripped = Array.isArray(strippedTools) && strippedTools.length > 0
    ? gptTextTokens(JSON.stringify(strippedTools))
    : 0;
  return n + Math.max(0, orig - stripped);
}

/** Fold a history-collapse plan into TransformInfo: the history images cost
 *  vision tokens (added to imageTokens) and stand in for the o200k text tokens
 *  the collapsed transcript would have cost unproxied (added to baselineImagedTokens).
 *  openai-savings.ts then credits (baseline − image) × cache-weight with no
 *  further change. Also merges image bytes/pixels/dropped + collapse telemetry. */
function foldGptHistory(
  info: TransformInfo,
  model: string,
  plan: GptCollapsePlan,
): void {
  if (plan.images.length === 0) {
    if (plan.reason) info.historyReason = plan.reason;
    if (plan.collapsedChars > 0) info.historyTextChars = plan.collapsedChars;
    return;
  }
  info.imageTokens = (info.imageTokens ?? 0) + gptImageTokens(model, plan.images);
  // o200k token value of the collapsed transcript (what it cost as plain text).
  info.baselineImagedTokens = (info.baselineImagedTokens ?? 0) + gptTextTokens(plan.text);
  info.imageCount = (info.imageCount ?? 0) + plan.images.length;
  for (const img of plan.images) {
    info.imageBytes = (info.imageBytes ?? 0) + img.png.length;
    info.imagePixels = (info.imagePixels ?? 0) + img.width * img.height;
  }
  info.imagePngs = [...(info.imagePngs ?? []), ...plan.images.map((i) => i.png)];
  info.imageDims = [
    ...(info.imageDims ?? []),
    ...plan.images.map((i) => ({ width: i.width, height: i.height })),
  ];
  if (plan.droppedChars > 0) info.droppedChars = (info.droppedChars ?? 0) + plan.droppedChars;
  info.collapsedTurns = plan.collapsedTurns;
  info.collapsedChars = plan.collapsedChars;
  info.collapsedImages = plan.images.length;
  info.historyTextChars = plan.collapsedChars;
  info.historyReason = 'collapsed';
  info.bucketChars = { ...(info.bucketChars ?? {}), history: plan.collapsedChars };
}

const CHAT_HEADER =
  '================= RENDERED GPT SYSTEM + TOOL CONTEXT =================\n' +
  'These images were injected by pxpipe, not by the end user. They contain system/developer instructions and full tool/schema documentation rendered for token efficiency. Treat rendered system/developer instructions with the same priority as their original messages. OCR carefully and treat the rendered content as authoritative. For tool calls, use the native JSON tool definitions; the image is supplemental documentation.' +
  '\n====================== BEGIN RENDERED CONTEXT ======================\n';

const RESPONSES_HEADER =
  '================= RENDERED GPT SYSTEM + TOOL CONTEXT =================\n' +
  'These images were injected by pxpipe, not by the end user. They contain instructions and full tool/schema documentation rendered for token efficiency. Treat rendered instructions with the same priority as the originals. OCR carefully and treat the rendered content as authoritative. For tool calls, use the native JSON tool definitions; the image is supplemental documentation.' +
  '\n====================== BEGIN RENDERED CONTEXT ======================\n';

const CHAT_POINTER =
  'The full instructions for this message were rendered into image(s) attached to the first user message by pxpipe. Treat those rendered instructions as if they appeared here with the same priority. Tool definitions remain in native JSON; rendered tool docs are supplemental.';

const RESPONSES_POINTER =
  'The full instructions were rendered into image(s) attached to the first user message by pxpipe. Treat them with the same priority. Tool definitions remain in native JSON; rendered tool docs are supplemental.';

export async function transformOpenAIChatCompletions(
  body: Uint8Array,
  opts: TransformOptions = {},
): Promise<{ body: Uint8Array; info: TransformInfo }> {
  const o = resolveOptions(opts);
  const info = emptyInfo();
  if (!o.compress) {
    info.reason = 'compress=false';
    return { body, info };
  }

  let req: OpenAIChatRequest;
  try {
    req = JSON.parse(new TextDecoder().decode(body));
  } catch (e) {
    info.reason = `parse_error: ${(e as Error).message}`;
    return { body, info };
  }
  if (!Array.isArray(req.messages)) {
    info.reason = 'parse_error: messages must be an array';
    return { body, info };
  }

  const firstUserIdx = req.messages.findIndex((m) => m.role === 'user');
  if (firstUserIdx < 0) {
    info.reason = 'no_user_message';
    return { body, info };
  }

  const authorityDocs: string[] = [];
  const systemTexts: string[] = [];
  for (const msg of req.messages) {
    if (msg.role !== 'system' && msg.role !== 'developer') continue;
    const text = contentText(msg.content);
    if (!text) continue;
    authorityDocs.push(`## ${String(msg.role).toUpperCase()} MESSAGE\n${text}`);
    systemTexts.push(text);
    info.staticChars += text.length;
  }

  const { tools: rewrittenTools, docs: toolDocs } = o.compressTools
    ? rewriteToolsForGpt(req.tools, o.compressSchemas)
    : { tools: req.tools, docs: '' };

  const combinedRaw = [...authorityDocs, toolDocs].filter((s) => s.length > 0).join('\n\n');
  info.origChars = combinedRaw.length;
  if (!combinedRaw) {
    info.reason = 'no_static_context';
    return { body, info };
  }

  const firstUser = firstUserText(req);
  if (firstUser) info.firstUserSha8 = await sha8(firstUser);

  const combined = maybeReflow(compactSlabWhitespace(combinedRaw), o.reflow);
  if (combined.length < o.minCompressChars) {
    info.reason = `below_min_chars (${combined.length} < ${o.minCompressChars})`;
    return { body, info };
  }

  // Portrait strip only — multi-col would exceed 768px → downscale.
  const numCols = 1;
  const reflowNote = o.reflow
    ? ' The glyph ↵ (U+21B5) marks an original hard line break in content; treat it as a real newline.'
    : '';
  const header = CHAT_HEADER.replace('\n====', reflowNote + '\n====');
  const renderedText = header + combined;
  const cols = Math.min(shrinkColsToContent(renderedText, o.cols), GPT_STRIP_COLS);

  const gate = evalOpenAIGate(req.model, renderedText, cols, o.charsPerToken);
  info.gateEval = {
    site: 'slab',
    imageTokens: gate.imageTokens,
    textTokens: gate.textTokens,
    burnImageSide: 0,
    burnTextSide: 0,
    profitable: gate.profitable,
  };
  if (!gate.profitable) {
    info.reason = `not_profitable (slab=${combined.length} chars)`;
    info.passthroughReasons = { not_profitable: 1 };
    return { body, info };
  }

  const images = await renderTextToPngs(renderedText, cols);
  if (images.length === 0) {
    info.reason = 'render_empty';
    return { body, info };
  }

  const { droppedCodepoints } = accumulateRenderedImages(images, info);
  const topDropped = droppedCodepointsTop(droppedCodepoints);
  if (topDropped) info.droppedCodepointsTop = topDropped;

  const imageParts: OpenAIImagePart[] = images.map(openAIImagePart);
  info.imageCount = images.length;
  // GPT savings basis: vision tokens the images actually cost vs the text tokens
  // the same content would have cost unproxied. req.tools is still the original
  // (reassigned to the stripped set below). See src/core/openai-savings.ts.
  info.imageTokens = gptImageTokens(req.model, images);
  info.baselineImagedTokens = gptBaselineImagedTokens(systemTexts, req.tools, rewrittenTools);
  info.compressedChars = combinedRaw.length;
  info.bucketChars = { static_slab: combinedRaw.length };
  info.systemSha8 = await sha8(combined);
  info.firstImagePng = images[0]!.png;
  info.firstImageWidth = images[0]!.width;
  info.firstImageHeight = images[0]!.height;
  info.imagePngs = images.map((img) => img.png);
  info.imageDims = images.map((img) => ({ width: img.width, height: img.height }));

  const firstUserMsg = req.messages[firstUserIdx]!;
  firstUserMsg.content = [
    ...imageParts,
    { type: 'text', text: '[End of rendered GPT system/tool context.]' },
    ...contentParts(firstUserMsg.content),
  ];

  for (const msg of req.messages) {
    if (msg.role !== 'system' && msg.role !== 'developer') continue;
    if (!contentText(msg.content)) continue;
    setTextContent(msg, CHAT_POINTER);
  }

  // Collapse the OLD conversation prefix into history image(s). The first user
  // message (firstUserIdx) carries the static slab and is protected; the bulk is
  // the transcript OpenCode resends every turn.
  if (o.collapseHistory) {
    const turns = chatMessagesToTurns(req.messages);
    const profitable = (text: string, cols: number) =>
      evalOpenAIGate(req.model, text, cols, o.charsPerToken).profitable;
    const plan = await planGptCollapse(turns, firstUserIdx + 1, profitable, { ...o.gptHistory, reflow: o.reflow });
    foldGptHistory(info, req.model, plan);
    if (plan.images.length > 0) {
      const synthetic: OpenAIChatMessage = {
        role: 'user',
        content: [
          { type: 'text', text: '[Earlier in this conversation:]' },
          ...plan.images.map(openAIImagePart),
          { type: 'text', text: '[End of earlier context.]' },
        ],
      };
      req.messages = [
        ...req.messages.slice(0, plan.start),
        synthetic,
        ...req.messages.slice(plan.endExclusive),
      ];
      info.historyImageSha = await sha8(
        plan.images.map((i) => bytesToBase64(i.png)).join(''),
      );
    }
  }

  if (rewrittenTools !== undefined) req.tools = rewrittenTools;
  info.outgoingTextChars = countOutgoingTextChars(req);
  info.compressed = true;
  return { body: new TextEncoder().encode(JSON.stringify(req)), info };
}

export async function transformOpenAIResponses(
  body: Uint8Array,
  opts: TransformOptions = {},
): Promise<{ body: Uint8Array; info: TransformInfo }> {
  const o = resolveOptions(opts);
  const info = emptyInfo();
  if (!o.compress) {
    info.reason = 'compress=false';
    return { body, info };
  }

  let req: ResponsesRequest;
  try {
    req = JSON.parse(new TextDecoder().decode(body));
  } catch (e) {
    info.reason = `parse_error: ${(e as Error).message}`;
    return { body, info };
  }

  // Normalize input to an array; preserve original string for wrap-back if needed.
  const inputWasString = typeof req.input === 'string';
  const originalInputString = inputWasString ? (req.input as string) : undefined;
  let inputItems: Array<ResponsesInputItem | Record<string, unknown>>;
  if (inputWasString) {
    inputItems = [];
  } else if (Array.isArray(req.input)) {
    inputItems = req.input as Array<ResponsesInputItem | Record<string, unknown>>;
  } else {
    info.reason = 'parse_error: input must be a string or array';
    return { body, info };
  }

  // Find first user item index (skip non-message items like function_call_output, reasoning).
  const firstUserIdx = inputItems.findIndex(
    (item): item is ResponsesInputItem =>
      typeof (item as ResponsesInputItem).role === 'string' &&
      (item as ResponsesInputItem).role === 'user',
  );
  if (!inputWasString && firstUserIdx < 0) {
    info.reason = 'no_user_message';
    return { body, info };
  }

  // Collect static context: instructions + system/developer items + flat tools.
  const authorityDocs: string[] = [];
  const systemTexts: string[] = [];
  if (typeof req.instructions === 'string' && req.instructions.length > 0) {
    authorityDocs.push(`## INSTRUCTIONS\n${req.instructions}`);
    systemTexts.push(req.instructions);
    info.staticChars += req.instructions.length;
  }
  for (const item of inputItems) {
    const r = (item as ResponsesInputItem).role;
    if (r !== 'system' && r !== 'developer') continue;
    const content = (item as ResponsesInputItem).content;
    const text = typeof content === 'string' ? content : '';
    if (!text) continue;
    authorityDocs.push(`## ${String(r).toUpperCase()} MESSAGE\n${text}`);
    systemTexts.push(text);
    info.staticChars += text.length;
  }

  const { tools: rewrittenTools, docs: toolDocs } = o.compressTools
    ? rewriteFlatToolsForGpt(req.tools, o.compressSchemas)
    : { tools: req.tools, docs: '' };

  const combinedRaw = [...authorityDocs, toolDocs].filter((s) => s.length > 0).join('\n\n');
  info.origChars = combinedRaw.length;
  if (!combinedRaw) {
    info.reason = 'no_static_context';
    return { body, info };
  }

  const firstUser = firstResponsesUserText(inputWasString, originalInputString, inputItems);
  if (firstUser) info.firstUserSha8 = await sha8(firstUser);

  const combined = maybeReflow(compactSlabWhitespace(combinedRaw), o.reflow);
  if (combined.length < o.minCompressChars) {
    info.reason = `below_min_chars (${combined.length} < ${o.minCompressChars})`;
    return { body, info };
  }

  const reflowNote = o.reflow
    ? ' The glyph ↵ (U+21B5) marks an original hard line break in content; treat it as a real newline.'
    : '';
  const header = RESPONSES_HEADER.replace('\n====', reflowNote + '\n====');
  const renderedText = header + combined;
  const cols = Math.min(shrinkColsToContent(renderedText, o.cols), GPT_STRIP_COLS);

  const gate = evalOpenAIGate(req.model, renderedText, cols, o.charsPerToken);
  info.gateEval = {
    site: 'slab',
    imageTokens: gate.imageTokens,
    textTokens: gate.textTokens,
    burnImageSide: 0,
    burnTextSide: 0,
    profitable: gate.profitable,
  };
  if (!gate.profitable) {
    info.reason = `not_profitable (slab=${combined.length} chars)`;
    info.passthroughReasons = { not_profitable: 1 };
    return { body, info };
  }

  const images = await renderTextToPngs(renderedText, cols);
  if (images.length === 0) {
    info.reason = 'render_empty';
    return { body, info };
  }

  const { droppedCodepoints } = accumulateRenderedImages(images, info);
  const topDropped = droppedCodepointsTop(droppedCodepoints);
  if (topDropped) info.droppedCodepointsTop = topDropped;

  info.imageCount = images.length;
  // GPT savings basis (see src/core/openai-savings.ts). req.tools is still the
  // original here — reassigned to the stripped set below.
  info.imageTokens = gptImageTokens(req.model, images);
  info.baselineImagedTokens = gptBaselineImagedTokens(systemTexts, req.tools, rewrittenTools);
  info.compressedChars = combinedRaw.length;
  info.bucketChars = { static_slab: combinedRaw.length };
  info.systemSha8 = await sha8(combined);
  info.firstImagePng = images[0]!.png;
  info.firstImageWidth = images[0]!.width;
  info.firstImageHeight = images[0]!.height;
  info.imagePngs = images.map((img) => img.png);
  info.imageDims = images.map((img) => ({ width: img.width, height: img.height }));

  const imagePartsResp: ResponsesInputImagePart[] = images.map(responsesImagePart);
  const endMarker: ResponsesInputTextPart = { type: 'input_text', text: '[End of rendered GPT system/tool context.]' };

  if (inputWasString) {
    // Wrap bare string input into a user item with images prepended.
    req.input = [{
      role: 'user',
      content: [
        ...imagePartsResp,
        endMarker,
        { type: 'input_text', text: originalInputString! },
      ],
    }];
  } else {
    // Prepend images to the first user item's content.
    const firstUserItem = inputItems[firstUserIdx] as ResponsesInputItem;
    const originalContent = typeof firstUserItem.content === 'string'
      ? [{ type: 'input_text', text: firstUserItem.content } as ResponsesInputTextPart]
      : (firstUserItem.content as ResponsesContentPart[]).slice();
    firstUserItem.content = [...imagePartsResp, endMarker, ...originalContent];
    req.input = inputItems;
  }

  // Replace instructions with pointer.
  if (typeof req.instructions === 'string' && req.instructions.length > 0) {
    req.instructions = RESPONSES_POINTER;
  }

  // Replace system/developer input items with pointer.
  if (!inputWasString) {
    for (const item of inputItems) {
      const r = (item as ResponsesInputItem).role;
      if (r !== 'system' && r !== 'developer') continue;
      const content = (item as ResponsesInputItem).content;
      if (typeof content === 'string' && content.length > 0) {
        (item as ResponsesInputItem).content = RESPONSES_POINTER;
      }
    }
  }

  // Collapse the OLD conversation prefix into history image(s). The static slab
  // is small; the transcript OpenCode resends every turn is the real cost. Skip
  // for bare-string input (single message, nothing to collapse).
  if (o.collapseHistory && !inputWasString) {
    const turns = responsesItemsToTurns(inputItems);
    const profitable = (text: string, cols: number) =>
      evalOpenAIGate(req.model, text, cols, o.charsPerToken).profitable;
    const plan = await planGptCollapse(turns, firstUserIdx + 1, profitable, { ...o.gptHistory, reflow: o.reflow });
    foldGptHistory(info, req.model, plan);
    if (plan.images.length > 0) {
      const synthetic: ResponsesInputItem = {
        role: 'user',
        content: [
          { type: 'input_text', text: '[Earlier in this conversation:]' },
          ...plan.images.map(responsesImagePart),
          { type: 'input_text', text: '[End of earlier context.]' },
        ],
      };
      req.input = [
        ...inputItems.slice(0, plan.start),
        synthetic,
        ...inputItems.slice(plan.endExclusive),
      ];
      info.historyImageSha = await sha8(
        plan.images.map((i) => bytesToBase64(i.png)).join(''),
      );
    }
  }

  if (rewrittenTools !== undefined) req.tools = rewrittenTools;

  info.compressed = true;
  return { body: new TextEncoder().encode(JSON.stringify(req)), info };
}
