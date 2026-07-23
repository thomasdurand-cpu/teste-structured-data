import { createServerFn } from "@tanstack/react-start";
import { createClient } from "@supabase/supabase-js";
import type { Database } from "@/integrations/supabase/types";
import { z } from "zod";
import { tryDeterministic, extractTimeRange, type DpdLite } from "./deterministic-extractors";


// --------- Pricing table (rough; per 1M tokens, USD) ----------
const PRICING: Record<string, { in: number; out: number }> = {
  "google/gemini-3-flash-preview": { in: 0.1, out: 0.4 },
  "google/gemini-3.1-flash-lite": { in: 0.05, out: 0.2 },
  "google/gemini-3.5-flash": { in: 0.1, out: 0.4 },
  "google/gemini-2.5-flash": { in: 0.075, out: 0.3 },
  "google/gemini-2.5-pro": { in: 1.25, out: 5 },
  "openai/gpt-5-mini": { in: 0.25, out: 2 },
  "openai/gpt-5-nano": { in: 0.05, out: 0.4 },
  "deepseek/deepseek-v4-flash": { in: 0.098, out: 0.196 },
};

function estimateCost(model: string, inT: number, outT: number) {
  const p = PRICING[model] ?? { in: 0.1, out: 0.4 };
  return (inT * p.in + outT * p.out) / 1_000_000;
}

function getSb() {
  return createClient<Database>(
    process.env.SUPABASE_URL!,
    process.env.SUPABASE_PUBLISHABLE_KEY!,
    { auth: { storage: undefined, persistSession: false, autoRefreshToken: false } },
  );
}

// Extraction over many chunks/topics means many sequential real LLM calls — a single run
// can take well beyond typical platform request timeouts, which kills the process without
// ever reaching its own catch block. That leaves extraction_runs stuck at status='running'
// forever, and — without this guard — a second run can start concurrently against the same
// project, hammering the same OpenRouter key and causing rate-limit failures in both.
const STALE_RUN_MS = 10 * 60 * 1000;

async function guardConcurrentExtraction(sb: ReturnType<typeof getSb>, projectId: string) {
  const { data: active } = await sb
    .from("extraction_runs")
    .select("id, started_at")
    .eq("project_id", projectId)
    .eq("status", "running")
    .order("started_at", { ascending: false })
    .limit(1)
    .maybeSingle();
  if (!active) return;

  const age = Date.now() - new Date(active.started_at).getTime();
  if (age < STALE_RUN_MS) {
    throw new Error("Já existe uma extração em andamento para este projeto. Aguarde ela terminar antes de iniciar outra.");
  }

  // Older than the staleness window: the process that owned this run is essentially
  // certain to have been killed by the platform before it could report its own outcome.
  // Reclaim it so a legitimate new run isn't blocked forever by a row nobody will finish.
  await sb.from("extraction_runs").update({
    status: "failed",
    finished_at: new Date().toISOString(),
    error: "Run abandonado: excedeu o tempo limite sem concluir (provável timeout da plataforma).",
  }).eq("id", active.id);
}

// The UI lets the user request cancellation by flipping this row's status directly
// (RLS-open table, same pattern already used for progress polling). Extraction itself
// is a single long-running server call with no other cancellation channel, so we poll
// our own run row between topics/batches and stop cooperatively once we see it.
async function isRunCancelled(sb: ReturnType<typeof getSb>, runId: string): Promise<boolean> {
  const { data } = await sb.from("extraction_runs").select("status").eq("id", runId).maybeSingle();
  return data?.status === "cancelled";
}

type GatewayResult = {
  content: string;
  inputTokens: number;
  outputTokens: number;
  latency: number;
};

async function callGateway(opts: {
  model: string;
  temperature: number;
  maxTokens: number;
  system?: string;
  user: string;
  jsonMode?: boolean;
}): Promise<GatewayResult> {
  const apiKey = process.env.OPENROUTER_API_KEY;
  if (!apiKey) throw new Error("OPENROUTER_API_KEY not configured");

  const messages: Array<{ role: string; content: string }> = [];
  if (opts.system) messages.push({ role: "system", content: opts.system });
  messages.push({ role: "user", content: opts.user });

  const body: Record<string, unknown> = {
    model: opts.model,
    messages,
    temperature: opts.temperature,
    max_tokens: opts.maxTokens,
  };
  if (opts.jsonMode) body.response_format = { type: "json_object" };

  const t0 = Date.now();
  const res = await fetch("https://openrouter.ai/api/v1/chat/completions", {
    method: "POST",
    headers: { "content-type": "application/json", "Authorization": `Bearer ${apiKey}` },
    body: JSON.stringify(body),
  });
  const latency = Date.now() - t0;

  if (!res.ok) {
    const text = await res.text();
    if (res.status === 429) throw new Error("Rate limit excedido. Tente novamente em instantes.");
    if (res.status === 402) throw new Error("Créditos insuficientes na conta OpenRouter.");
    throw new Error(`Gateway error ${res.status}: ${text.slice(0, 300)}`);
  }
  const json = (await res.json()) as {
    choices: Array<{ message: { content: string } }>;
    usage?: { prompt_tokens?: number; completion_tokens?: number };
  };
  return {
    content: json.choices[0]?.message?.content ?? "",
    inputTokens: json.usage?.prompt_tokens ?? 0,
    outputTokens: json.usage?.completion_tokens ?? 0,
    latency,
  };
}

function parseJsonLenient(text: string): unknown {
  let s = text.trim();
  if (s.startsWith("```")) {
    s = s.replace(/^```(?:json)?\s*/i, "").replace(/```\s*$/, "").trim();
  }
  const first = s.indexOf("{");
  const last = s.lastIndexOf("}");
  if (first >= 0 && last > first) s = s.slice(first, last + 1);
  return JSON.parse(s);
}

// ----- topic classification (alias-first, LLM fallback) -----
type TopicLite = {
  topicId: string;
  defId: string;
  slug: string;
  name: string;
  description: string;
  aliases: string[];
};

function aliasMatch(chunk: string, topics: TopicLite[]): string[] {
  const text = " " + chunk.toLowerCase().normalize("NFD").replace(/[\u0300-\u036f]/g, "") + " ";
  const found = new Set<string>();
  for (const t of topics) {
    const candidates = [t.slug, t.name, ...t.aliases].filter(Boolean);
    for (const kw of candidates) {
      const norm = kw.toLowerCase().normalize("NFD").replace(/[\u0300-\u036f]/g, "");
      if (norm.length < 3) continue;
      // word-boundary-ish match
      const re = new RegExp(`[^a-z0-9]${norm.replace(/[.*+?^${}()|[\]\\]/g, "\\$&")}[^a-z0-9]`);
      if (re.test(text)) { found.add(t.slug); break; }
    }
  }
  return Array.from(found);
}

async function classifyChunkWithLLM(
  chunk: string,
  topics: TopicLite[],
  model: string,
  temperature: number,
): Promise<{ slugs: string[]; inT: number; outT: number; latency: number; cost: number }> {
  const list = topics.map((t) => `- ${t.slug}: ${t.description || t.name}`).join("\n");
  const sys =
    "Você classifica trechos de texto em tópicos hoteleiros. Responda EXCLUSIVAMENTE com JSON {\"topics\":[\"slug1\",\"slug2\"]}. Use somente os slugs listados. Se nenhum tópico se aplica, devolva [].";
  const user = `TÓPICOS DISPONÍVEIS:\n${list}\n\nTEXTO:\n"""${chunk.slice(0, 1200)}"""`;
  const res = await callGateway({
    model, temperature, maxTokens: 200, system: sys, user, jsonMode: true,
  });
  let slugs: string[] = [];
  try {
    const parsed = parseJsonLenient(res.content) as { topics?: unknown };
    if (Array.isArray(parsed.topics)) {
      slugs = parsed.topics.filter((s): s is string => typeof s === "string");
    }
  } catch { /* ignore */ }
  const valid = new Set(topics.map((t) => t.slug));
  slugs = slugs.filter((s) => valid.has(s));
  return {
    slugs,
    inT: res.inputTokens,
    outT: res.outputTokens,
    latency: res.latency,
    cost: estimateCost(model, res.inputTokens, res.outputTokens),
  };
}

// Batch version: classifies many chunks against the full topic list in a single call.
// Used to replace plain word-matching (aliasMatch) with real semantic classification —
// aliasMatch produces heavy false positives for generic alias words (e.g. "spa" matching
// every page because the hotel's own name contains it). Results are cached by the caller
// (raw_chunks.metadata) so this only runs once per chunk, ever.
async function classifyChunksBatchLLM(
  items: Array<{ id: string; content: string }>,
  topics: TopicLite[],
  model: string,
  temperature: number,
): Promise<{ result: Map<string, string[]>; inT: number; outT: number }> {
  const topicList = topics.map((t) => `- ${t.slug}: ${t.description || t.name}`).join("\n");
  const numbered = items.map((c, i) => `[${i}] ${c.content.slice(0, 500)}`).join("\n---\n");
  const sys = [
    "Você classifica trechos de texto de um site de hotel em zero ou mais tópicos, com base no CONTEÚDO REAL do trecho.",
    "IGNORE menus de navegação, links de rodapé, banners de cookies e menções incidentais (ex: o nome do hotel conter 'Spa' não significa que o trecho é sobre o tópico massagem).",
    "Responda APENAS com JSON: {\"classifications\":[{\"i\":0,\"topics\":[\"slug1\"]},...]}. Use somente os slugs da lista de tópicos.",
    "Inclua uma entrada para CADA índice recebido, mesmo que topics seja uma lista vazia.",
  ].join("\n");
  const user = `TÓPICOS DISPONÍVEIS:\n${topicList}\n\nTRECHOS (classifique cada um pelo índice):\n${numbered}`;
  const res = await callGateway({ model, temperature, maxTokens: 2000, system: sys, user, jsonMode: true });
  const result = new Map<string, string[]>();
  const validSlugs = new Set(topics.map((t) => t.slug));
  try {
    const parsed = parseJsonLenient(res.content) as { classifications?: Array<{ i?: number; topics?: unknown }> };
    for (const c of parsed.classifications ?? []) {
      if (typeof c.i !== "number" || !items[c.i]) continue;
      const slugs = Array.isArray(c.topics)
        ? c.topics.filter((s): s is string => typeof s === "string" && validSlugs.has(s))
        : [];
      result.set(items[c.i].id, slugs);
    }
  } catch (e) {
    console.error("classifyChunksBatchLLM parse failed", e);
  }
  // Anything the model didn't return an entry for is cached as "no topics" — otherwise
  // a chunk with no match would be re-classified (and re-billed) on every future run.
  for (const it of items) if (!result.has(it.id)) result.set(it.id, []);
  return { result, inT: res.inputTokens, outT: res.outputTokens };
}

// ----- Per (chunk, topic) extraction schema -----
const CoreFieldSchema = z.object({
  field_name: z.string(),
  field_value: z.any(),
  confidence: z.number().min(0).max(1).optional(),
});
const DynamicFieldSchema = z.object({
  field_name: z.string(),
  field_type: z.enum(["text", "boolean", "number", "currency", "time", "time_range", "multi_select"]),
  field_value: z.any(),
  confidence: z.number().min(0).max(1).optional(),
});
const ExtractionSchema = z.object({
  core_fields: z.array(CoreFieldSchema).default([]),
  dynamic_fields: z.array(DynamicFieldSchema).default([]),
  additional_information: z.array(z.string()).default([]),
});
type Extraction = z.infer<typeof ExtractionSchema>;


function renderPrompt(tmpl: string, vars: Record<string, string>): string {
  return tmpl.replace(/\{\{(\w+)\}\}/g, (_, k) => vars[k] ?? "");
}

function isEmptyValue(v: unknown): boolean {
  if (v === null || v === undefined) return true;
  if (typeof v === "string" && v.trim() === "") return true;
  if (Array.isArray(v) && v.length === 0) return true;
  return false;
}

function canonicalValue(v: unknown): string {
  if (v === null || v === undefined) return "";
  if (typeof v === "object") return JSON.stringify(v);
  return String(v).trim().toLowerCase();
}

function toPlainTextValue(v: unknown): string {
  if (v === null || v === undefined) return "";
  if (typeof v === "object") return JSON.stringify(v);
  return String(v).trim();
}

function normalizeForMatch(s: string): string {
  return s.toLowerCase().normalize("NFD").replace(/[\u0300-\u036f]/g, "");
}

function sentenceSplit(text: string): string[] {
  return text
    .replace(/\s+/g, " ")
    .split(/(?<=[.!?])\s+/)
    .map((s) => s.trim())
    .filter(Boolean);
}

function sentenceMentionsTimePair(sentence: string, start: string, end: string): boolean {
  const norm = normalizeForMatch(sentence);
  const [sh, sm] = start.split(":");
  const [eh, em] = end.split(":");
  const startHour = String(Number(sh));
  const endHour = String(Number(eh));
  const startPatterns = [start, `${startHour}h`, `${startHour}h${sm}`, `${sh}h`, `${sh}h${sm}`].map(normalizeForMatch);
  const endPatterns = [end, `${endHour}h`, `${endHour}h${em}`, `${eh}h`, `${eh}h${em}`].map(normalizeForMatch);
  return startPatterns.some((p) => norm.includes(p)) && endPatterns.some((p) => norm.includes(p));
}

function removeCoreFactsFromAdditionalInfo(
  text: string,
  topicSlug: string,
  coreValues: Map<string, { value: unknown; chunkIds: string[] }>,
): string {
  if (!text.trim()) return "";
  const start = toPlainTextValue(coreValues.get(`${topicSlug}_start_time`)?.value);
  const end = toPlainTextValue(coreValues.get(`${topicSlug}_end_time`)?.value);
  const location = toPlainTextValue(coreValues.get(`${topicSlug}_location`)?.value);
  const price = toPlainTextValue(coreValues.get(`${topicSlug}_price`)?.value);
  const available = coreValues.get(`${topicSlug}_available`)?.value;

  const cleaned = sentenceSplit(text).filter((sentence) => {
    const norm = normalizeForMatch(sentence);
    if (start && end && sentenceMentionsTimePair(sentence, start, end)) return false;
    if (price && normalizeForMatch(price).length > 1 && norm.includes(normalizeForMatch(price))) return false;
    if (location) {
      const loc = normalizeForMatch(location);
      if (loc.length > 8 && norm.includes(loc)) return false;
      if (topicSlug === "breakfast" && norm.includes("3o andar") && norm.includes("cafe")) return false;
    }
    if (available === true && topicSlug === "breakfast" && /inclus|gratuit|incluid|incluí/.test(norm)) return false;
    return true;
  });

  return cleaned.join(" ").trim();
}

function topicRelevantSnippet(text: string, topic: TopicLite): string {
  const sentences = sentenceSplit(text);
  if (sentences.length <= 2) return text;

  const keep = new Set<number>();
  sentences.forEach((sentence, index) => {
    if (aliasMatch(sentence, [topic]).length > 0) {
      keep.add(index);
      if (index + 1 < sentences.length) keep.add(index + 1);
    }
  });

  if (keep.size === 0) return text;
  return Array.from(keep)
    .sort((a, b) => a - b)
    .map((index) => sentences[index])
    .join(" ")
    .trim();
}

// --- Sanity bounds for time-type fields ---
function timeToMinutes(t: string): number | null {
  const m = /^(\d{1,2}):(\d{2})$/.exec(String(t).trim());
  if (!m) return null;
  const h = Number(m[1]); const min = Number(m[2]);
  if (h < 0 || h > 23 || min < 0 || min > 59) return null;
  return h * 60 + min;
}
// [minHour, maxHour] inclusive — semantics by topic/field name.
function expectedTimeBounds(topicSlug: string, fieldName: string): [number, number] | null {
  const n = (fieldName || "").toLowerCase();
  const s = (topicSlug || "").toLowerCase();
  if (s.includes("breakfast") || n.includes("breakfast") || n.includes("cafe") || n.includes("café")) return [4, 13];
  if (n.includes("checkout") || n.includes("check_out") || s.includes("checkout")) return [4, 14];
  if (n.includes("checkin")  || n.includes("check_in")  || s.includes("checkin"))  return [10, 23];
  if (n.includes("lunch")    || n.includes("almoco")    || n.includes("almoço"))   return [10, 16];
  if (n.includes("dinner")   || n.includes("jantar"))                              return [17, 23];
  if (n.includes("pool")     || s.includes("pool")      || n.includes("piscina"))  return [6, 22];
  if (n.includes("gym")      || s.includes("gym")       || n.includes("academia")) return [5, 23];
  if (n.includes("spa")      || s.includes("spa"))                                 return [8, 22];
  return null;
}
function isSaneTime(value: unknown, topicSlug: string, fieldName: string): boolean {
  if (value == null) return true;
  const v = typeof value === "string" ? value : (typeof value === "object" ? "" : String(value));
  const mins = timeToMinutes(v);
  if (mins == null) return true; // not a HH:MM string — let upstream handle
  const b = expectedTimeBounds(topicSlug, fieldName);
  if (!b) return true;
  const h = mins / 60;
  return h >= b[0] && h <= b[1];
}
function isSaneTimeRange(range: { start: string; end: string }, topicSlug: string, fieldStart: string, fieldEnd: string): boolean {
  return isSaneTime(range.start, topicSlug, fieldStart) && isSaneTime(range.end, topicSlug, fieldEnd);
}

async function assertDb<T>(
  op: PromiseLike<{ data: T | null; error: { message: string } | null }>,
  label: string,
): Promise<T | null> {
  const { data, error } = await op;
  if (error) throw new Error(`${label}: ${error.message}`);
  return data;
}

// ----- Field-name normalization (used to dedupe dynamic vs core) -----
const PT_STOPWORDS = new Set(["de", "da", "do", "das", "dos", "a", "o", "e", "em", "para", "the", "of"]);
function normalizeFieldKey(s: string): string {
  return (s ?? "")
    .toLowerCase()
    .normalize("NFD").replace(/[\u0300-\u036f]/g, "")
    .replace(/[^a-z0-9]+/g, "");
}
function tokensFieldKey(s: string): string {
  return (s ?? "")
    .toLowerCase()
    .normalize("NFD").replace(/[\u0300-\u036f]/g, "")
    .split(/[^a-z0-9]+/)
    .filter((t) => t && !PT_STOPWORDS.has(t))
    .join("");
}
function fieldKeyVariants(s: string): string[] {
  const set = new Set<string>();
  const n = normalizeFieldKey(s);
  const t = tokensFieldKey(s);
  if (n) set.add(n);
  if (t) set.add(t);
  return Array.from(set);
}

// =====================================================
// runExtraction (Etapa 2 — DataPoint-aware)
// =====================================================
export const runExtraction = createServerFn({ method: "POST" })
  .inputValidator((input: {
    projectId: string;
    mode: "dry_run" | "persist";
    chunkIds?: string[];
    modelOverride?: { model?: string; temperature?: number; maxTokens?: number };
  }) => input)
  .handler(async ({ data }) => {
    const sb = getSb();



    // Project + sources + chunks
    const { data: project } = await sb
      .from("projects").select("id, name").eq("id", data.projectId).maybeSingle();
    if (!project) throw new Error("Projeto não encontrado");

    await guardConcurrentExtraction(sb, data.projectId);

    const { data: sources } = await sb
      .from("raw_sources").select("id").eq("project_id", data.projectId);
    const sourceIds = (sources ?? []).map((s) => s.id);
    if (sourceIds.length === 0) throw new Error("Nenhuma fonte bruta. Faça upload de um CSV primeiro.");

    // Settings
    const { data: settings } = await sb
      .from("extraction_settings").select("*").limit(1).maybeSingle();
    if (!settings) throw new Error("Configuração de extração ausente.");

    const { data: modelCfg } = await sb
      .from("model_configurations").select("*").eq("active", true)
      .order("created_at", { ascending: false }).limit(1).maybeSingle();
    if (!modelCfg) throw new Error("Nenhum modelo ativo configurado.");

    const effModel = data.modelOverride?.model?.trim() || modelCfg.model_name;
    const effTemp = data.modelOverride?.temperature ?? Number(settings.temperature);
    const effMaxTokens = data.modelOverride?.maxTokens ?? modelCfg.max_tokens;
    const unifiedPrompt = (settings as { unified_prompt?: string | null }).unified_prompt?.trim()
      || `${settings.system_prompt ?? ""}\n\n${settings.extraction_prompt ?? ""}`.trim();

    let chunkQuery = sb
      .from("raw_chunks").select("id, content").in("raw_source_id", sourceIds).order("position");
    if (data.chunkIds && data.chunkIds.length > 0) {
      chunkQuery = sb
        .from("raw_chunks").select("id, content").in("id", data.chunkIds).order("position");
    }
    const { data: chunksRaw } = await chunkQuery;
    const allChunks = chunksRaw ?? [];
    const chunks = data.chunkIds && data.chunkIds.length > 0 ? allChunks : allChunks.slice(0, settings.max_chunks);

    if (chunks.length === 0) throw new Error("Nenhum chunk encontrado.");

    // Topics in this project (with definitions + aliases)
    const { data: topicsRaw } = await sb
      .from("topics")
      .select("id, topic_definition_id, topic_definitions(slug, name, description, aliases)")
      .eq("project_id", data.projectId);
    const topics: TopicLite[] = (topicsRaw ?? []).map((t) => {
      const td = t.topic_definitions as {
        slug: string; name: string; description: string | null; aliases: string[];
      } | null;
      return {
        topicId: t.id,
        defId: t.topic_definition_id,
        slug: td?.slug ?? "",
        name: td?.name ?? "",
        description: td?.description ?? "",
        aliases: td?.aliases ?? [],
      };
    });
    if (topics.length === 0) throw new Error("Nenhum tópico ativo. Ative tópicos na aba Topics.");
    const topicBySlug = new Map(topics.map((t) => [t.slug, t]));

    // Data point definitions (only for active definitions)
    const defIds = topics.map((t) => t.defId);
    const { data: dpdRaw } = await sb
      .from("data_point_definitions").select("*").in("topic_definition_id", defIds).eq("active", true);
    type DpdFull = DpdLite & { field_label: string; description: string | null };
    const dpdByDefId = new Map<string, DpdFull[]>();
    for (const d of dpdRaw ?? []) {
      const list = dpdByDefId.get(d.topic_definition_id) ?? [];
      list.push({
        field_name: d.field_name,
        field_label: d.field_label,
        field_type: d.field_type,
        description: d.description,
        // eslint-disable-next-line @typescript-eslint/no-explicit-any
        extraction_strategy: (d as any).extraction_strategy ?? null,
        // eslint-disable-next-line @typescript-eslint/no-explicit-any
        regex_pattern: (d as any).regex_pattern ?? null,
        // eslint-disable-next-line @typescript-eslint/no-explicit-any
        keywords: (d as any).keywords ?? {},
        // eslint-disable-next-line @typescript-eslint/no-explicit-any
        negative_keywords: (d as any).negative_keywords ?? [],
      });
      dpdByDefId.set(d.topic_definition_id, list);
    }

    // Re-extraction never reuses or merges with previously stored data: before the extraction
    // agent runs, wipe all structured data for every topic this run will touch — regardless of
    // whether the raw source is the same CSV as last time or brand new content. Scoped to
    // persist mode only — a dry_run never writes data, so there is nothing to repopulate.
    if (data.mode === "persist") {
      const topicIds = topics.map((t) => t.topicId);
      await assertDb(sb.from("knowledge_fields").delete().in("topic_id", topicIds), "Apagar campos estruturados anteriores");
      await assertDb(sb.from("additional_info").delete().in("topic_id", topicIds), "Apagar informações adicionais anteriores");
      await assertDb(
        sb.from("knowledge_candidates").delete().eq("project_id", data.projectId).in("topic_definition_id", defIds),
        "Apagar candidatos anteriores",
      );
      await assertDb(
        sb.from("knowledge_conflicts").delete().eq("project_id", data.projectId).in("topic_definition_id", defIds),
        "Apagar conflitos anteriores",
      );
    }

    // Create the extraction_run row
    const { data: run, error: runErr } = await sb
      .from("extraction_runs")
      .insert({
        project_id: data.projectId,
        raw_source_ids: sourceIds,
        mode: data.mode,
        model_configuration_id: modelCfg.id,
        status: "running",
        started_at: new Date().toISOString(),
      })
      .select("*").single();
    if (runErr || !run) throw new Error(runErr?.message ?? "Falha ao criar run");

    // Aggregation buckets per topic
    type ExtractionMethod = "regex" | "keyword" | "llm";
    type TopicAggregate = {
      topic_slug: string;
      topic_name: string;
      topic_def_id: string;
      // eslint-disable-next-line @typescript-eslint/no-explicit-any
      core_fields: Array<{ field_name: string; field_value: any; confidence?: number; source_chunk_ids: string[]; extraction_method: ExtractionMethod }>;
      // eslint-disable-next-line @typescript-eslint/no-explicit-any
      dynamic_fields: Array<{ field_name: string; field_type: string; field_value: any; confidence?: number; source_chunk_ids: string[]; extraction_method: ExtractionMethod }>;

      additional_information: Array<{ content: string; source_chunk_ids: string[] }>;
    };
    const agg = new Map<string, TopicAggregate>();
    for (const t of topics) {
      agg.set(t.slug, {
        topic_slug: t.slug,
        topic_name: t.name,
        topic_def_id: t.defId,
        core_fields: [],
        dynamic_fields: [],
        additional_information: [],
      });
    }

    let totalIn = 0, totalOut = 0, totalCost = 0, totalLatency = 0;
    const chunkTopicMap: Record<string, { matched: string[]; via: "alias" | "llm" | "none" }> = {};
    const classifyCalls = { alias: 0, llm: 0, none: 0 };
    const detStats = {
      regex_fields: 0,
      keyword_fields: 0,
      llm_fields: 0,
      chunks_skipped_llm: 0,
      chunks_sent_to_llm: 0,
      estimated_llm_calls_saved: 0,
    };
    const useLlmForDynamic = (settings as { use_llm_for_dynamic?: boolean }).use_llm_for_dynamic ?? true;


    try {
      for (const chunk of chunks) {
        // Step 1: alias classification
        let matched = aliasMatch(chunk.content, topics);
        let via: "alias" | "llm" | "none" = "alias";
        if (matched.length === 0) {
          // Step 2: LLM classification
          const c = await classifyChunkWithLLM(chunk.content, topics, effModel, effTemp);
          totalIn += c.inT; totalOut += c.outT; totalCost += c.cost; totalLatency += c.latency;
          await sb.from("llm_calls").insert({
            prompt_type: "classify",
            model_name: effModel,
            input_tokens: c.inT, output_tokens: c.outT, latency: c.latency, estimated_cost: c.cost,
            extraction_run_id: run.id,
          });
          matched = c.slugs;
          via = matched.length > 0 ? "llm" : "none";
        }
        chunkTopicMap[chunk.id] = { matched, via };
        classifyCalls[via]++;

        if (matched.length === 0) continue;

        // Step 3: per (chunk, topic) extraction
        for (const slug of matched) {
          const topic = topicBySlug.get(slug);
          if (!topic) continue;
          const dps = dpdByDefId.get(topic.defId) ?? [];
          const bucket = agg.get(slug)!;

          // 3a) Deterministic pass on every DPD (regex/keyword/hybrid).
          const resolvedCore = new Set<string>();
          for (const d of dps) {
            const det = tryDeterministic(d, chunk.content);
            if (det) {
              bucket.core_fields.push({
                field_name: d.field_name,
                field_value: det.value,
                confidence: 0.95,
                source_chunk_ids: [chunk.id],
                extraction_method: det.method,
              });
              resolvedCore.add(d.field_name);
              if (det.method === "regex") detStats.regex_fields++;
              else detStats.keyword_fields++;
            }
          }

          // 3b) Decide if we need LLM at all for this (chunk, topic).
          const unresolvedDps = dps.filter((d) => !resolvedCore.has(d.field_name));
          // Strategies that still want LLM when unresolved: 'hybrid' (no det match) or 'llm'.
          const unresolvedNeedsLLM = unresolvedDps.filter((d) => {
            const strat = d.extraction_strategy ?? null;
            if (strat === "regex" || strat === "keyword") return false; // strict — no LLM fallback
            return true; // hybrid + llm + null(default text/multi_select → llm)
          });
          const needLLM = unresolvedNeedsLLM.length > 0 || useLlmForDynamic;

          if (!needLLM) {
            detStats.chunks_skipped_llm++;
            detStats.estimated_llm_calls_saved++;
            continue;
          }
          detStats.chunks_sent_to_llm++;

          // 3c) Build prompt — only list DPs the LLM should still try.
          const llmDpBlock = unresolvedNeedsLLM.length === 0
            ? "(todos os data points oficiais já foram preenchidos por regra determinística — extraia somente dynamic_fields e additional_information)"
            : unresolvedNeedsLLM.map((d) => `- ${d.field_name} (${d.field_type})${d.description ? `: ${d.description}` : ""}`).join("\n");

          const userPrompt = renderPrompt(unifiedPrompt, {
            topic_slug: topic.slug,
            topic_name: topic.name,
            topic_description: topic.description,
            data_points: llmDpBlock,
            chunk: chunk.content,
          });

          const res = await callGateway({
            model: effModel,
            temperature: effTemp,
            maxTokens: effMaxTokens,
            user: userPrompt,
            jsonMode: true,
          });
          const cost = estimateCost(effModel, res.inputTokens, res.outputTokens);
          totalIn += res.inputTokens; totalOut += res.outputTokens;
          totalCost += cost; totalLatency += res.latency;

          await sb.from("llm_calls").insert({
            prompt_type: `extract:${topic.slug}`,
            model_name: effModel,
            input_tokens: res.inputTokens,
            output_tokens: res.outputTokens,
            latency: res.latency,
            estimated_cost: cost,
            extraction_run_id: run.id,
          });

          let parsed: Extraction = { core_fields: [], dynamic_fields: [], additional_information: [] };
          try {
            parsed = ExtractionSchema.parse(parseJsonLenient(res.content));
          } catch (e) {
            console.error("Parse fail", topic.slug, chunk.id, e);
          }

          const allowedCore = new Set(dps.map((d) => d.field_name));
          // Build alias index: normalized variant -> canonical field_name
          const coreAlias = new Map<string, string>();
          for (const d of dps) {
            for (const v of fieldKeyVariants(d.field_name)) coreAlias.set(v, d.field_name);
            for (const v of fieldKeyVariants(d.field_label)) coreAlias.set(v, d.field_name);
          }
          const resolveToCore = (name: string): string | null => {
            if (allowedCore.has(name)) return name;
            for (const v of fieldKeyVariants(name)) {
              const hit = coreAlias.get(v);
              if (hit) return hit;
            }
            return null;
          };

          for (const f of parsed.core_fields) {
            if (isEmptyValue(f.field_value)) continue;
            const canonical = resolveToCore(f.field_name);
            if (!canonical) continue;
            if (resolvedCore.has(canonical)) continue; // deterministic wins
            bucket.core_fields.push({
              field_name: canonical,
              field_value: f.field_value,
              confidence: f.confidence,
              source_chunk_ids: [chunk.id],
              extraction_method: "llm",
            });
            detStats.llm_fields++;
          }
          if (useLlmForDynamic) {
            for (const f of parsed.dynamic_fields) {
              if (isEmptyValue(f.field_value)) continue;
              // If the dynamic name matches a core field (exact or via normalized variants), promote to core.
              const canonical = resolveToCore(f.field_name);
              if (canonical) {
                if (resolvedCore.has(canonical)) continue;
                if (bucket.core_fields.some((c) => c.field_name === canonical && c.source_chunk_ids[0] === chunk.id)) continue;
                bucket.core_fields.push({
                  field_name: canonical,
                  field_value: f.field_value,
                  confidence: f.confidence,
                  source_chunk_ids: [chunk.id],
                  extraction_method: "llm",
                });
                detStats.llm_fields++;
                continue;
              }
              bucket.dynamic_fields.push({
                field_name: f.field_name,
                field_type: f.field_type,
                field_value: f.field_value,
                confidence: f.confidence,
                source_chunk_ids: [chunk.id],
                extraction_method: "llm",
              });
              detStats.llm_fields++;
            }
            for (const text of parsed.additional_information) {
              const t = (text ?? "").trim();
              if (!t) continue;
              bucket.additional_information.push({ content: t, source_chunk_ids: [chunk.id] });
            }
          }
        }
      }

      // Build preview shape

      const previewTopics = Array.from(agg.values())
        .filter((b) => b.core_fields.length > 0 || b.dynamic_fields.length > 0 || b.additional_information.length > 0)
        .map((b) => ({
          topic_slug: b.topic_slug,
          topic_name: b.topic_name,
          core_fields: b.core_fields,
          dynamic_fields: b.dynamic_fields,
          additional_information: b.additional_information,
        }));

      const totalCore = previewTopics.reduce((s, t) => s + t.core_fields.length, 0);
      const totalDyn = previewTopics.reduce((s, t) => s + t.dynamic_fields.length, 0);
      const totalAdd = previewTopics.reduce((s, t) => s + t.additional_information.length, 0);

      const stats = {
        chunks_processed: chunks.length,
        chunks_total: allChunks.length,
        topics_with_data: previewTopics.length,
        core_fields_found: totalCore,
        dynamic_fields_found: totalDyn,
        additional_info_found: totalAdd,
        input_tokens: totalIn,
        output_tokens: totalOut,
        estimated_cost: totalCost,
        latency_ms: totalLatency,
        classify_alias_hits: classifyCalls.alias,
        classify_llm_calls: classifyCalls.llm,
        classify_unmatched: classifyCalls.none,
        deterministic_extraction: detStats,
      };


      // ---- Persist mode (Etapa 4): salva apenas candidates + additional_info pending.
      //  Consolidação em KnowledgeFields é responsabilidade de consolidateKnowledge.
      let persisted = { candidates: 0, additional_info: 0 };
      if (data.mode === "persist") {
        for (const t of previewTopics) {
          const topic = topicBySlug.get(t.topic_slug);
          if (!topic) continue;

          const allFields = [
            ...t.core_fields.map((f) => ({ ...f, field_type: "text", field_origin: "core" as const })),
            ...t.dynamic_fields.map((f) => ({ ...f, field_origin: "dynamic" as const })),
          ];

          for (const f of allFields) {
            await sb.from("knowledge_candidates").insert({
              project_id: data.projectId,
              extraction_run_id: run.id,
              topic_definition_id: topic.defId,
              field_name: f.field_name,
              field_type: f.field_type,
              field_value: (f.field_value ?? null) as never,
              field_origin: f.field_origin,
              confidence: f.confidence ?? null,
              source_chunk_ids: f.source_chunk_ids as never,
              status: "pending",
              extraction_method: f.extraction_method,
            } as never);
            persisted.candidates++;
          }

          // Additional info was already wiped for this topic above — dedupe within this run's
          // own results (a chunk can repeat the same fact across pages).
          const seenContent = new Set<string>();
          for (const a of t.additional_information) {
            const key = a.content.trim().toLowerCase();
            if (seenContent.has(key)) continue;
            seenContent.add(key);
            await sb.from("additional_info").insert({
              topic_id: topic.topicId,
              content: a.content,
              source_chunk_ids: a.source_chunk_ids as never,
              status: "pending",
            } as never);
            persisted.additional_info++;
          }
        }
      }

      // --- Update raw_chunks.extraction_status (only in persist mode) ---
      if (data.mode === "persist") {
        const extractedChunkIds = new Set<string>();
        for (const b of agg.values()) {
          for (const f of b.core_fields) f.source_chunk_ids.forEach((id) => extractedChunkIds.add(id));
          for (const f of b.dynamic_fields) f.source_chunk_ids.forEach((id) => extractedChunkIds.add(id));
          for (const a of b.additional_information) a.source_chunk_ids.forEach((id) => extractedChunkIds.add(id));
        }
        const processedIds = chunks.map((c) => c.id);
        const noKnowledgeIds = processedIds.filter((id) => !extractedChunkIds.has(id));
        if (extractedChunkIds.size > 0) {
          await sb.from("raw_chunks").update({ extraction_status: "extracted" } as never)
            .in("id", Array.from(extractedChunkIds));
        }
        if (noKnowledgeIds.length > 0) {
          // Don't overwrite manually-marked irrelevant chunks
          await sb.from("raw_chunks").update({ extraction_status: "no_knowledge_found" } as never)
            .in("id", noKnowledgeIds)
            .neq("extraction_status", "marked_irrelevant");
        }
      }

      const preview = { topics: previewTopics, chunk_topics: chunkTopicMap, statistics: stats, persisted };


      await sb.from("extraction_runs").update({
        status: "done",
        finished_at: new Date().toISOString(),
        preview_result: preview as never,
        stats: stats as never,
      }).eq("id", run.id);

      return { runId: run.id, mode: data.mode, preview, stats, persisted };
    } catch (err) {
      const msg = err instanceof Error ? err.message : String(err);
      await sb.from("extraction_runs").update({
        status: "failed", finished_at: new Date().toISOString(), error: msg,
      }).eq("id", run.id);
      throw err;
    }
  });

// =====================================================
// Persist a previous dry-run by re-running in persist mode.
// (Simple version: starts a new persist run from current state.)
// =====================================================
export const persistRun = createServerFn({ method: "POST" })
  .inputValidator((input: { projectId: string }) => input)
  .handler(async ({ data }) => {
    return { ok: true, hint: "Use runExtraction com mode=persist", projectId: data.projectId };
  });

// =====================================================
// extractTopicAggregated — re-extracts one (or all) topics
// by aggregating ALL classified chunks per topic into a single
// LLM call. Writes results DIRECTLY into knowledge_fields
// (consolidated) and additional_info (approved). Every run wipes
// all previously stored structured data for the topic(s) it targets
// before extracting — re-extraction never merges with old data,
// whether the raw source is the same CSV as last time or brand new.
// =====================================================
export const extractTopicAggregated = createServerFn({ method: "POST" })
  .inputValidator((input: {
    projectId: string;
    topicSlug?: string;
    modelOverride?: { model?: string; temperature?: number; maxTokens?: number };
  }) => input)
  .handler(async ({ data }) => {
    const sb = getSb();

    const { data: project } = await sb
      .from("projects").select("id, name").eq("id", data.projectId).maybeSingle();
    if (!project) throw new Error("Projeto não encontrado");

    await guardConcurrentExtraction(sb, data.projectId);

    const { data: sources } = await sb
      .from("raw_sources").select("id").eq("project_id", data.projectId);
    const sourceIds = (sources ?? []).map((s) => s.id);
    if (sourceIds.length === 0) throw new Error("Sem fontes. Faça upload primeiro.");

    const { data: chunksRaw } = await sb
      .from("raw_chunks").select("id, content, metadata").in("raw_source_id", sourceIds).order("position");
    const allChunks = chunksRaw ?? [];
    if (allChunks.length === 0) throw new Error("Nenhum chunk encontrado.");

    // Dedup: scraped multi-page sources repeat verbatim boilerplate (cookie banners,
    // footers) on every page. Dropping exact duplicates is free (no LLM) and shrinks
    // both the deterministic pass and the number of LLM batches needed per topic below.
    const normalizeForDedup = (s: string) => s.trim().toLowerCase().replace(/\s+/g, " ");
    const seenContent = new Set<string>();
    const dedupedChunks = allChunks.filter((c) => {
      const key = normalizeForDedup(c.content);
      if (seenContent.has(key)) return false;
      seenContent.add(key);
      return true;
    });

    // Strip site-wide boilerplate lines (nav menus, footers) that recur verbatim across
    // many different pages. These cause false-positive alias matches — e.g. a "Spa & Leisure"
    // nav link makes every page containing that menu "match" the massage topic even when
    // unrelated — and waste tokens in the LLM prompt. Free (no LLM): a line counts as
    // boilerplate if it appears, as-is, in enough distinct chunks to be part of the site
    // template rather than real page content.
    const MIN_LINE_LEN = 15;
    const BOILERPLATE_MIN_CHUNKS = Math.max(5, Math.ceil(dedupedChunks.length * 0.03));
    const lineChunkCount = new Map<string, number>();
    for (const c of dedupedChunks) {
      const uniqueLines = new Set(
        c.content.split("\n").map((l) => l.trim()).filter((l) => l.length >= MIN_LINE_LEN),
      );
      for (const line of uniqueLines) {
        lineChunkCount.set(line, (lineChunkCount.get(line) ?? 0) + 1);
      }
    }
    const boilerplateLines = new Set(
      Array.from(lineChunkCount.entries())
        .filter(([, count]) => count >= BOILERPLATE_MIN_CHUNKS)
        .map(([line]) => line),
    );
    const chunks = boilerplateLines.size === 0
      ? dedupedChunks
      : dedupedChunks.map((c) => ({
          ...c,
          content: c.content.split("\n").filter((l) => !boilerplateLines.has(l.trim())).join("\n"),
        }));

    const { data: modelCfg } = await sb
      .from("model_configurations").select("*").eq("active", true)
      .order("created_at", { ascending: false }).limit(1).maybeSingle();
    if (!modelCfg) throw new Error("Nenhum modelo ativo configurado.");

    const effModel = data.modelOverride?.model?.trim() || modelCfg.model_name;
    const effTemp = data.modelOverride?.temperature ?? (Number(modelCfg.temperature) || 0.2);
    const effMaxTokens = data.modelOverride?.maxTokens ?? modelCfg.max_tokens;

    // Tracked in extraction_runs so guardConcurrentExtraction() can see this run too —
    // without this, "Re-extrair todos" and the legacy runExtraction flow could still run
    // concurrently against the same project, since only one of them wrote to this table.
    const { data: run, error: runErr } = await sb
      .from("extraction_runs")
      .insert({
        project_id: data.projectId,
        raw_source_ids: sourceIds,
        mode: "persist",
        model_configuration_id: modelCfg.id,
        status: "running",
        started_at: new Date().toISOString(),
      })
      .select("*").single();
    if (runErr || !run) throw new Error(runErr?.message ?? "Falha ao criar run");

    try {

    const { data: topicsRaw } = await sb
      .from("topics")
      .select("id, topic_definition_id, topic_definitions(slug, name, description, aliases)")
      .eq("project_id", data.projectId);

    const allTopics: TopicLite[] = (topicsRaw ?? []).map((t) => {
      const td = t.topic_definitions as {
        slug: string; name: string; description: string | null; aliases: string[];
      } | null;
      return {
        topicId: t.id,
        defId: t.topic_definition_id,
        slug: td?.slug ?? "",
        name: td?.name ?? "",
        description: td?.description ?? "",
        aliases: td?.aliases ?? [],
      };
    });
    if (allTopics.length === 0) throw new Error("Nenhum tópico encontrado.");

    // ---- Chunk → topic classification (LLM-based, cached in raw_chunks.metadata) ----
    // Replaces aliasMatch (plain word-matching) as the chunk-topic filter below. Classified
    // once against the FULL topic list (not just the topic(s) this run targets) so the
    // cache is reusable no matter which topic is re-extracted next. A chunk is only ever
    // classified once, ever — the result is persisted, so repeated "Re-extrair" runs incur
    // no further classification cost, only the per-topic extraction calls.
    const CLASSIFICATION_CACHE_KEY = "__topic_classification_v1";
    const CLASSIFY_BATCH_SIZE = 15;
    const chunkTopicMap = new Map<string, string[]>();
    const toClassify: typeof chunks = [];
    for (const c of chunks) {
      const meta = (c as { metadata?: unknown }).metadata as { [k: string]: unknown } | null;
      const cached = meta && typeof meta === "object" ? (meta[CLASSIFICATION_CACHE_KEY] as { slugs?: string[] } | undefined) : undefined;
      if (cached && Array.isArray(cached.slugs)) {
        chunkTopicMap.set(c.id, cached.slugs);
      } else {
        toClassify.push(c);
      }
    }
    for (let i = 0; i < toClassify.length; i += CLASSIFY_BATCH_SIZE) {
      const batch = toClassify.slice(i, i + CLASSIFY_BATCH_SIZE);
      // A single transient failure (e.g. rate limit on a free-tier key) must not abort the
      // whole run — leave this batch's chunks uncached and let a future run pick them up.
      try {
        const { result, inT, outT } = await classifyChunksBatchLLM(batch, allTopics, effModel, effTemp);
        await sb.from("llm_calls").insert({
          prompt_type: "classify_batch",
          model_name: effModel,
          input_tokens: inT, output_tokens: outT, latency: 0,
          estimated_cost: estimateCost(effModel, inT, outT),
        } as never);
        for (const c of batch) {
          const slugs = result.get(c.id) ?? [];
          chunkTopicMap.set(c.id, slugs);
          const meta = (c as { metadata?: unknown }).metadata;
          const baseMeta = meta && typeof meta === "object" && !Array.isArray(meta) ? meta as Record<string, unknown> : {};
          await sb.from("raw_chunks").update({
            metadata: { ...baseMeta, [CLASSIFICATION_CACHE_KEY]: { slugs, at: new Date().toISOString() } },
          } as never).eq("id", c.id);
        }
      } catch (e) {
        console.error("classifyChunksBatchLLM batch failed, skipping (will retry next run)", e);
      }
      // Small pacing delay between batches — free-tier keys are commonly rate-limited per minute.
      await new Promise((resolve) => setTimeout(resolve, 1000));
    }

    let topics: TopicLite[] = allTopics;
    if (data.topicSlug) topics = topics.filter((t) => t.slug === data.topicSlug);
    if (topics.length === 0) throw new Error("Nenhum tópico encontrado.");

    const defIds = topics.map((t) => t.defId);
    const { data: dpdRaw } = await sb
      .from("data_point_definitions").select("*").in("topic_definition_id", defIds).eq("active", true);
    type DpdFull = DpdLite & { field_label: string; description: string | null };
    const dpdByDefId = new Map<string, DpdFull[]>();
    for (const d of dpdRaw ?? []) {
      const list = dpdByDefId.get(d.topic_definition_id) ?? [];
      list.push({
        field_name: d.field_name,
        field_label: d.field_label,
        field_type: d.field_type,
        description: d.description,
        // eslint-disable-next-line @typescript-eslint/no-explicit-any
        extraction_strategy: (d as any).extraction_strategy ?? null,
        // eslint-disable-next-line @typescript-eslint/no-explicit-any
        regex_pattern: (d as any).regex_pattern ?? null,
        // eslint-disable-next-line @typescript-eslint/no-explicit-any
        keywords: (d as any).keywords ?? {},
        // eslint-disable-next-line @typescript-eslint/no-explicit-any
        negative_keywords: (d as any).negative_keywords ?? [],
      });
      dpdByDefId.set(d.topic_definition_id, list);
    }

    const CHUNK_CAP = 25;
    const CHUNK_CHAR_CAP = 1600;
    const MAX_BATCHES = 4; // safety cap: up to CHUNK_CAP*MAX_BATCHES chunks sent to the LLM per topic
    const result: Array<{
      topic_slug: string;
      core_filled: number;
      core_total: number;
      additional_info_chars: number;
      chunks_used: number;
      input_tokens: number;
      output_tokens: number;
    }> = [];

    let cancelled = false;
    for (const topic of topics) {
      // Checked before touching this topic's data at all — if the user cancelled, leave
      // this (and every remaining) topic exactly as it was rather than wiping it for
      // work that will never run.
      if (await isRunCancelled(sb, run.id)) { cancelled = true; break; }

      // Progress feedback for the UI: it polls this run row directly via Supabase (RLS-open)
      // while extraction is in flight, since this whole handler is one blocking request/response
      // with no other channel to report intermediate state.
      await sb.from("extraction_runs").update({
        stats: { progress: { done: result.length, total: topics.length, current_topic: topic.slug } } as never,
      }).eq("id", run.id);

      const dps = dpdByDefId.get(topic.defId) ?? [];

      // Re-extraction never reuses or merges with previously stored data — every scan starts
      // this topic from a clean slate, regardless of whether the raw source changed since
      // the last run. This wipes ALL structured data for the topic, including fields the
      // user had manually approved.
      await assertDb(sb.from("knowledge_fields").delete().eq("topic_id", topic.topicId), "Apagar campos estruturados anteriores");
      await assertDb(sb.from("additional_info").delete().eq("topic_id", topic.topicId), "Apagar informações adicionais anteriores");
      await assertDb(
        sb.from("knowledge_conflicts").delete().eq("project_id", data.projectId).eq("topic_definition_id", topic.defId),
        "Apagar conflitos anteriores",
      );

      const classified = chunks.filter((c) => (chunkTopicMap.get(c.id) ?? []).includes(topic.slug));
      if (classified.length === 0) {
        result.push({
          topic_slug: topic.slug, core_filled: 0, core_total: dps.length,
          additional_info_chars: 0, chunks_used: 0, input_tokens: 0, output_tokens: 0,
        });
        continue;
      }

      const coreValues = new Map<string, { value: unknown; chunkIds: string[] }>();
      const usedChunkIds: string[] = [];
      let additionalInfoText = "";
      let inT = 0, outT = 0;

      const dpTypeByName = new Map(dps.map((d) => [d.field_name, d.field_type]));
      const timeStarts = dps.filter((d) => d.field_type === "time" && /(_start_time|_start|_inicio|_inicio_time)$/.test(d.field_name));
      // Fields that belong to a start/end pair: the naive single-value extractor below can't
      // tell "start" from "end" apart — it just returns the first time-like token it finds —
      // so if the pair-aware extractTimeRange pass above didn't resolve both sides together,
      // letting each field fall through to it independently would assign them the SAME
      // (and often unrelated) value. Better to leave them unresolved for the LLM than to
      // silently write a wrong-but-plausible duplicate.
      const pairedTimeFieldNames = new Set<string>();
      for (const startDpd of timeStarts) {
        const base = startDpd.field_name.replace(/(_start_time|_start|_inicio|_inicio_time)$/, "");
        const endDpd = dps.find((d) => d.field_type === "time" && (d.field_name === `${base}_end_time` || d.field_name === `${base}_end` || d.field_name === `${base}_fim` || d.field_name === `${base}_fim_time`));
        if (endDpd) {
          pairedTimeFieldNames.add(startDpd.field_name);
          pairedTimeFieldNames.add(endDpd.field_name);
        }
      }
      const allowedCore = new Set(dps.map((d) => d.field_name));
      const coreAlias = new Map<string, string>();
      for (const d of dps) {
        for (const v of fieldKeyVariants(d.field_name)) coreAlias.set(v, d.field_name);
        for (const v of fieldKeyVariants(d.field_label)) coreAlias.set(v, d.field_name);
      }
      const resolve = (name: string): string | null => {
        if (allowedCore.has(name)) return name;
        for (const v of fieldKeyVariants(name)) {
          const hit = coreAlias.get(v);
          if (hit) return hit;
        }
        return null;
      };

      // Batch through every alias-matched chunk (not just the first CHUNK_CAP) so no
      // relevant content is skipped, but keep each LLM call's context small (one batch
      // of CHUNK_CAP chunks at a time) and stop as soon as every field is resolved —
      // this is what bounds both token spend and per-call context size.
      const totalBatches = Math.min(MAX_BATCHES, Math.ceil(classified.length / CHUNK_CAP));
      for (let batchIdx = 0; batchIdx < totalBatches; batchIdx++) {
        // Checked before each batch's LLM call — the finest granularity available, since an
        // in-flight LLM call itself can't be aborted mid-request. Whatever this topic already
        // resolved in earlier batches is kept and persisted below, not thrown away.
        if (await isRunCancelled(sb, run.id)) { cancelled = true; break; }
        await sb.from("extraction_runs").update({
          stats: { progress: {
            done: result.length, total: topics.length, current_topic: topic.slug,
            current_batch: batchIdx + 1, total_batches: totalBatches,
          } } as never,
        }).eq("id", run.id);

        const useChunks = classified.slice(batchIdx * CHUNK_CAP, (batchIdx + 1) * CHUNK_CAP);
        if (useChunks.length === 0) break;
        usedChunkIds.push(...useChunks.map((c) => c.id));

        // ---- Pair pass: handle *_start_time / *_end_time atomically (deterministic, free) ----
        // (a single regex match would otherwise fill BOTH fields with the same first time)
        for (const startDpd of timeStarts) {
          if (coreValues.has(startDpd.field_name)) continue;
          const base = startDpd.field_name.replace(/(_start_time|_start|_inicio|_inicio_time)$/, "");
          const endDpd = dps.find((d) => d.field_type === "time" && (d.field_name === `${base}_end_time` || d.field_name === `${base}_end` || d.field_name === `${base}_fim` || d.field_name === `${base}_fim_time`));
          if (!endDpd) continue;
          for (const c of useChunks) {
            // Only search inside sentences that actually mention this topic — avoid grabbing checkout/checkin times for breakfast.
            const snippet = topicRelevantSnippet(c.content, topic);
            const range = extractTimeRange(snippet);
            if (!range) continue;
            if (!isSaneTimeRange(range, topic.slug, startDpd.field_name, endDpd.field_name)) continue;
            if (!coreValues.has(startDpd.field_name)) coreValues.set(startDpd.field_name, { value: range.start, chunkIds: [c.id] });
            if (!coreValues.has(endDpd.field_name)) coreValues.set(endDpd.field_name, { value: range.end, chunkIds: [c.id] });
            break;
          }
        }

        // Per-field deterministic pass — first-match wins, restricted to topic-relevant sentences.
        for (const c of useChunks) {
          const snippet = topicRelevantSnippet(c.content, topic);
          for (const d of dps) {
            if (coreValues.has(d.field_name)) continue;
            if (d.field_type === "time" && pairedTimeFieldNames.has(d.field_name)) continue;
            const det = tryDeterministic(d, snippet);
            if (!det) continue;
            if (d.field_type === "time" && !isSaneTime(det.value, topic.slug, d.field_name)) continue;
            coreValues.set(d.field_name, { value: det.value, chunkIds: [c.id] });
          }
        }

        const unresolved = dps.filter((d) => !coreValues.has(d.field_name));
        if (unresolved.length === 0) break; // everything resolved deterministically — skip the LLM call entirely

        const combinedText = useChunks
          .map((c, i) => `[chunk ${i + 1} · ${c.id.slice(0, 6)}]\n${topicRelevantSnippet(c.content, topic).slice(0, CHUNK_CHAR_CAP)}`)
          .join("\n---\n")
          .slice(0, 14000);

        const dpList = unresolved.map((d) => `- ${d.field_name} (${d.field_type})${d.field_label ? ` — ${d.field_label}` : ""}${d.description ? `: ${d.description}` : ""}`).join("\n");

        const sys = [
          "Você extrai informações estruturadas de textos de hotéis em pt-BR. Responda APENAS com JSON válido.",
          "REGRAS:",
          "1. Use SOMENTE informações presentes nos textos. Não invente. Se a informação não está nos textos, OMITA o campo.",
          "2. Atribua cada horário ao tópico CORRETO. Nunca confunda café da manhã com check-in/check-out/jantar. Exemplos: '20:00 check-out' NÃO é horário de café da manhã; '15:00 check-in' NÃO é horário de almoço.",
          "3. Plausibilidade por tópico (descarte o valor se estiver fora destas faixas):",
          "   - café da manhã: 04:00–13:00",
          "   - almoço: 10:00–16:00 · jantar: 17:00–23:00",
          "   - check-in: 10:00–23:00 · check-out: 04:00–14:00",
          "   - piscina: 06:00–22:00 · academia: 05:00–23:00 · spa: 08:00–22:00",
          "4. Campos de horário (field_type=time) devem vir em HH:MM (24h). '07h' → '07:00', '10h30' → '10:30'.",
          "5. Em intervalo ('07h às 10h', '6:30 até 10h', 'das 7 às 10'), preencha *_start_time e *_end_time com valores DIFERENTES e na ordem correta (start < end).",
          "6. Campos boolean: true/false (sem string). Campos number/currency: número puro, sem moeda.",
          "7. Campos de texto curtos (location, name): só o trecho factual. Detalhes acessórios vão em additional_info.",
          "8. Prefira preencher core_fields. additional_info é APENAS para o que NÃO couber em campo oficial.",
        ].join("\n");
        const user = `TÓPICO: ${topic.name} (${topic.slug})\n${topic.description ? `DESCRIÇÃO: ${topic.description}\n` : ""}\nCAMPOS OFICIAIS A EXTRAIR (preencha o máximo possível, mas SEMPRE respeitando o tópico):\n${dpList}\n\nTEXTOS DISPONÍVEIS (já filtrados para este tópico, mas podem conter frases de contexto vizinho — IGNORE horários que pertençam a outros tópicos):\n${combinedText}\n\nResponda com JSON estritamente neste formato:\n{\n  "core_fields": { "field_name_oficial": valor_no_tipo_certo, ... },\n  "additional_info": "Narrativa em pt-BR com TUDO que for relevante e não couber em core_fields. Pode ficar vazia."\n}`;

        try {
          const res = await callGateway({
            model: effModel,
            temperature: effTemp,
            maxTokens: effMaxTokens,
            system: sys,
            user,
            jsonMode: true,
          });
          inT += res.inputTokens; outT += res.outputTokens;
          await sb.from("llm_calls").insert({
            prompt_type: `extract_aggregated:${topic.slug}`,
            model_name: effModel,
            input_tokens: res.inputTokens, output_tokens: res.outputTokens, latency: res.latency,
            estimated_cost: estimateCost(effModel, res.inputTokens, res.outputTokens),
          } as never);

          try {
            const parsed = parseJsonLenient(res.content) as {
              core_fields?: Record<string, unknown>;
              additional_info?: string;
            };
            for (const [name, val] of Object.entries(parsed.core_fields ?? {})) {
              if (isEmptyValue(val)) continue;
              const canonical = resolve(name);
              if (!canonical) continue;
              if (coreValues.has(canonical)) continue;
              // Sanity check: drop nonsensical time values (e.g. café da manhã 20:00).
              if (dpTypeByName.get(canonical) === "time" && !isSaneTime(val, topic.slug, canonical)) continue;
              // The LLM sees every chunk in the batch combined into one prompt, so there's no
              // direct signal for which one a given field actually came from. Try to pin it
              // down by checking which chunk's text literally contains the extracted value;
              // if none match (common for reformatted values like times), attribute the whole
              // batch rather than falsely pointing at chunk[0] every time.
              const needle = normalizeForMatch(toPlainTextValue(val));
              const sourceChunk = needle.length >= 2
                ? useChunks.find((c) => normalizeForMatch(topicRelevantSnippet(c.content, topic)).includes(needle))
                : undefined;
              coreValues.set(canonical, {
                value: val,
                chunkIds: sourceChunk ? [sourceChunk.id] : useChunks.map((c) => c.id),
              });
            }
            if (typeof parsed.additional_info === "string" && parsed.additional_info.trim()) {
              const chunk = parsed.additional_info.trim();
              additionalInfoText = additionalInfoText ? `${additionalInfoText}\n${chunk}` : chunk;
            }
          } catch (e) {
            console.error("Parse aggregated extraction failed", topic.slug, e);
          }
        } catch (e) {
          console.error("Aggregated extraction LLM call failed", topic.slug, e);
        }

        const stillUnresolved = dps.filter((d) => !coreValues.has(d.field_name));
        if (stillUnresolved.length === 0) break; // every field filled — no need to scan further batches
        // Small pacing delay — free-tier keys are commonly rate-limited per minute.
        await new Promise((resolve) => setTimeout(resolve, 1000));
      }

      additionalInfoText = removeCoreFactsFromAdditionalInfo(additionalInfoText, topic.slug, coreValues);

      // ---- Persist core fields (fresh insert — old data for this topic was already wiped above) ----
      for (const d of dps) {
        const newVal = coreValues.get(d.field_name);
        if (!newVal) continue;
        await assertDb(sb.from("knowledge_fields").insert({
          topic_id: topic.topicId,
          field_name: d.field_name,
          field_type: d.field_type,
          field_value: newVal.value,
          field_origin: "core",
          approved_by_user: false,
          source_of_truth: "auto_single_candidate",
          consolidation_status: "consolidated",
          source_chunk_ids: newVal.chunkIds,
          confidence: 0.85,
        } as never), `Criar ${d.field_name}`);
      }

      // ---- Persist additional_info (fresh insert) ----
      if (additionalInfoText.length > 0) {
        await assertDb(sb.from("additional_info").insert({
          topic_id: topic.topicId,
          content: additionalInfoText,
          status: "approved",
          source_chunk_ids: usedChunkIds,
          approved_at: new Date().toISOString(),
        } as never), "Criar narrativa complementar");
      }

      result.push({
        topic_slug: topic.slug,
        core_filled: coreValues.size,
        core_total: dps.length,
        additional_info_chars: additionalInfoText.length,
        chunks_used: usedChunkIds.length,
        input_tokens: inT,
        output_tokens: outT,
      });

      if (cancelled) break;
    }

    await sb.from("extraction_runs").update({
      status: cancelled ? "cancelled" : "done",
      finished_at: new Date().toISOString(),
      stats: { progress: { done: result.length, total: topics.length, current_topic: null }, topics: result } as never,
    }).eq("id", run.id);

    return { topics: result, cancelled };
    } catch (err) {
      const msg = err instanceof Error ? err.message : String(err);
      await sb.from("extraction_runs").update({
        status: "failed", finished_at: new Date().toISOString(), error: msg,
      }).eq("id", run.id);
      throw err;
    }
  });

// =====================================================
// runTestAnswer (unchanged behavior)
// =====================================================
export const runTestAnswer = createServerFn({ method: "POST" })
  .inputValidator((input: { questionId: string; mode: "structured" | "raw_chunks" }) => input)
  .handler(async ({ data }) => {
    const sb = getSb();

    const { data: q } = await sb
      .from("test_questions").select("*").eq("id", data.questionId).maybeSingle();
    if (!q) throw new Error("Pergunta não encontrada");

    const { data: tmpl } = await sb
      .from("prompt_templates").select("*").eq("type", "answer")
      .order("created_at", { ascending: false }).limit(1).maybeSingle();
    const { data: modelCfg } = await sb
      .from("model_configurations").select("*").eq("active", true)
      .order("created_at", { ascending: false }).limit(1).maybeSingle();
    if (!tmpl || !modelCfg) throw new Error("Configuração de prompt/modelo ausente.");

    const { data: topicsRaw } = await sb
      .from("topics")
      .select("id, topic_definitions(slug, name, aliases)")
      .eq("project_id", q.project_id);
    type T = { id: string; slug: string; name: string; aliases: string[] };
    const topics: T[] = (topicsRaw ?? []).map((t) => {
      const td = t.topic_definitions as { slug: string; name: string; aliases: string[] } | null;
      return { id: t.id, slug: td?.slug ?? "", name: td?.name ?? "", aliases: td?.aliases ?? [] };
    });
    const qLower = q.question.toLowerCase();
    const matched = topics.filter((t) =>
      [t.slug, t.name.toLowerCase(), ...t.aliases.map((a) => a.toLowerCase())]
        .some((kw) => kw && qLower.includes(kw)),
    );
    const useTopics = matched.length > 0 ? matched : topics;

    let contextText = "";
    const contextSent: Record<string, unknown> = { mode: data.mode, matched_topics: useTopics.map((t) => t.slug) };

    if (data.mode === "structured") {
      const lines: string[] = [];
      for (const t of useTopics) {
        const { data: fields } = await sb
          .from("knowledge_fields").select("*")
          .eq("topic_id", t.id)
          .eq("consolidation_status", "consolidated");
        const { data: addl } = await sb
          .from("additional_info").select("content")
          .eq("topic_id", t.id)
          .eq("status", "approved");
        if ((fields?.length ?? 0) === 0 && (addl?.length ?? 0) === 0) continue;
        lines.push(`# Tópico: ${t.name} (${t.slug})`);
        for (const f of fields ?? []) {
          const v = typeof f.field_value === "object" ? JSON.stringify(f.field_value) : String(f.field_value);
          const verified = f.verified ? " ✓" : "";
          lines.push(`- ${f.field_name}: ${v}${verified}`);
        }
        if ((addl?.length ?? 0) > 0) {
          lines.push(`Informações adicionais:`);
          for (const a of addl ?? []) lines.push(`- ${a.content}`);
        }
        lines.push("");
      }
      contextText = lines.join("\n") || "(base estruturada vazia — rode Consolidation primeiro)";
      contextSent.structured_context = contextText;
    } else {
      const { data: sources } = await sb
        .from("raw_sources").select("id").eq("project_id", q.project_id);
      const sourceIds = (sources ?? []).map((s) => s.id);
      const { data: chunks } = await sb
        .from("raw_chunks").select("id, content").in("raw_source_id", sourceIds).limit(500);
      const keywords = useTopics.flatMap((t) => [t.slug, t.name.toLowerCase(), ...t.aliases.map((a) => a.toLowerCase())]);
      let filtered = (chunks ?? []).filter((c) =>
        keywords.some((kw) => kw && c.content.toLowerCase().includes(kw)),
      );
      if (filtered.length === 0) filtered = (chunks ?? []).slice(0, 30);
      filtered = filtered.slice(0, 40);
      contextText = filtered.map((c) => `[chunk ${c.id}] ${c.content}`).join("\n---\n") || "(sem chunks)";
      contextSent.raw_chunks_count = filtered.length;
    }

    const userPrompt = `CONTEXTO:\n${contextText}\n\nPERGUNTA: ${q.question}`;
    const result = await callGateway({
      model: modelCfg.model_name,
      temperature: Number(modelCfg.temperature),
      maxTokens: modelCfg.max_tokens,
      system: tmpl.content,
      user: userPrompt,
    });

    const cost = estimateCost(modelCfg.model_name, result.inputTokens, result.outputTokens);

    const { data: llmCall } = await sb.from("llm_calls").insert({
      prompt_type: `answer:${data.mode}`,
      model_name: modelCfg.model_name,
      input_tokens: result.inputTokens,
      output_tokens: result.outputTokens,
      latency: result.latency,
      estimated_cost: cost,
      response: { content: result.content } as never,
    }).select("id").single();

    const { data: testRun } = await sb.from("test_runs").insert({
      question_id: q.id,
      mode: data.mode,
      prompt_template_id: tmpl.id,
      model_configuration_id: modelCfg.id,
      context_sent: contextSent as never,
      answer: result.content,
      llm_call_id: llmCall?.id ?? null,
    }).select("*").single();

    if (llmCall?.id && testRun?.id) {
      await sb.from("llm_calls").update({ test_run_id: testRun.id }).eq("id", llmCall.id);
    }

    return {
      answer: result.content,
      latency: result.latency,
      input_tokens: result.inputTokens,
      output_tokens: result.outputTokens,
      estimated_cost: cost,
      test_run_id: testRun?.id ?? null,
    };
  });
