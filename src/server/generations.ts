import "server-only";
import fs from "node:fs";
import path from "node:path";
import { nanoid } from "nanoid";
import { getModel, getPreset } from "@/lib/catalog";
import { applyMentions } from "@/lib/catalog/elements";
import { migrateRequest, replacedBy } from "@/lib/catalog/replaced";
import { directorFieldWords } from "@/lib/catalog/cinema";
import { withSignatureWords } from "@/lib/catalog/palettes";
import { applySketch, stripMotionPaths } from "@/lib/catalog/sketch";
import { cueText, type Cue } from "@/lib/cues";
import { HELPER_FEATURES, HELPER_SUFFIX, isReviewStatus, type AssetUse, type ReviewFilter } from "@/lib/library";
import { upscaleTier } from "@/lib/av/upscale";
import { chainedWaitMessage, keyframeChain } from "@/lib/catalog/keyframes";
import { clipWindowProblem } from "@/lib/catalog/clip-windows";
import { avatarSeconds, clipEditSeconds, estimateCost, inferOperation, planGeneration, presetRoute, routeLoras, routesFor, withoutTriggers } from "@/lib/catalog/plan";
import { framedLength, keepMatte } from "@/lib/catalog/payload";
import { fitLoras, loraName, lorasFit } from "@/lib/catalog/loras";
import { dualEngine, onEngine, pickEngine } from "@/lib/catalog/engines";
import { promptWithLoras, SOUL_MODELS, soulKind, soulLook, soulPostStep, soulPostSteps } from "@/lib/catalog/soul";
import { isDop } from "@/lib/catalog/dop";
import { postStepCost } from "@/lib/composer";
import { MIXED_ORIGINAL, originalFrameSize } from "@/lib/catalog/mixed-media";
import { imageSize } from "@/lib/image-size";
import { finishSteps, mosaicPixels, unionMasks } from "@/lib/soul-post";
import { ANGLES_ORIGINAL, MOSAIC_SCALE } from "@/lib/catalog/open-tools";
import {
  CHAIN_LIST_SLACK,
  LAST_FRAME_CHAIN,
  OPERATION_OUTPUT,
  type ChainSlot,
  type Engine,
  type Generation,
  type GenerationRequest,
  type MediaKind,
  type GenInput,
  type LoraRef,
  type ModelDef,
  type ModelRoute,
  type Operation,
  type OutputFile,
  type Preset,
  type ProviderId,
} from "@/lib/catalog/types";
import { db } from "./db";
import { listElements } from "./elements";
import { pollTrainings } from "./training";
import { createExtendChain, createKeyframeFilm, createMosaicRun, createRelitClip, createShotFilm, createStillTo3d } from "./chains";
import { enhancePrompt, enhanceSoulWords } from "./enhance";
import { setResolver, watchGenerations, type LiveEvent } from "./live";
import { provider, PROVIDERS, RETIRED_PROVIDER_ERROR } from "./providers";
import { comfyLoraFiles, probeComfy } from "./providers/comfyui";
import { graphLoras } from "@/lib/catalog/character-swap";
import { ensureLorasOnComfy, prepareCloudLoras, withoutUnreachableCivitai } from "./loras";
import { ACCESS_PLACE } from "@/lib/model-access";
import { offeredLoras, offeredRoutes, requireOffered } from "./model-access";
import { llmBackends, llmMissing, llmUsesClaude, probeOllama } from "./providers/llm";
import type { PollContext, PollResult, RemoteOutput } from "./providers/types";
import { mediaFacts } from "./media-facts";
import { convertMask, decodePng, encodePng } from "./png";
import { engineMode, getSetting } from "./settings";
import { fetchRemoteToFile } from "./remote-fetch";
import { adoptFile, contentTypeFor, deleteAsset, localHead, readRef, saveFile, scratchDir } from "./storage";

interface Row {
  id: string;
  batch_id: string | null;
  feature: string;
  preset_id: string | null;
  model_id: string;
  engine: Generation["engine"];
  provider: ProviderId;
  op: Generation["op"];
  kind: Generation["kind"];
  status: Generation["status"];
  progress: number | null;
  message: string | null;
  prompt: string | null;
  request_json: string;
  provider_input_json: string | null;
  external_id: string | null;
  external_meta_json: string | null;
  outputs_json: string;
  error: string | null;
  cost_usd: number | null;
  favorite: number;
  created_at: number;
  updated_at: number;
  completed_at: number | null;
  depends_on: string | null;
  /** Library pin and review status (NULL until set; inserts leave them out). */
  pinned_at?: number | null;
  review?: string | null;
  /** Joined by the library readers (generation_trash, folder_items); looked up when absent. */
  deleted_at?: number | null;
  folder_id?: string | null;
}

/** Trash and folder columns, joined onto every library read. */
const LIBRARY_COLUMNS = "g.*, t.deleted_at AS deleted_at, fi.folder_id AS folder_id";
const LIBRARY_JOIN = "generations g LEFT JOIN generation_trash t ON t.generation_id = g.id LEFT JOIN folder_items fi ON fi.generation_id = g.id";

export function toGeneration(r: Row): Generation {
  const request = JSON.parse(r.request_json) as GenerationRequest;
  const model = getModel(r.model_id);
  const ar = request.params?.aspectRatio ?? model?.defaults?.aspectRatio;
  // Rows read without the library join (the runner's own SELECTs) look the trash and folder up.
  const lib =
    r.deleted_at !== undefined && r.folder_id !== undefined
      ? { deleted_at: r.deleted_at, folder_id: r.folder_id }
      : (db()
          .prepare(
            "SELECT (SELECT deleted_at FROM generation_trash WHERE generation_id = ?) AS deleted_at, (SELECT folder_id FROM folder_items WHERE generation_id = ?) AS folder_id",
          )
          .get(r.id, r.id) as { deleted_at: number | null; folder_id: string | null });
  return {
    id: r.id,
    batchId: r.batch_id,
    feature: r.feature,
    presetId: r.preset_id,
    modelId: r.model_id,
    engine: r.engine,
    provider: r.provider,
    op: r.op,
    kind: r.kind,
    status: r.status,
    progress: r.progress,
    message: r.message,
    prompt: r.prompt,
    request,
    outputs: JSON.parse(r.outputs_json) as OutputFile[],
    error: r.error,
    costUsd: r.cost_usd,
    favorite: !!r.favorite,
    createdAt: r.created_at,
    updatedAt: r.updated_at,
    completedAt: r.completed_at,
    // A run on a model Fuobe retired keeps the name it ran under (replaced.ts `was`); Reuse moves it to the replacement.
    modelName: model?.name ?? replacedBy(r.model_id)?.was ?? r.model_id,
    // A Fuobe Soul look is named like a preset ("Look · Y2K" in the viewer).
    presetName: r.preset_id ? (getPreset(r.preset_id)?.name ?? (soulKind(r.model_id) ? (soulLook(r.preset_id)?.name ?? null) : null)) : null,
    aspectRatio: ar && ar !== "auto" ? ar : null,
    deletedAt: lib.deleted_at ?? null,
    folderId: lib.folder_id ?? null,
    pinnedAt: r.pinned_at ?? null,
    review: isReviewStatus(r.review) ? r.review : null,
  };
}

function update(id: string, fields: Partial<Row>): void {
  const keys = Object.keys(fields);
  if (!keys.length) return;
  db()
    .prepare(`UPDATE generations SET ${keys.map((k) => `${k} = @${k}`).join(", ")}, updated_at = @__now WHERE id = @__id`)
    .run({ ...fields, __now: Date.now(), __id: id });
}

/**
 * Set server fields on rows a studio tool made, after it made them (a skill recipe's tool run: the `skill` stamp and the
 * skill's `batchTitle`), and on every row of their batches (the tool's helper steps). Returns those batches.
 */
export function stampRequests(ids: string[], fields: (batches: string[]) => Pick<GenerationRequest, "skill" | "batchTitle">): string[] {
  if (!ids.length) return [];
  const marks = (n: number) => Array.from({ length: n }, () => "?").join(", ");
  const batches = (db().prepare(`SELECT DISTINCT batch_id FROM generations WHERE id IN (${marks(ids.length)}) AND batch_id IS NOT NULL`).all(...ids) as { batch_id: string }[]).map((r) => r.batch_id);
  const rows = db()
    .prepare(`SELECT id, request_json FROM generations WHERE id IN (${marks(ids.length)})${batches.length ? ` OR batch_id IN (${marks(batches.length)})` : ""}`)
    .all(...ids, ...batches) as Pick<Row, "id" | "request_json">[];
  const set = fields(batches);
  db().transaction(() => {
    for (const r of rows) update(r.id, { request_json: JSON.stringify({ ...(JSON.parse(r.request_json) as GenerationRequest), ...set }) });
  })();
  return batches;
}

/** One generation; a row in the Trash reads as missing unless `includeDeleted`. */
export function getGeneration(id: string, opts: { includeDeleted?: boolean } = {}): Generation | null {
  ensureRunner();
  const r = db().prepare(`SELECT ${LIBRARY_COLUMNS} FROM ${LIBRARY_JOIN} WHERE g.id = ?`).get(id) as Row | undefined;
  if (!r || (r.deleted_at && !opts.includeDeleted)) return null;
  return toGeneration(r);
}

export interface ListOptions {
  batchId?: string;
  feature?: string;
  features?: string[];
  kind?: string;
  kinds?: string[];
  models?: string[];
  favorites?: boolean;
  status?: string;
  statuses?: string[];
  /** Only the Trash, newest deletion first (`before` is then a deletedAt cursor). Otherwise the Trash is left out. */
  trashed?: boolean;
  folderId?: string;
  /** In any of these folders (a folder and its subfolders). */
  folderIds?: string[];
  /** Only pinned ones, most recently pinned first (`before` is then a pinnedAt cursor); false: only the others. */
  pinned?: boolean;
  /** Review statuses ("none": no status). */
  reviews?: ReviewFilter[];
  /**
   * Also list helper steps (chain steps and helper jobs: isHelperFeature in src/lib/library.ts). A list
   * that names its features or its batch always gets them; others (the Library, the home feed,
   * Assist's list_recent) leave them out unless this is set.
   */
  steps?: boolean;
  limit?: number;
  /**
   * Paging cursor: made before this (deleted before, in the Trash). With `beforeId` it is the last
   * row of the previous page, so rows sharing its timestamp (a bulk trash, a batch made in one
   * millisecond) are paged by id instead of skipped.
   */
  before?: number;
  beforeId?: string;
  /** Date range on createdAt: since ≤ t < until. */
  since?: number;
  until?: number;
  q?: string;
}

const featureLike = (f: string) => (f.endsWith("*") ? `${f.slice(0, -1)}%` : f);

export function listGenerations(o: ListOptions = {}): Generation[] {
  const where: string[] = [o.trashed ? "t.deleted_at IS NOT NULL" : "t.deleted_at IS NULL"];
  const args: unknown[] = [];
  const add = (sql: string, ...values: unknown[]) => {
    where.push(sql);
    args.push(...values);
  };
  const oneOf = (col: string, values: unknown[]) => add(`${col} IN (${values.map(() => "?").join(", ")})`, ...values);
  if (o.batchId) add("g.batch_id = ?", o.batchId);
  if (o.feature) add("g.feature = ?", o.feature);
  if (o.features?.length) add(`(${o.features.map(() => "g.feature LIKE ?").join(" OR ")})`, ...o.features.map(featureLike));
  if (o.kind) add("g.kind = ?", o.kind);
  if (o.kinds?.length) oneOf("g.kind", o.kinds);
  if (o.models?.length) oneOf("g.model_id", o.models);
  if (o.favorites) add("g.favorite = 1");
  if (o.status) add("g.status = ?", o.status);
  if (o.statuses?.length) oneOf("g.status", o.statuses);
  if (o.folderId) add("fi.folder_id = ?", o.folderId);
  if (o.folderIds?.length) oneOf("fi.folder_id", o.folderIds);
  if (o.pinned !== undefined) add(o.pinned ? "g.pinned_at IS NOT NULL" : "g.pinned_at IS NULL");
  if (o.reviews?.length) {
    const set = o.reviews.filter((r) => r !== "none");
    const any = [set.length ? `g.review IN (${set.map(() => "?").join(", ")})` : "", o.reviews.includes("none") ? "g.review IS NULL" : ""].filter(Boolean);
    add(`(${any.join(" OR ")})`, ...set);
  }
  if (!o.steps && !o.feature && !o.features?.length && !o.batchId) {
    add(`g.feature NOT LIKE ? AND g.feature NOT IN (${HELPER_FEATURES.map(() => "?").join(", ")})`, `%${HELPER_SUFFIX}`, ...HELPER_FEATURES);
  }
  // The cursor's order: the Trash by deletion, a pinned list by pin, the rest by creation (then id, all descending).
  const col = o.trashed ? "t.deleted_at" : o.pinned ? "g.pinned_at" : "g.created_at";
  if (o.before) {
    if (o.beforeId) add(`(${col} < ? OR (${col} = ? AND g.id < ?))`, o.before, o.before, o.beforeId);
    else add(`${col} < ?`, o.before);
  }
  if (o.since) add("g.created_at >= ?", o.since);
  if (o.until) add("g.created_at < ?", o.until);
  const q = o.q?.trim();
  // The user's own words (request.prompt) and what the model got (prompt, with suffixes and templates).
  if (q) add("(g.prompt LIKE ? OR json_extract(g.request_json, '$.prompt') LIKE ?)", `%${q}%`, `%${q}%`);
  const sql = `SELECT ${LIBRARY_COLUMNS} FROM ${LIBRARY_JOIN} WHERE ${where.join(" AND ")} ORDER BY ${col} DESC, g.id DESC LIMIT ?`;
  return (db().prepare(sql).all(...args, Math.max(1, Math.min(o.limit ?? 60, 200))) as Row[]).map(toGeneration);
}

export function setFavorite(id: string, favorite: boolean): void {
  update(id, { favorite: favorite ? 1 : 0 });
}

export interface AssetRef {
  table: string;
  cols: string[];
  /** A column whose row belongs to the generation being purged (its own row and Cinema membership don't keep its files). */
  except?: string;
  /** What a row is, for "where is it used" ("element", "Cinema project"). */
  what: string;
  /** SQL that names the row, and the key that tells rows apart (default `id`; a Cinema take and its project are one project). */
  name?: string;
  key?: string;
}

/**
 * Everywhere a stored file can still be in use, by URL (which ends in the asset id, …/<id>.png) or
 * by id: other jobs' inputs and outputs (an upload a request still names keeps Retry and Reuse
 * working), elements, Assist chats and projects, every studio's sessions, projects and presets.
 * When a table starts storing file URLs, add it here (tests/library.test.ts checks every `_json` /
 * `_url` column is either here or in ASSET_FREE).
 */
export const ASSET_REFS: AssetRef[] = [
  { table: "generations", cols: ["request_json", "outputs_json"], except: "id", what: "result" },
  { table: "characters", cols: ["reference_asset_ids_json", "loras_json", "lora_file"], what: "element", name: "name" },
  { table: "trainings", cols: ["meta_json"], what: "element", key: "element_id", name: "(SELECT name FROM characters WHERE id = element_id)" },
  { table: "assist_threads", cols: ["messages_json", "items_json", "pending_json"], what: "Assist chat", name: "title" },
  // A chat's frozen context names its project's sources; a project's file sources are uploads.
  { table: "assist_thread_state", cols: ["context", "sent_json"], what: "Assist chat", key: "thread_id", name: "(SELECT title FROM assist_threads WHERE id = thread_id)" },
  { table: "assist_project_sources", cols: ["url", "content"], what: "Assist project", key: "project_id", name: "(SELECT name FROM assist_projects WHERE id = project_id)" },
  { table: "cinema_projects", cols: ["cover_url", "palettes_json", "director_json", "chat_json", "brief_body"], what: "Cinema project", name: "name" },
  { table: "cinema_items", cols: ["meta_json"], except: "generation_id", what: "Cinema project", key: "project_id", name: "(SELECT name FROM cinema_projects WHERE id = project_id)" },
  { table: "canvases", cols: ["graph_json", "runs_json"], what: "canvas", name: "name" },
  // A Layers project's source, cover, its tools' inputs (a picked image) and every saved version.
  { table: "layer_projects", cols: ["source_url", "cover_url", "jobs_json"], what: "Layers project", name: "name" },
  { table: "layer_versions", cols: ["doc_json"], what: "Layers project", key: "project_id", name: "(SELECT name FROM layer_projects WHERE id = project_id)" },
  { table: "shorts_sessions", cols: ["source_json", "look_json"], what: "Shorts session", name: "title" },
  { table: "shorts_presets", cols: ["references_json"], what: "Shorts preset", name: "name" },
  { table: "brand_kits", cols: ["kit_json", "chat_json"], what: "brand kit", name: "name" },
  { table: "products", cols: ["images_json"], what: "product", name: "name" },
  { table: "ad_creatives", cols: ["meta_json"], what: "ad", name: "headline" },
  { table: "marketing_runs", cols: ["meta_json"], what: "marketing run", name: "title" },
  // Image studios: a palette's thumbnail, a moodboard's images, collages and cover, an Instadump pack's photos.
  { table: "palettes", cols: ["thumb_url"], what: "palette", name: "name" },
  { table: "moodboards", cols: ["images_json", "collages_json", "cover_url"], what: "moodboard", name: "name" },
  { table: "photodump_packs", cols: ["refs_json"], what: "photo pack", name: "name" },
  // Faceless / Explainer: a channel's avatar, style references and voice samples; an episode's sources, script and picture edits.
  { table: "faceless_channels", cols: ["avatar_url", "reference_json", "settings_json"], what: "Faceless channel", name: "name" },
  { table: "faceless_episodes", cols: ["settings_json", "sources_json", "script_json", "plan_json"], what: "episode", name: "title" },
  // Translate & dub sessions and Katana jobs: the source video, the subject picture and each step's files.
  { table: "dub_sessions", cols: ["data_json"], what: "dub", name: "json_extract(data_json, '$.title')" },
  { table: "katana_jobs", cols: ["data_json"], what: "Katana job", name: "json_extract(data_json, '$.title')" },
  // Content Factory: a series' reference clip and its thumbnail.
  { table: "content_series", cols: ["data_json"], what: "Content Factory series", name: "COALESCE(json_extract(data_json, '$.name'), json_extract(data_json, '$.reference.title'))" },
  // Assist's scheduled tasks: the files the prompt runs with.
  { table: "assist_schedules", cols: ["attachments_json"], what: "scheduled task", name: "title" },
  // Character Swap Studio: the character picture, each clip and its 24 fps copy, masks, anchors, takes and their masters.
  { table: "swap_projects", cols: ["data_json"], what: "Character Swap project", name: "name" },
  // A user skill's bundled text files: its recipe.json names the files a run starts from (an example, a fixed logo).
  { table: "skills", cols: ["files_json"], what: "skill", key: "name", name: "title" },
  // Accounts (o/acc-1): a person's picture is an uploaded asset.
  { table: "users", cols: ["avatar_asset_id"], what: "account picture", name: "provisioned_name" },
];

/**
 * Columns that look like they could hold a file (`_json`, `_url`) but never hold one of Fuobe's
 * stored files, with the reason. The ASSET_REFS coverage test reads this list.
 */
export const ASSET_FREE: Record<string, string> = {
  "generations.provider_input_json": "what a provider was sent: its own upload URLs or file names, never ours",
  "generations.external_meta_json": "the provider's job handles",
  "shorts_sessions.range_json": "start and end times",
  "shorts_sessions.settings_json": "ratio, language, model and resolution",
  "shorts_sessions.segments_json": "generation ids of each take",
  "shorts_sessions.stitches_json": "generation ids of each stitch",
  "brand_kits.progress_json": "research progress labels",
  "products.selling_points_json": "words",
  "products.url": "the product's own web page",
  "marketing_runs.final_ids_json": "generation ids",
  "palettes.colors_json": "hex colours",
  "assist_projects.skills_json": "skill names",
  "assist_thread_state.skills_json": "skill names",
  "skills.meta_json": "SKILL.md front matter",
  "lora_mirrors.source_url": "where a LoRA file downloads from (civitai, Hugging Face), without the key",
  "lora_mirrors.hosted_url": "the provider's copy of a LoRA file (fal or Replicate storage), never ours",
  "shares.tags_json": "words",
  "shares.items_json": "generation ids: a share link shows what still exists and keeps no file alive",
  "lora_mirrors.licence_json": "the licence and civitai permissions a LoRA copy was made under",
  "assist_schedules.rule_json": "when a scheduled task runs",
  "assist_schedules.mode_json": "the Assist mode a scheduled run starts in",
  "assist_connectors.url": "a remote MCP server Claude connects to, never one of ours",
  "assist_connectors.tools_json": "the tool names a connector is limited to",
  "audit_log.meta_json": "what an audit entry is about: ids, setting names and masked prefixes, never files",
};

/** The query that finds the rows of one ASSET_REFS table naming a file (@id), except the purged generation's own (@g). */
export function assetRefSql(r: AssetRef): string {
  const where = r.cols.map((c) => `instr(COALESCE(${c}, ''), @id) > 0`).join(" OR ");
  const except = r.except ? ` AND ${r.except} != @g` : "";
  const trashed = r.table === "generations" ? ", EXISTS (SELECT 1 FROM generation_trash t WHERE t.generation_id = generations.id) AS trashed" : "";
  return `SELECT ${r.key ?? "id"} AS k, ${r.name ?? "NULL"} AS n${trashed} FROM ${r.table} WHERE (${where})${except} LIMIT @max`;
}

/**
 * Where a stored file is still used (see ASSET_REFS), at most `max` rows: enough to say where
 * ("2 results and the element “Maya”", describeUses in src/lib/library.ts) or, with max 1, whether.
 */
export function assetUses(assetId: string, opts: { exceptGeneration?: string; max?: number } = {}): AssetUse[] {
  const max = opts.max ?? 50;
  const out: AssetUse[] = [];
  for (const r of ASSET_REFS) {
    try {
      const rows = db()
        .prepare(assetRefSql(r))
        .all({ id: assetId, g: opts.exceptGeneration ?? "", max: max - out.length }) as { k: string; n: string | null; trashed?: number }[];
      for (const row of rows) out.push({ what: r.what, key: String(row.k), name: row.n ?? null, ...(row.trashed ? { trashed: true } : {}) });
    } catch {
      // A table or column this install doesn't have yet: nothing there to keep the file for.
    }
    if (out.length >= max) break;
  }
  return out;
}

/** Whether anything still refers to this stored file (see ASSET_REFS). */
export function assetInUse(assetId: string, exceptGeneration = ""): boolean {
  return assetUses(assetId, { exceptGeneration, max: 1 }).length > 0;
}

/**
 * Delete for good (Trash → Delete forever, Empty trash, the 30-day purge): the row, its trash and
 * folder entries, and the output files nothing else still points at (assetInUse). Dependents still
 * waiting on it fail ("An earlier step didn't finish"). Use deleteForever / emptyTrash in
 * src/server/library.ts (they cancel running jobs first); moving to the Trash is trashGenerations.
 */
export function deleteGeneration(id: string): void {
  const assets = db().prepare("SELECT id FROM assets WHERE generation_id = ?").all(id) as { id: string }[];
  db().transaction(() => {
    db().prepare("DELETE FROM generations WHERE id = ?").run(id);
    db().prepare("DELETE FROM generation_trash WHERE generation_id = ?").run(id);
    db().prepare("DELETE FROM folder_items WHERE generation_id = ?").run(id);
  })();
  for (const a of assets) if (!assetInUse(a.id, id)) deleteAsset(a.id);
}

// ---------------------------------------------------------------------------
// Routing

/**
 * Pick the provider for a run: a configured real provider, else the demo provider (unless demo is off).
 * `images` is how many images the run sends: a route whose list takes fewer (FieldMap.maxImages: Grok
 * Imagine Image takes 5 on fal) gives way to one that takes them all, or says so.
 * `loras` and `seconds` (the clip length asked for) prefer a route that carries every LoRA and makes that
 * length (Replicate's Wan 2.2 fast renders only 81–121 frames, fal's 17–161).
 */
export function chooseRoute(candidates: ModelRoute[], images = 0, loras: LoraRef[] = [], seconds?: number, forceDemo = false): { route: ModelRoute; demo: boolean } {
  // Honour the preferred cloud aggregator (Settings → API configuration) when a model is on several.
  const preferred = getSetting("cloudProvider");
  const routes = preferred === "auto" ? candidates : [...candidates].sort((a, b) => Number(b.provider === preferred) - Number(a.provider === preferred));
  const demo = getSetting("demoMode");
  // A request marked demo (a skill recipe's free dry run) runs on the demo provider whatever Settings says.
  if (demo === "on" || forceDemo) return { route: routes[0], demo: true };
  const takes = (r: ModelRoute) => !r.map?.maxImages || images <= r.map.maxImages;
  // A route that carries every LoRA wins (Replicate's Wan 2.2 takes one per expert, fal's takes a Mix), then one
  // that makes the length asked; otherwise the first ready one runs and the plan's notes say what it changes.
  const ok = (r: ModelRoute) => routeReady(r) && takes(r);
  const long = (r: ModelRoute) => framedLength(r.map?.numFrames, seconds) === undefined;
  const real =
    routes.find((r) => ok(r) && lorasFit(r, loras) && long(r)) ?? routes.find((r) => ok(r) && lorasFit(r, loras)) ?? routes.find((r) => ok(r) && long(r)) ?? routes.find(ok);
  if (real) return { route: real, demo: false };
  const short = routes.find(routeReady);
  if (short) {
    const others = [...new Set(routes.filter((r) => takes(r) && r.provider !== short.provider).map((r) => provider(r.provider).label))];
    throw new Error(`This model takes up to ${short.map!.maxImages} images on ${provider(short.provider).label} — remove some${others.length ? `, or connect ${others.join(" or ")} for more` : ""}`);
  }
  if (demo === "off") {
    if (routes.every((r) => r.provider === "llm")) throw new Error(llmMissing(routes[0]));
    const names = [...new Set(routes.map((r) => provider(r.provider).label))].join(" or ");
    throw new Error(`Connect ${names} in Settings to run this model`);
  }
  return { route: routes[0], demo: true };
}

/** Text steps depend on which LLM the route may use (the open model never calls Claude). */
const routeReady = (r: ModelRoute) => (r.provider === "llm" ? llmBackends(r).length > 0 : provider(r.provider).isConfigured());

/** What a run produces: colour matching works on images and videos, and fal renders a timeline as a video, so those follow the model. */
export function outputKind(op: Generation["op"], model: { kind: MediaKind }): MediaKind {
  // A 3D scene is a mesh on the open engine and a depth map (an image) on the cloud.
  return op === "color-match" || op === "timeline" || op === "scene-3d" ? model.kind : OPERATION_OUTPUT[op];
}

// Live updates: every write to the table becomes an event (src/server/live.ts). A trashed row
// (soft delete, when the table has one) leaves the feeds like a deleted one.
setResolver((ids) =>
  ids.map((id): LiveEvent => {
    const r = db().prepare("SELECT * FROM generations WHERE id = ?").get(id) as (Row & { deleted_at?: number | null; trashed_at?: number | null }) | undefined;
    const g = r && (toGeneration(r) as Generation & { deletedAt?: number | null; trashedAt?: number | null });
    if (!r || !g || r.deleted_at || r.trashed_at || g.deletedAt || g.trashedAt) return { type: "deleted", id, json: JSON.stringify({ id }) };
    return { type: "generation", id, json: JSON.stringify(g) };
  }),
);

// ---------------------------------------------------------------------------
// Create

/**
 * A request as it runs now: one that names a model (or an operation) Fuobe retired when it stopped calling Higgsfield moves
 * to what replaced it (src/lib/catalog/replaced.ts), with Cinema Studio's Director fields in words. Every way in goes
 * through it (the API, a retry, a waiting step, a saved project's run); `note` says what changed.
 */
export function currentRequest(req: GenerationRequest): { request: GenerationRequest; note?: string } {
  return migrateRequest(req, { directorWords: directorFieldWords });
}

/**
 * The engine a model runs a request on: a Fuobe Original runs on the engine asked for (the composer's switch), else
 * the engine mode, else the first one connected; any other model on its own.
 */
export function engineFor(m: ModelDef, asked: Engine | undefined): Engine {
  return dualEngine(m) ? pickEngine(m, asked, engineMode(), (e) => onEngine(m, e).routes.some(routeReady)) : m.engine;
}

/**
 * Fuobe DoP's relight effects (Silhouette, Window…) on their own model: the step that relights the start frame on the
 * engine the clip runs on. None for any other request (the effect on a partner model runs on its words).
 */
export function relightStep(req: GenerationRequest, model: ModelDef): { engine: Engine; step: NonNullable<Preset["prestep"]>["open"] } | undefined {
  const preset = req.presetId ? getPreset(req.presetId) : undefined;
  if (!preset?.prestep || !req.inputs?.images?.length) return undefined;
  const engine = engineFor(model, req.engine);
  if (presetRoute(preset, engine)?.modelId !== model.id) return undefined;
  return { engine, step: preset.prestep[engine] };
}

/**
 * The engine an app runs an Original on when only one of its routes names it (the AI Influencer app: Fuobe Soul in the
 * cloud, the Soul Cast sheet graph on your GPU); undefined otherwise.
 */
export function appEngine(req: Pick<GenerationRequest, "presetId">, m: ModelDef): Engine | undefined {
  const preset = req.presetId ? getPreset(req.presetId) : undefined;
  if (preset?.type !== "app") return undefined;
  const sides = (["cloud", "open"] as const).filter((e) => presetRoute(preset, e)?.modelId === m.id);
  return sides.length === 1 ? sides[0] : undefined;
}

/**
 * The model a request may run, as Settings → Models & licences offers it (only its routes that are on). Engine mode
 * refuses an Original's engine it rules out first; then a model that is off is refused naming the switch, and so is
 * an Original's engine that is off when it is the one asked for, or the one the install's engine mode runs it on.
 * Every run and every chain (createGenerations, before any step is queued) goes through it.
 */
export function offeredFor(m: ModelDef, asked: Engine | undefined): ModelDef {
  const mode = engineMode();
  if (dualEngine(m)) pickEngine(m, asked, mode, () => true);
  return requireOffered(m, asked ?? (mode === "both" ? undefined : mode));
}

/**
 * Fuobe Mixed Media's single picture in the cloud (DoP's Mixed Media stills, an API caller's edit), and Fuobe Angles' other
 * camera, drawn at about 1 megapixel in its picture's shape, as it's priced (and as the GPU graphs scale it): without a
 * size, fal keeps the upload's own (a 12-megapixel photo costs 12 times as much). The studio sends each Mixed Media frame's
 * size itself; a picture that isn't a file in Fuobe keeps fal's.
 */
const SIZED_EDITS = new Set([MIXED_ORIGINAL, ANGLES_ORIGINAL]);
function sizedMixedFrame(plan: ReturnType<typeof planGeneration>, req: GenerationRequest): ReturnType<typeof planGeneration> {
  if (!SIZED_EDITS.has(plan.model.id) || plan.model.engine !== "cloud" || plan.op !== "edit" || plan.params.extra?.image_size) return plan;
  const first = req.inputs?.images?.[0];
  const head = first ? localHead(first) : null;
  const size = head ? imageSize(head) : null;
  const fit = size ? originalFrameSize(size, "1K") : undefined;
  return fit ? { ...plan, params: { ...plan.params, extra: { ...plan.params.extra, image_size: fit } } } : plan;
}

/** Resolve mentions and drawings, plan, enforce the engine mode and pick a provider route. */
function prepare(original: GenerationRequest) {
  // @element mentions become reference images / LoRAs; the stored request keeps the mentions for "Reuse".
  // A style signature's sentences (palette, look) join the prompt here; the stored request keeps the user's words.
  const worded = withSignatureWords(original);
  const mode = engineMode();
  // Settings → Models & licences: a model (or the engine of an Original asked for) that is switched off is refused,
  // naming the switch; an Original otherwise runs on an engine that is still on, with the routes that are on.
  const found = getModel(worded.modelId);
  const onSide = worded.engine ?? (found && appEngine(worded, found));
  const allowed = found && offeredFor(found, onSide);
  const model = allowed && dualEngine(allowed) ? onEngine(allowed, engineFor(allowed, onSide)) : allowed;
  const lookup = (id: string) => (model && id === model.id ? model : getModel(id));
  const req = model ? stripMotionPaths(applySketch(applyMentions(worded, model, listElements()).request, model).request, model) : worded;
  let plan = sizedMixedFrame(planGeneration(req, lookup, getPreset), req);
  if (mode !== "both" && plan.model.engine !== mode) {
    throw new Error(
      mode === "open"
        ? `${plan.model.name} is a paid cloud model, but this install is set to open source only (Settings → Engine mode)`
        : `${plan.model.name} is an open-source model, but this install is set to paid cloud APIs only (Settings → Engine mode)`,
    );
  }
  // Checks planGeneration can't make without knowing the model's kind or the text ops' needs.
  if (plan.op === "color-match" && plan.model.kind === "video" && !req.inputs?.video) throw new Error("Add the video and a reference image");
  if (plan.op === "translate" && !plan.params.targetLanguage) throw new Error("Pick a language to translate into");
  // The length asked of a clip that is made (not one that follows its input video's length).
  const seconds = MADE_LENGTH_OPS.has(plan.op) ? plan.params.duration : undefined;
  // LoRAs switched off (by file or licence class) are left out, their trigger words with them; with "keep GPU-only
  // LoRAs on your GPU" on, the rest are marked so a cloud route leaves those out (fitLoras).
  const access = offeredLoras(plan.loras);
  // A LoRA the model's recipe can't run without (Fuobe Try-On's try-on LoRA) switched off: the model can't run.
  const needed = access.dropped.find((d) => plan.model.options.loras?.some((l) => l.file === d.file));
  if (needed) throw new Error(`${plan.model.name} runs with the LoRA “${loraName(needed)}”, which is switched off in ${ACCESS_PLACE}. Turn it back on there, or pick another model`);
  if (access.dropped.length) plan = { ...plan, loras: access.loras, prompt: withoutTriggers(plan.prompt, plan.loras.filter((l) => !access.loras.some((k) => k.file === l.file)), access.loras) };
  else if (access.loras.some((l, i) => l !== plan.loras[i])) plan = { ...plan, loras: access.loras };
  // A preset can route to another model than the one asked for: its routes that are on (or the switch that's off).
  const { route, demo } = chooseRoute(offeredRoutes(plan.model, routesFor(plan.model, plan.op)), req.inputs?.images?.length ?? 0, plan.loras, seconds, !!worded.demo);
  // What the cloud run can carry: a LoRA whose licence doesn't allow hosting stays on the GPU, and an API
  // takes at most so many (the plan's notes say which were left out). Open runs carry them all. Without a
  // civitai key a look's civitai LoRA the run can't get is left out (and said), rather than failing at the
  // download: the look's words still carry it. Looks are Fuobe Soul's and Fuobe Mixed Media's (the studio's frames,
  // Smooth's first frame, DoP's Mixed Media stills). Any other run (a motion, whose LoRA is the point) still stops there.
  const asked = plan.loras;
  const look = !!plan.soul || plan.model.id === MIXED_ORIGINAL;
  const reachable =
    demo || !look ? { loras: asked, notes: [] } : withoutUnreachableCivitai(asked, route.provider === "comfyui" ? "comfyui" : route.provider === "replicate" ? "replicate" : "fal");
  const fitted = fitLoras(reachable.loras, route);
  // A LoRA the recipe can't run without that this route leaves out for any reason (its cap, a GPU-only licence, no
  // cloud path): the model can't run here, rather than running without it.
  const lost = demo ? undefined : plan.model.options.loras?.find((l) => asked.some((a) => a.file === l.file) && !fitted.loras.some((k) => k.file === l.file));
  if (lost) {
    const why = [...reachable.notes, ...fitted.notes].join("; ");
    throw new Error(`${plan.model.name} runs with the LoRA “${loraName(lost)}”, which this run leaves out${why ? ` (${why})` : ""}. Pick another model or engine`);
  }
  // A look's triggers lead the prompt: a LoRA left out takes its trigger with it.
  const prompt = plan.soul
    ? promptWithLoras(plan.prompt, plan.soul.triggers, fitted.loras)
    : look
      ? withoutTriggers(plan.prompt, asked.filter((l) => !reachable.loras.includes(l)), reachable.loras)
      : plan.prompt;
  plan = { ...plan, prompt, loras: fitted.loras };
  const notes = [...(plan.notes ?? []), ...access.notes, ...reachable.notes, ...fitted.notes];
  // A frame-count API that can't make the length asked (Replicate's Wan 2.2 fast: 81–121 frames) says what it makes.
  const made = demo ? undefined : framedLength(route.map?.numFrames, seconds, plan.params.fps);
  if (made !== undefined && route.map?.numFrames) {
    const f = route.map.numFrames;
    const fps = plan.params.fps && plan.params.fps > 0 ? plan.params.fps : f.fps;
    const half = (x: number) => Math.round(x * 2) / 2;
    const span = f.min !== undefined && f.max !== undefined ? ` makes ${half(f.min / fps)}–${half(f.max / fps)} s clips,` : "";
    notes.push(`${plan.model.name} on ${provider(route.provider).label}${span} so this one is about ${half(made)} s, not ${seconds} s`);
  }
  // A talking avatar is as long as its voice, up to what a frame-count route makes a call (fal's InfiniteTalk about 29 s, Wan
  // 2.2 S2V 7.5 s): a longer voice is cut there, and said.
  const voice = !demo && plan.op === "avatar" && route.map?.numFrames ? plan.params.sourceDuration : undefined;
  if (voice && voice > 0) {
    const reach = avatarSeconds({ routes: [route] }, voice, plan.params.fps);
    const half = (x: number) => Math.round(x * 2) / 2;
    if (reach < voice - 0.25) notes.push(`${plan.model.name} on ${provider(route.provider).label} makes up to ${half(reach)} s a call, so this one stops ${half(reach)} s into the ${half(voice)} s voice`);
  }
  // A route that can't batch (Replicate's Nano Banana Pro beside fal's num_images; a ComfyUI graph, which makes
  // one picture a run: Fuobe Soul on the open engine) runs one job per output.
  if (!demo && !route.map?.numOutputs && plan.perJobOutputs > 1) {
    plan = { ...plan, jobs: plan.jobs * plan.perJobOutputs, perJobOutputs: 1, params: { ...plan.params, numOutputs: 1 } };
  }
  const providerId: ProviderId = demo ? "mock" : route.provider;
  // A text step that runs on Ollama is free; only Claude costs money.
  const free = demo || (route.provider === "llm" && !llmUsesClaude(route));
  const withLoras = fitted.loras.length > 0 && !!route.loraEndpoint;
  const unreachable = asked.filter((l) => !reachable.loras.includes(l));
  // Priced for the clip the route makes: Replicate's Wan 2.2 fast makes 5 s when 3 s was asked.
  const priced = made !== undefined && plan.params.duration !== undefined ? { ...plan.params, duration: Math.round(made * 2) / 2 } : plan.params;
  return { req, plan, route, demo, providerId, notes, asked, unreachable, switchedOff: access.dropped, cost: free ? 0 : estimateCost(plan.model, priced, 1, plan.op, withLoras) };
}

/** Operations whose clip length is the duration picked (made, or added by extend), not an input video's. */
const MADE_LENGTH_OPS = new Set<Operation>(["t2v", "i2v", "flf2v", "ref2v", "extend", "keyframes"]);


/** What a request would run as — model, operation, job count and cost — without starting it. */
export function previewGeneration(asked: GenerationRequest) {
  const moved = currentRequest(asked);
  const prepared = prepare(moved.request);
  const { plan, route, demo, providerId, cost, asked: askedLoras, unreachable, switchedOff } = prepared;
  const notes = moved.note ? [moved.note, ...prepared.notes] : prepared.notes;
  const fitted = routeLoras(route, askedLoras.filter((l) => !unreachable.includes(l)));
  const loras = {
    ...fitted,
    dropped: [...switchedOff, ...unreachable.map((l) => ({ file: l.file, reason: "it downloads from civitai, which needs your civitai key (Settings → LoRAs)" })), ...fitted.dropped],
  };
  // PixeletedFace pixelates each picture's faces afterwards (createMosaicRun): fal's SAM 3.1 per picture in the cloud.
  const post = demo || moved.request.postMade ? 0 : postStepCost(plan.model.id, moved.request.presetId, plan.model.engine, plan.jobs * plan.perJobOutputs, getModel);
  return {
    model: plan.model,
    op: plan.op,
    jobs: plan.jobs,
    outputs: plan.jobs * plan.perJobOutputs,
    demo,
    providerId,
    costUsd: cost === null ? null : post ? Math.round((cost * plan.jobs + post) * 1000) / 1000 : cost * plan.jobs,
    // The engine it runs on (a Fuobe Original picks one per request).
    engine: plan.model.engine,
    // What the route runs (the evaluation harness records it): the provider endpoint, the final prompt and the LoRAs it loads.
    route: { provider: route.provider, endpoint: loras.applied.length && route.provider !== "comfyui" && route.loraEndpoint ? route.loraEndpoint : route.endpoint },
    prompt: plan.prompt,
    loras,
    ...(notes.length && { notes }),
  };
}

/** Preview a step that will wait for `deps` earlier steps: validated with placeholders in its chain slots, as createGenerations does. */
export function previewChained(req: GenerationRequest, deps: number) {
  if (!deps) return previewGeneration(req);
  // A waiting step always runs as one job (createGenerations doesn't batch dependents).
  const p = previewGeneration(withChainInputs(req, slotsFor(req, deps).map(placeholderFor)));
  // Refused before anything starts, as createGenerations refuses it.
  if (routesFor(p.model, p.op).some((r) => r.chained)) throw new Error(chainedWaitMessage(p.model.name, p.op));
  const jobs = Math.max(1, p.jobs);
  return { ...p, jobs: 1, outputs: p.outputs / jobs, costUsd: p.costUsd === null ? null : p.costUsd / jobs };
}

export interface CreateOptions {
  /** Group several requests (storyboard frames, the shots of a film) into one batch. */
  batchId?: string;
  /**
   * Wait for these generations, then feed their first outputs in as inputs: where each goes is
   * `request.chain` (one slot per id), or `request.chainFrom` for a single image dependency.
   */
  dependsOn?: string | string[];
}

const depIds = (v: string | null): string[] => (!v ? [] : v.startsWith("[") ? (JSON.parse(v) as string[]) : [v]);

export function createGenerations(asked: GenerationRequest, opts: CreateOptions = {}): Generation[] {
  // A retired model or operation (a retry, an old script, a saved project) runs on what replaced it, and says so.
  const moved = currentRequest(asked);
  const original = moved.request;
  // Open models make multi-shot films shot by shot, then join the clips. A Fuobe Original is taken on the engine it runs
  // on (Fuobe DoP's Frames mode is a GPU chain).
  // A model (or an Original's engine asked for) switched off in Settings → Models & licences is refused here, before a
  // chain queues any step; an Original otherwise runs on an engine still on.
  const catalogModel = getModel(original.modelId);
  const found = catalogModel && offeredFor(catalogModel, original.engine);
  const shotModel = found && dualEngine(found) ? onEngine(found, engineFor(found, original.engine)) : found;
  if (!opts.dependsOn && shotModel?.options.multiShot?.mode === "concat" && (original.params?.shots?.filter((x) => x.prompt.trim()).length ?? 0) > 1) {
    return createShotFilm(original, shotModel);
  }
  if (!opts.dependsOn && original.op === "extend" && shotModel && routesFor(shotModel, "extend").some((r) => r.endpoint === LAST_FRAME_CHAIN)) {
    return createExtendChain(original, shotModel);
  }
  // Frames mode on an open model: one start/end-frame clip per pair of frames, then joined.
  const filmRoute = shotModel && keyframeChain(shotModel);
  if (!opts.dependsOn && filmRoute && inferOperation(shotModel, original) === "keyframes") return createKeyframeFilm(original, shotModel, filmRoute);
  // Text to 3D on the open engine: a still first, then the 3D model of it. The operation is read as the planner
  // reads it (Assist, MCP and API clients usually leave op out).
  const stillTo3d = !opts.dependsOn && shotModel && inferOperation(shotModel, original) === "text-to-3d" ? routesFor(shotModel, "text-to-3d").find((r) => r.chained) : undefined;
  if (shotModel && stillTo3d) return createStillTo3d(original, shotModel, stillTo3d);
  // Fuobe DoP's relight effects: the start frame is relit first, then animated.
  const relight = !opts.dependsOn && shotModel ? relightStep(original, shotModel) : undefined;
  if (relight) return createRelitClip(original, relight);
  // Fuobe Soul's PixeletedFace look: the picture, then its faces pixelated (SAM 3.1 + a mosaic), also as a pipeline step or a
  // Canvas node (it waits for what they wait for). The picture made inside that run (postMade) runs as it is.
  if (!original.postMade && shotModel && soulPostStep(shotModel.id, original.presetId) === "face-mosaic") {
    const waitsFor = opts.dependsOn === undefined ? undefined : Array.isArray(opts.dependsOn) ? opts.dependsOn : [opts.dependsOn];
    return createMosaicRun(original, shotModel, { batchId: opts.batchId, dependsOn: waitsFor });
  }
  const deps = opts.dependsOn === undefined ? [] : Array.isArray(opts.dependsOn) ? opts.dependsOn : [opts.dependsOn];
  const waits = deps.length > 0;
  // A dependent job can't be planned until its inputs exist; it's validated with placeholders, then launched by the runner.
  const p = waits ? prepare(withChainInputs(original, slotsFor(original, deps.length).map(placeholderFor))) : prepare(original);
  const { req, plan, route, demo, providerId, cost } = p;
  const notes = moved.note ? [moved.note, ...p.notes] : p.notes;
  // A chained route is built from its inputs when it's created; it can't wait for another step's output.
  if (waits && route.chained) throw new Error(chainedWaitMessage(plan.model.name, plan.op));
  const jobs = waits ? 1 : plan.jobs;
  const batchId = opts.batchId ?? (jobs > 1 ? nanoid(10) : null);
  const now = Date.now();
  const created: Generation[] = [];
  for (let i = 0; i < jobs; i++) {
    const id = nanoid(12);
    const row: Row = {
      id,
      batch_id: batchId,
      feature: req.feature,
      preset_id: req.presetId ?? null,
      model_id: plan.model.id,
      engine: plan.model.engine,
      provider: providerId,
      op: plan.op,
      kind: outputKind(plan.op, plan.model),
      status: "queued",
      progress: null,
      message: waits ? (original.frame ? "Waits for the previous frame" : "Waits for the earlier steps") : demo ? "Demo mode — no provider connected" : "Submitting",
      // A step whose prompt comes from an earlier step shows its own words (not the placeholder) until then.
      prompt: waits && req.chain?.some((s) => s.slot === "prompt") ? original.prompt?.replaceAll("{text}", "…").trim() || null : plan.prompt,
      // An Original remembers the engine it ran on, so a retry or a chained step runs there too.
      request_json: JSON.stringify(dualEngine(plan.model) ? { ...original, engine: plan.model.engine } : original),
      provider_input_json: null,
      external_id: null,
      external_meta_json: null,
      outputs_json: "[]",
      error: null,
      cost_usd: cost,
      favorite: 0,
      created_at: now + i,
      updated_at: now + i,
      completed_at: null,
      depends_on: !waits ? null : deps.length === 1 ? deps[0] : JSON.stringify(deps),
    };
    db()
      .prepare(
        `INSERT INTO generations (${Object.keys(row).join(", ")}) VALUES (${Object.keys(row)
          .map((k) => `@${k}`)
          .join(", ")})`,
      )
      .run(row);
    // What the run leaves out or changes (LoRAs a cloud run can't carry, a length the API rounds) goes back
    // with it, so the composer and API clients can say so; it isn't stored.
    created.push(notes.length ? { ...toGeneration(row), notes } : toGeneration(row));
    if (!waits) void submit(id, route, providerId, plan, req, i);
  }
  ensureRunner();
  return created;
}

/** Where each dependency's output goes: `chain`, or the single-image `chainFrom`. */
function slotsFor(req: GenerationRequest, n: number): ChainSlot[] {
  // Dependencies beyond the listed slots are images (a chain shorter than dependsOn used to crash the launch).
  return Array.from({ length: n }, (_, i) => req.chain?.[i] ?? { slot: "images" as const, position: req.chainFrom ?? "last" });
}

const SLOT_KIND: Record<ChainSlot["slot"], MediaKind> = {
  images: "image",
  endImage: "image",
  video: "video",
  videos: "video",
  audio: "audio",
  voiceAudio: "audio",
  audio2: "audio",
  audios: "audio",
  model3d: "model3d",
  mask: "video",
  prompt: "text",
};

/** Names providers give the same stem (ComfyUI: voice/background, DBS also music/effects; Demucs: vocals…; SAM Audio: target/residual). */
const STEM_ALIASES: Record<string, string[]> = {
  voice: ["voice", "vocals", "speech", "target"],
  background: ["background", "accompaniment", "instrumental", "residual", "no_vocals"],
  music: ["music"],
  effects: ["effects", "sfx"],
};

/**
 * Soundtrack slots a video can fill: a step that made only a clip hands over the clip itself, and the
 * mux reads its sound (ComfyUI's LoadAudio and fal's FFmpeg take a video file as the audio input).
 * Shorts and Mixed Media put the trimmed source's own sound back under the restyled picture this way.
 */
const SOUNDTRACK_SLOTS = new Set<ChainSlot["slot"]>(["audio", "audio2"]);

/** The dependency output a slot takes: the first of the slot's kind, or the one with the slot's `stem`. */
export function pickOutput(outputs: OutputFile[], s: ChainSlot): OutputFile | undefined {
  // A mask: the output made as one (meta.role "mask": a painted window's last tracked frame), else a mask video, else a still.
  if (s.slot === "mask") return outputs.find((o) => o.meta?.role === "mask") ?? outputs.find((o) => o.kind === "video") ?? outputs.find((o) => o.kind === "image");
  const ofKind = outputs.filter((o) => o.kind === SLOT_KIND[s.slot]);
  if (s.index !== undefined) {
    if (!ofKind.length) return undefined;
    const at = (o: OutputFile, i: number) => (typeof o.meta?.index === "number" ? o.meta.index : i);
    const ordered = ofKind.map((o, i) => ({ o, i: at(o, i) })).sort((a, b) => a.i - b.i);
    return (ordered.find((x) => x.i === s.index) ?? ordered[Math.min(s.index, ordered.length - 1)]).o;
  }
  if (!s.stem) return ofKind[0] ?? (SOUNDTRACK_SLOTS.has(s.slot) ? outputs.find((o) => o.kind === "video") : undefined);
  const want = STEM_ALIASES[s.stem.toLowerCase()] ?? [s.stem.toLowerCase()];
  return ofKind.find((o) => typeof o.meta?.stem === "string" && want.includes(o.meta.stem.toLowerCase()));
}

const slotNoun = (s: ChainSlot) => (s.stem ? `${s.stem} stem` : s.slot === "mask" ? "mask" : SLOT_KIND[s.slot]);

/**
 * A planned list (ChainSlot `index` + `of`) that came back too short to read: a frame or two missing at
 * the end is held (pickOutput takes the last one), more fails the step before it is paid for.
 */
export function listShortfall(outputs: OutputFile[], s: ChainSlot): string | null {
  if (s.index === undefined || s.of === undefined) return null;
  const made = outputs.filter((o) => o.kind === SLOT_KIND[s.slot]).length;
  if (made >= s.of - CHAIN_LIST_SLACK) return null;
  const noun = slotNoun(s);
  return `made ${made} ${noun}${made === 1 ? "" : "s"} where ${s.of} were planned`;
}

function placeholderFor(s: ChainSlot): string {
  const kind = SLOT_KIND[s.slot];
  if (kind === "text") return "Placeholder text from an earlier step";
  if (kind === "model3d") return "/api/files/placeholder.glb";
  return kind === "image" ? "/api/files/placeholder.png" : kind === "video" ? "/api/files/placeholder.mp4" : "/api/files/placeholder.wav";
}

/**
 * What a chained step takes from a dependency's output: the file URL, or the text for "prompt".
 * A translation of timed text gets the cue list (so the timing survives); text saved only as a
 * file, or cut short inline (meta.truncated), is read back from it.
 */
export async function chainValue(o: OutputFile | undefined, s: ChainSlot, op?: Generation["op"]): Promise<string | undefined> {
  if (!o) return undefined;
  // The picture as it was made, before a Soul finish replaced it (a look board's next frame: its own grade comes after).
  if (s.raw && typeof o.meta?.original === "string" && o.meta.original) return o.meta.original;
  if (s.slot !== "prompt") return o.url;
  const cues = Array.isArray(o.meta?.cues) && o.meta.cues.length ? (o.meta.cues as Cue[]) : null;
  if (op === "translate" && cues) return JSON.stringify(cues);
  if (typeof o.text === "string" && !o.meta?.truncated) return o.text;
  // Timed text is saved as subtitles: its words come from the cues, not the .srt file.
  if (cues) return cueText(cues);
  if (!o.url) return undefined;
  return readRef(o.url)
    .then((f) => f.data.toString("utf8"))
    .catch(() => undefined);
}

/**
 * Put the dependencies' outputs into the request's inputs, slot by slot (lists keep dependency order).
 * A "prompt" slot gets the dependency's text: it fills "{text}" in the prompt, or becomes the prompt.
 */
export function withChainInputs(req: GenerationRequest, urls: string[]): GenerationRequest {
  const inputs = { ...req.inputs };
  let prompt = req.prompt;
  const slots = slotsFor(req, urls.length);
  for (const k of ["images", "videos", "audios"] as const) {
    const at = (pos: "first" | "last") => slots.flatMap((s, i) => (s.slot === k && (s.position ?? "last") === pos ? [urls[i]] : []));
    const first = at("first");
    const last = at("last");
    if (first.length || last.length) inputs[k] = [...first, ...(inputs[k] ?? []), ...last];
  }
  slots.forEach((s, i) => {
    if (s.slot === "prompt") prompt = prompt?.includes("{text}") ? prompt.replaceAll("{text}", urls[i]) : urls[i];
    else if (s.slot !== "images" && s.slot !== "videos" && s.slot !== "audios") inputs[s.slot] = urls[i];
  });
  return { ...req, prompt, inputs };
}

/**
 * A stored step as it was before the runner filled its chain slots (`chainFilled`): the chained list
 * items come out from the front ("first") and the back ("last"), single slots are emptied, and the
 * step's own items stay. A retry rebuilds the step from new dependencies this way. Text that filled a
 * "prompt" slot can't be told from the prompt, so it stays.
 */
export function unfilledRequest(req: GenerationRequest, deps: number): GenerationRequest {
  const { chainFilled, chainSkipped, ...rest } = req;
  // A fallback's notice belongs to the run that fell back, not to a retry.
  delete rest.notice;
  if (!chainFilled) return chainSkipped ? { ...rest, ...(chainSkipped.prompt !== undefined ? { prompt: chainSkipped.prompt } : {}) } : rest;
  // Optional slots left out filled nothing; the fallback's prompt goes back to the one planned.
  if (chainSkipped?.prompt !== undefined) rest.prompt = chainSkipped.prompt;
  const slots = filledSlots({ ...rest, chainSkipped }, deps);
  const inputs = { ...rest.inputs };
  for (const k of ["images", "videos", "audios"] as const) {
    const count = (pos: "first" | "last") => slots.filter((s) => s.slot === k && (s.position ?? "last") === pos).length;
    const list = inputs[k] ?? [];
    const own = list.slice(count("first"), list.length - count("last"));
    if (own.length) inputs[k] = own;
    else delete inputs[k];
  }
  for (const s of slots) if (s.slot !== "images" && s.slot !== "videos" && s.slot !== "audios" && s.slot !== "prompt") delete inputs[s.slot];
  return { ...rest, inputs: Object.keys(inputs).length ? inputs : undefined };
}

/** Generations this process is handing to a provider right now (shared across hot reloads and bundles). */
declare global {
  var __fuobeSubmitting: Set<string> | undefined;
}
const submitting = (): Set<string> => (globalThis.__fuobeSubmitting ??= new Set<string>());

/**
 * A chain runs all for real or all as a demo (a demo join of paid clips, or a paid step fed a demo
 * placeholder, helps nobody). Returns the error for a step that can't match its dependencies, and
 * whether it should run as a demo because they did.
 */
function chainMode(p: { demo: boolean; plan: { model: { name: string } }; route: ModelRoute }, deps: Pick<Row, "provider">[], asked?: Pick<GenerationRequest, "demo">): { error?: string; forceDemo?: boolean } {
  const demoDeps = deps.filter((d) => d.provider === "mock").length;
  if (p.demo && demoDeps < deps.length) {
    const needs = p.route.provider === "llm" ? "Claude or Ollama" : provider(p.route.provider).label;
    return { error: `${p.plan.model.name} needs ${needs} to continue what the earlier steps made for real — connect it in Settings, then retry` };
  }
  if (!p.demo && demoDeps > 0) {
    // A dry run (GenerationRequest.demo) stays a demo even with Settings → Demo mode off.
    if (getSetting("demoMode") === "off" && !asked?.demo) return { error: "An earlier step ran as a demo — retry it with its provider connected" };
    return { forceDemo: true };
  }
  return {};
}

/** A waiting row's dependency ids as a json_each source (depends_on is one id, or a JSON list). */
const DEP_IDS = "json_each(CASE WHEN substr(g.depends_on, 1, 1) = '[' AND json_valid(g.depends_on) THEN g.depends_on ELSE json_array(g.depends_on) END) d";

/**
 * Waiting steps that can move: none of their dependencies is still queued or running (so they launch), or one
 * failed, was canceled or is gone (so they fail now, not after the others finish). A per-frame render keeps
 * hundreds of steps waiting for its lanes, and a plain "oldest 50 waiting" would hold every chain started after
 * it until its backlog drained. The steps this process is handing to a provider right now are still "queued":
 * the limit makes room for them.
 */
const READY_DEPENDENTS = `SELECT g.* FROM generations g
  WHERE g.status = 'queued' AND g.external_id IS NULL AND g.depends_on IS NOT NULL
    AND (
      NOT EXISTS (SELECT 1 FROM ${DEP_IDS} JOIN generations dep ON dep.id = d.value WHERE dep.status IN ('queued', 'running'))
      OR EXISTS (SELECT 1 FROM ${DEP_IDS} LEFT JOIN generations dep ON dep.id = d.value WHERE dep.id IS NULL OR dep.status IN ('failed', 'canceled'))
    )
  ORDER BY g.created_at ASC LIMIT ?`;

/** The error a waiting step gets when an input failed (framesProgress tells these from a step's own failure). */
export const waitedOnFailure = (frame?: boolean) => `${frame ? "The previous frame" : "An earlier step"} didn't finish`;
/** What a step dropped by dropUnused says (canceled, not by anyone: the steps it was for failed). */
export const DROPPED_UNUSED = "Stopped before it ran: the steps it was for failed";

/** Ids in a depends_on column that name `id` (one id, or a JSON list). */
const DEPENDENTS_OF = "(depends_on = @id OR (substr(depends_on, 1, 1) = '[' AND instr(depends_on, @quoted) > 0))";

/**
 * A waiting step marked dropWhenUnused whose every dependent has failed or been canceled can no longer be
 * used: cancel it (nothing was spent on it) and look again at the steps it waited for. `ids` are the inputs
 * of a step that just failed. A step being handed to its provider right now is left alone.
 */
function dropUnused(ids: string[]): void {
  const todo = [...ids];
  // Settled: dropped, or not a waiting dropWhenUnused step. One still used is looked at again when a step using it is dropped.
  const settled = new Set<string>();
  const live = db().prepare(`SELECT 1 FROM generations WHERE status IN ('queued', 'running') AND ${DEPENDENTS_OF} LIMIT 1`);
  while (todo.length) {
    const id = todo.pop()!;
    if (settled.has(id) || submitting().has(id)) continue;
    const r = db().prepare("SELECT status, external_id, depends_on, request_json FROM generations WHERE id = ?").get(id) as Pick<Row, "status" | "external_id" | "depends_on" | "request_json"> | undefined;
    if (!r || r.status !== "queued" || r.external_id || !r.depends_on || !(JSON.parse(r.request_json) as GenerationRequest).dropWhenUnused) {
      settled.add(id);
      continue;
    }
    if (live.get({ id, quoted: JSON.stringify(id) })) continue;
    settled.add(id);
    const now = Date.now();
    db()
      .prepare("UPDATE generations SET status = 'canceled', error = ?, message = NULL, completed_at = ?, updated_at = ? WHERE id = ? AND status = 'queued' AND external_id IS NULL")
      .run(DROPPED_UNUSED, now, now, id);
    todo.push(...depIds(r.depends_on));
  }
}

/**
 * A step with optional inputs whose steps failed (ChainSlot.optional): its chain without those slots, the fallback's
 * prompt and notice, and what was left out (so a retry can put the request back as it was: unfilledRequest).
 */
export function withoutSkipped(req: GenerationRequest, slots: ChainSlot[], skipped: number[]): GenerationRequest {
  const left = skipped.map((i) => slots[i]);
  const prompt = left.map((s) => s.optional?.prompt).find((p) => p !== undefined);
  const notice = [req.notice, ...left.map((s) => s.optional?.notice)].filter(Boolean).join(" · ");
  return {
    ...req,
    chainSkipped: { slots: skipped, ...(prompt !== undefined && req.prompt !== undefined ? { prompt: req.prompt } : {}) },
    ...(prompt !== undefined ? { prompt } : {}),
    ...(notice ? { notice } : {}),
  };
}

/** The chain slots a step fills: its own, less the optional ones left out (chainSkipped). */
const filledSlots = (req: GenerationRequest, n: number): ChainSlot[] => slotsFor(req, n).filter((_, i) => !req.chainSkipped?.slots.includes(i));

/** When a step after real ComfyUI steps first found ComfyUI not answering, by step id (shared across hot reloads). */
declare global {
  var __fuobeComfyWaits: Map<string, number> | undefined;
}
const comfyWaits = (): Map<string, number> => (globalThis.__fuobeComfyWaits ??= new Map<string, number>());
/** How long such a step waits for ComfyUI to answer again before chainMode fails it. */
export const COMFY_WAIT = { ms: 60_000 };

/** Launch dependent jobs whose inputs finished; fail the ones whose inputs failed. Never waits for an upload. */
async function advanceDependents(): Promise<void> {
  const rows = db().prepare(READY_DEPENDENTS).all(50 + submitting().size) as Row[];
  // A forced look at ComfyUI, at most one a sweep, for the steps that found it not answering.
  let lookedAgain: Promise<boolean> | undefined;
  for (const r of rows) {
    if (submitting().has(r.id)) continue;
    // A step queued before its model was retired runs on what replaced it (and its row says so).
    const moved = currentRequest(JSON.parse(r.request_json) as GenerationRequest);
    const stored = moved.request;
    const allIds = depIds(r.depends_on);
    const allSlots = slotsFor(stored, allIds.length);
    const allDeps = allIds.map(
      (id) => db().prepare("SELECT status, provider, outputs_json, request_json FROM generations WHERE id = ?").get(id) as Pick<Row, "status" | "provider" | "outputs_json" | "request_json"> | undefined,
    );
    const earlier = stored.frame ? "The previous frame" : "An earlier step";
    const fail = (error: string) => {
      update(r.id, { status: "failed", error, message: null, completed_at: Date.now() });
      // Steps waiting only to feed this one (the other lanes of a per-frame render) are dropped before they are paid for.
      dropUnused(allIds);
    };
    const broken = (d: (typeof allDeps)[number]) => !d || d.status === "failed" || d.status === "canceled";
    // An optional input whose step failed is left out (Genjutsu's anchor frame): the step runs without it.
    const skipped = allSlots.flatMap((s, i) => (s.optional && broken(allDeps[i]) ? [i] : []));
    if (allDeps.some((d, i) => broken(d) && !skipped.includes(i))) {
      fail(waitedOnFailure(!!stored.frame));
      continue;
    }
    const keep = (_: unknown, i: number) => !skipped.includes(i);
    const deps = allDeps.filter(keep);
    const slots = allSlots.filter(keep);
    if (deps.some((d) => d!.status !== "succeeded")) continue;
    const request = skipped.length ? withoutSkipped(stored, allSlots, skipped) : stored;
    // What changed upstream (an earlier fallback) is said on this step too, down to the finished result.
    const notices = [request.notice, ...deps.map((d) => (JSON.parse(d!.request_json) as GenerationRequest).notice)].filter((x): x is string => !!x);
    if (notices.length) request.notice = [...new Set(notices)].join(" · ");
    const outputs = deps.map((d) => JSON.parse(d!.outputs_json) as OutputFile[]);
    const short = slots.map((s, i) => listShortfall(outputs[i], s)).find(Boolean);
    if (short) {
      fail(`${earlier} ${short}`);
      continue;
    }
    submitting().add(r.id);
    let handedOff = false;
    try {
      // The planned op (r.op), not request.op: a translate whose op was inferred still gets the cue list.
      const values = await Promise.all(outputs.map((o, i) => chainValue(pickOutput(o, slots[i]), slots[i], r.op)));
      const missing = values.findIndex((u) => !u);
      if (missing >= 0) {
        fail(`${earlier} has no ${slotNoun(slots[missing])} to use`);
        continue;
      }
      // Routing reads cached reachability: make sure it's fresh for local engines. An Original counts with the routes of
      // the engine it runs on, ComfyUI taken as answering: one on the cloud doesn't use it, so doesn't wait for it.
      const model = getModel(request.modelId);
      const runs = model && dualEngine(model) ? onEngine(model, pickEngine(model, request.engine, engineMode(), () => true)) : model;
      if (runs?.routes.some((x) => x.provider === "comfyui") && !(await probeComfy()) && deps.some((d) => d!.provider === "comfyui")) {
        // The earlier steps ran for real on ComfyUI: one missed check (a server busy finishing them, or restarting)
        // mustn't make this one a demo, which chainMode fails. Look again at once (one forced look a sweep), then wait
        // for the next sweeps (COMFY_WAIT from the first miss) before chainMode has its say.
        const first = comfyWaits().get(r.id);
        const back = first === undefined && (await (lookedAgain ??= probeComfy(true)));
        if (!back && first === undefined) {
          comfyWaits().set(r.id, Date.now());
          update(r.id, { message: "Waits for ComfyUI to answer" });
          continue;
        }
        if (!back && Date.now() - first! < COMFY_WAIT.ms) continue;
      }
      comfyWaits().delete(r.id);
      if (model?.routes.some((x) => x.provider === "llm")) await probeOllama();
      // Filled with the slots that have an input; stored with its whole chain (and what was skipped) for a retry.
      const filled = withChainInputs({ ...request, chain: slots }, values as string[]);
      const original: GenerationRequest = { ...filled, chain: request.chain, chainFilled: true };
      const prepared = prepare(original);
      const mode = chainMode(prepared, deps as Pick<Row, "provider">[], original);
      if (mode.error) throw new Error(mode.error);
      const p = mode.forceDemo ? { ...prepared, demo: true, providerId: "mock" as const, cost: 0 } : prepared;
      update(r.id, {
        ...(moved.note && { model_id: p.plan.model.id, engine: p.plan.model.engine }),
        provider: p.providerId,
        op: p.plan.op,
        kind: outputKind(p.plan.op, p.plan.model),
        prompt: p.plan.prompt,
        cost_usd: p.cost,
        request_json: JSON.stringify(original),
        message: mode.forceDemo ? "Demo — an earlier step ran as a demo" : p.demo ? "Demo mode — no provider connected" : "Submitting",
      });
      // In the background: an upload must not hold up the runner's other polls.
      handedOff = true;
      void submit(r.id, p.route, p.providerId, p.plan, p.req, 0);
    } catch (e) {
      fail((e as Error).message);
    } finally {
      if (!handedOff) submitting().delete(r.id);
    }
  }
}

const statusOf = (id: string) => (db().prepare("SELECT status FROM generations WHERE id = ?").get(id) as Pick<Row, "status"> | undefined)?.status;

/** Start the timeout clock: the job has reached its provider. */
function recordSubmission(id: string, at: number): void {
  db()
    .prepare("INSERT INTO generation_runs (id, submitted_at, started_at) VALUES (?, ?, NULL) ON CONFLICT(id) DO UPDATE SET submitted_at = excluded.submitted_at, started_at = NULL")
    .run(id, at);
}

async function submit(
  id: string,
  route: ModelRoute,
  providerId: ProviderId,
  plan: ReturnType<typeof planGeneration>,
  req: GenerationRequest,
  index: number,
): Promise<void> {
  const adapter = provider(providerId);
  submitting().add(id);
  try {
    const prep = async (ref?: string) => {
      if (!ref) return undefined;
      const f = await readRef(ref);
      return adapter.prepareFile(f.data, f.contentType, f.name, route);
    };
    // The input clip's header (size, frame rate, length): upscalers that take a factor and frame-count routes read it.
    let source: Pick<GenInput, "sourceSize" | "sourceFps" | "sourceDuration"> = {};
    const prepVideo = async (ref?: string) => {
      if (!ref) return undefined;
      const f = await readRef(ref);
      const facts = mediaFacts(f.data);
      source = {
        ...(facts.width && facts.height ? { sourceSize: { width: facts.width, height: facts.height } } : {}),
        ...(facts.fps ? { sourceFps: facts.fps } : {}),
        ...(facts.duration ? { sourceDuration: facts.duration } : {}),
      };
      return adapter.prepareFile(f.data, f.contentType, f.name, route);
    };
    // A talking avatar is as long as its voice (fal's InfiniteTalk and Wan 2.2 S2V take a frame count): the voice's header.
    const prepVoice = async (ref?: string) => {
      if (!ref) return undefined;
      const f = await readRef(ref);
      const facts = mediaFacts(f.data);
      if (facts.duration && !source.sourceDuration) source = { ...source, sourceDuration: facts.duration };
      return adapter.prepareFile(f.data, f.contentType, f.name, route);
    };
    const prepMask = async (ref?: string) => {
      if (!ref) return undefined;
      const f = await readRef(ref);
      const fmt = route.map?.maskFormat;
      const data = fmt && fmt !== "white" && f.contentType === "image/png" ? convertMask(f.data, fmt) : f.data;
      return adapter.prepareFile(data, f.contentType, f.name, route);
    };
    let prompt = plan.prompt;
    if (req.params?.enhancePrompt && prompt) {
      update(id, { message: "Enhancing prompt" });
      const words = plan.soul?.words;
      const at = words ? prompt.indexOf(words) : -1;
      if (words && at >= 0) {
        // Soul: only the user's words are expanded (60–120 words of subject, wardrobe, place, light); the look stays as it is.
        const longer = await enhanceSoulWords(words).catch(() => words);
        prompt = prompt.slice(0, at) + longer + prompt.slice(at + words.length);
      } else prompt = await enhancePrompt(prompt, plan.model.kind, plan.op).catch(() => prompt);
      update(id, { prompt });
    }
    const input: GenInput = {
      ...plan.params,
      prompt,
      negativePrompt: req.negativePrompt,
      images: (await Promise.all((req.inputs?.images ?? []).map(prep))).filter(Boolean) as string[],
      endImage: await prep(req.inputs?.endImage),
      mask: await prepMask(req.inputs?.mask),
      video: await prepVideo(req.inputs?.video),
      audio: await (plan.op === "avatar" ? prepVoice : prep)(req.inputs?.audio),
      audio2: await prep(req.inputs?.audio2),
      voiceAudio: await prep(req.inputs?.voiceAudio),
      voiceAudio2: await prep(req.inputs?.voiceAudio2),
      videos: (await Promise.all((req.inputs?.videos ?? []).map(prep))).filter(Boolean) as string[],
      audios: (await Promise.all((req.inputs?.audios ?? []).map(prep))).filter(Boolean) as string[],
      model3d: await prep(req.inputs?.model3d),
      loras: plan.loras,
      // Vary seeds across a batch so N jobs don't return N identical results.
      seed: plan.params.seed !== undefined && plan.params.seed >= 0 ? plan.params.seed + index : undefined,
    };
    // What the caller said about the clip's length wins; the header fills the rest.
    Object.assign(input, { ...source, ...(plan.params.sourceDuration !== undefined && { sourceDuration: plan.params.sourceDuration }) });
    // A talking avatar renders as long as its voice: priced for it once its header is read (an API call that didn't say).
    if (plan.op === "avatar" && plan.params.sourceDuration === undefined && input.sourceDuration && providerId !== "mock" && plan.model.engine !== "open") {
      update(id, { cost_usd: estimateCost(plan.model, { ...plan.params, sourceDuration: input.sourceDuration }, 1, plan.op, plan.loras.length > 0 && !!route.loraEndpoint) });
    }
    // A clip edit of a clip sent as it is (Edit video, an API call; the studios that cut clips keep to the windows
    // themselves): one outside the model's window is refused before it's paid for (Happy Horse bills 60 s and returns
    // 15), and one that keeps the clip's length is priced for it once the header is read (a call that didn't say).
    if (plan.op === "v2v" && input.sourceDuration && !req.chain?.length && req.params?.duration === undefined && providerId !== "mock" && plan.model.engine !== "open") {
      const problem = clipWindowProblem(plan.model, input.sourceDuration);
      if (problem) throw new Error(problem);
      if (plan.params.sourceDuration === undefined && clipEditSeconds(plan.model, input, plan.op) !== undefined) {
        update(id, { cost_usd: estimateCost(plan.model, { ...plan.params, sourceDuration: input.sourceDuration }, 1, plan.op, plan.loras.length > 0 && !!route.loraEndpoint) });
      }
    }
    // An upscale that wouldn't enlarge the clip (a 1080p clip at a default 1080p; a 4K clip would even shrink):
    // a tier the model only defaulted to moves up to the next one it offers, one the caller picked is refused.
    if (plan.op === "upscale-video" && input.sourceSize) {
      const tier = upscaleTier(input.resolution, plan.model.options.resolutions, input.sourceSize, req.params?.resolution !== undefined);
      if ("error" in tier) throw new Error(tier.error);
      if (tier.resolution !== input.resolution) {
        input.resolution = tier.resolution;
        if (providerId !== "mock" && plan.model.engine !== "open") update(id, { cost_usd: estimateCost(plan.model, { ...plan.params, resolution: tier.resolution }, 1, plan.op) });
      }
    }
    // LoRA files: ComfyUI gets the ones it lacks downloaded into its loras folder; a cloud run gets a civitai
    // file mirrored once to the provider's storage (the civitai key never leaves this server).
    if (input.loras?.length && (providerId === "fal" || providerId === "replicate")) {
      input.loras = await prepareCloudLoras(input.loras, providerId, (data, name) => adapter.prepareFile(data, "application/octet-stream", name, route), (message) => update(id, { message }));
    } else if (providerId === "comfyui" && (input.loras?.length || graphLoras(route.endpoint, input.extra).length)) {
      // A graph that loads its own LoRAs (Genjutsu's Character swap: the Turbo and swap LoRAs) gets them downloaded too.
      await ensureLorasOnComfy([...(input.loras ?? []), ...graphLoras(route.endpoint, input.extra)], await comfyLoraFiles(route), (message) => update(id, { message }));
    }
    const res = await adapter.submit({ generationId: id, model: plan.model, route, input });
    const now = Date.now();
    const status = statusOf(id);
    if (!status || status === "canceled") {
      // Canceled (or deleted) while it was being handed over: stop the provider's job too.
      await adapter.cancel?.({ externalId: res.externalId, meta: res.meta ?? {}, route, model: plan.model, createdAt: now }).catch(() => {});
      if (status) update(id, { external_id: res.externalId, external_meta_json: JSON.stringify(res.meta ?? {}), message: null });
      return;
    }
    db().transaction(() => {
      update(id, {
        external_id: res.externalId,
        external_meta_json: JSON.stringify(res.meta ?? {}),
        provider_input_json: res.payload ? JSON.stringify(res.payload).slice(0, 200_000) : null,
        message: "Queued",
      });
      recordSubmission(id, now);
    })();
  } catch (e) {
    // A cancel during the hand-over stays a cancel.
    if (statusOf(id) !== "canceled") update(id, { status: "failed", error: (e as Error).message, completed_at: Date.now(), message: null });
  } finally {
    submitting().delete(id);
  }
}

// ---------------------------------------------------------------------------
// Polling loop

const POLL_MS = 1500;
/** Jobs about to finish (progress ≥ 0.9) are polled this often, so results land sooner. */
const FAST_POLL_MS = 500;
/** How long a job may run once its provider has started it… */
const TIMEOUT_MS = 45 * 60 * 1000;
/** …and how long it may wait in the provider's queue first (a busy local GPU works through jobs one by one). */
const QUEUE_TIMEOUT_MS = 4 * 60 * 60 * 1000;
/** A row this old with no external id, that no submit in this process is working on, was cut off by a restart. */
const STALE_SUBMIT_MS = 2 * 60 * 1000;

interface RunnerState {
  timer: NodeJS.Timeout;
  busy: boolean;
  tick: () => Promise<void>;
  fastTimer?: NodeJS.Timeout;
  fastBusy?: boolean;
  fast?: () => Promise<void>;
  /** Rows being polled right now (the fast lane and the tick never poll one row twice at once). */
  polling?: Set<string>;
}

declare global {
  var __fuobeRunner: RunnerState | undefined;
}

/**
 * Start the background runner (once per process; started at boot by src/instrumentation.ts).
 * Also installs the live-update hooks and primes the reachability probes routing reads.
 */
export function ensureRunner(): void {
  watchGenerations(db());
  const cur = globalThis.__fuobeRunner;
  if (cur) {
    // After a dev hot-reload, point the existing timers at this module's (fresh) code.
    cur.tick = tick;
    cur.fast = fastTick;
    cur.polling ??= new Set();
    if (!cur.fastTimer) {
      cur.fastTimer = setInterval(() => void globalThis.__fuobeRunner?.fast?.(), FAST_POLL_MS);
      cur.fastTimer.unref?.();
    }
    return;
  }
  const state: RunnerState = {
    busy: false,
    tick,
    fast: fastTick,
    polling: new Set(),
    timer: setInterval(() => void globalThis.__fuobeRunner?.tick(), POLL_MS),
    fastTimer: setInterval(() => void globalThis.__fuobeRunner?.fast?.(), FAST_POLL_MS),
  };
  state.timer.unref?.();
  state.fastTimer?.unref?.();
  globalThis.__fuobeRunner = state;
  void probeComfy().catch(() => false);
  void probeOllama().catch(() => false);
  sweepInterrupted();
}

/** Jobs that never got an external id (the server died mid-submit) can't be recovered. Runs every tick. */
function sweepInterrupted(): void {
  const rows = db()
    .prepare("SELECT id FROM generations WHERE status IN ('queued','running') AND external_id IS NULL AND depends_on IS NULL AND created_at < ?")
    .all(Date.now() - STALE_SUBMIT_MS) as Pick<Row, "id">[];
  const busy = submitting();
  for (const r of rows) {
    if (busy.has(r.id)) continue;
    update(r.id, { status: "failed", error: "Interrupted before it reached the provider", completed_at: Date.now(), message: null });
  }
}

async function pollGuarded(r: Row): Promise<void> {
  const polling = (globalThis.__fuobeRunner!.polling ??= new Set());
  if (polling.has(r.id)) return;
  polling.add(r.id);
  try {
    await pollOne(r);
  } catch (e) {
    update(r.id, { message: `Poll error: ${(e as Error).message}` });
  } finally {
    polling.delete(r.id);
  }
}

async function tick(): Promise<void> {
  const state = globalThis.__fuobeRunner;
  if (!state || state.busy) return;
  state.busy = true;
  try {
    sweepInterrupted();
    const active = db()
      .prepare("SELECT * FROM generations WHERE status IN ('queued','running') AND external_id IS NOT NULL ORDER BY created_at ASC LIMIT 50")
      .all() as Row[];
    await Promise.all([...active.map(pollGuarded), pollTrainings().catch(() => {}), advanceDependents().catch(() => {})]);
  } finally {
    state.busy = false;
  }
}

async function fastTick(): Promise<void> {
  const state = globalThis.__fuobeRunner;
  if (!state || state.fastBusy) return;
  state.fastBusy = true;
  try {
    const rows = db()
      .prepare(
        "SELECT g.*, r.started_at AS run_started_at FROM generations g LEFT JOIN generation_runs r ON r.id = g.id WHERE g.status = 'running' AND g.external_id IS NOT NULL AND g.progress IS NOT NULL ORDER BY g.created_at ASC LIMIT 50",
      )
      .all() as (Row & { run_started_at: number | null })[];
    const now = Date.now();
    // At 90% (or on course to be there by now, at the pace it has reported since it started).
    const nearlyDone = rows.filter((r) => {
      const p = r.progress ?? 0;
      if (p >= 0.9) return true;
      const ran = r.run_started_at ? r.updated_at - r.run_started_at : 0;
      return ran > 0 && p > 0 && (p * (now - r.run_started_at!)) / ran >= 0.9;
    });
    await Promise.all(nearlyDone.slice(0, 20).map(pollGuarded));
  } finally {
    state.fastBusy = false;
  }
}

function runRoute(model: NonNullable<ReturnType<typeof getModel>>, r: Pick<Row, "op" | "provider">): ModelRoute {
  return model.routes.find((x) => x.op === r.op && (x.provider === r.provider || r.provider === "mock")) ?? model.routes[0];
}

function pollContext(r: Row, model: NonNullable<ReturnType<typeof getModel>>): PollContext {
  return { externalId: r.external_id!, meta: JSON.parse(r.external_meta_json ?? "{}") as Record<string, unknown>, route: runRoute(model, r), model, createdAt: r.created_at };
}

async function pollOne(r: Row): Promise<void> {
  const model = getModel(r.model_id);
  if (!model) {
    // A job on a model Fuobe retired with its provider (replaced.ts) can't be collected: Reuse runs it on the replacement.
    const retired = !!replacedBy(r.model_id) || !Object.hasOwn(PROVIDERS, r.provider);
    update(r.id, { status: "failed", error: retired ? RETIRED_PROVIDER_ERROR : `Model ${r.model_id} no longer exists`, completed_at: Date.now(), message: null });
    return;
  }
  // The clock runs from when the provider got the job (and from when it started it), not from creation:
  // a chained step created at the start of a long pipeline gets its full time once it's submitted.
  const now = Date.now();
  let run = db().prepare("SELECT submitted_at, started_at FROM generation_runs WHERE id = ?").get(r.id) as { submitted_at: number; started_at: number | null } | undefined;
  if (!run) {
    // Submitted before this was recorded (an upgrade mid-job): start counting now.
    recordSubmission(r.id, now);
    run = { submitted_at: now, started_at: null };
  }
  const ctx = pollContext(r, model);
  // Poll first: a job that finished while the server was asleep or down is collected, not timed out.
  let res: PollResult | undefined;
  let pollError: unknown;
  try {
    res = await provider(r.provider).poll(ctx);
  } catch (e) {
    pollError = e;
  }
  if (!res || res.state === "queued" || res.state === "running") {
    // A job that has just left the queue gets its full running time from now.
    const startsNow = res?.state === "running" && !run.started_at;
    const overdue = run.started_at ? now - run.started_at > TIMEOUT_MS : !startsNow && now - run.submitted_at > QUEUE_TIMEOUT_MS;
    if (overdue) {
      // Stop the provider's job too, so it doesn't keep rendering (or billing) for nothing.
      await provider(r.provider)
        .cancel?.(ctx)
        .catch(() => {});
      update(r.id, {
        status: "failed",
        error: run.started_at ? `Timed out after ${TIMEOUT_MS / 60_000} minutes` : `Timed out waiting ${QUEUE_TIMEOUT_MS / 3_600_000} hours in the provider's queue`,
        completed_at: now,
        message: null,
      });
      return;
    }
    if (!res) throw pollError;
    if (startsNow) db().prepare("UPDATE generation_runs SET started_at = ? WHERE id = ?").run(Date.now(), r.id);
    update(r.id, { status: res.state, progress: res.progress ?? r.progress, message: res.message ?? null });
    return;
  }
  if (res.state === "failed") {
    update(r.id, { status: "failed", error: res.error, completed_at: Date.now(), message: null });
    return;
  }
  // Mark first so a slow download isn't polled twice.
  update(r.id, { status: "running", progress: 0.99, message: "Saving results" });
  const outputs: OutputFile[] = [];
  // Remove background: of a cut-out and its mask (BiRefNet's answer), the one asked for (params.matteOutput).
  const matte = r.op === "bg-remove-video" ? (JSON.parse(r.request_json) as GenerationRequest).params?.matteOutput : undefined;
  // The face mosaic's cloud step answers with the faces' masks: the result is the picture, pixelated under them.
  const faceMasks = r.op === "face-mosaic" && res.outputs.length > 0 && (res.outputs as RichOutput[]).every((o) => o.meta?.role === "mask" && Array.isArray(o.meta.masks));
  if (faceMasks) {
    try {
      outputs.push(await mosaicOutput(r, res.outputs as RichOutput[]));
    } catch (e) {
      update(r.id, { status: "failed", error: (e as Error).message, completed_at: Date.now(), message: null });
      return;
    }
  } else {
    for (const o of keepMatte(res.outputs as RichOutput[], matte)) {
      try {
        outputs.push(await persistOutput(o, r.id));
      } catch (e) {
        outputs.push({ url: o.url, kind: o.kind ?? r.kind, ...inlineText(o.text, o.meta), ...(o.draftId ? { draftId: o.draftId } : {}) });
        console.warn(`[fuobe] could not save output for ${r.id}: ${(e as Error).message}`);
      }
    }
  }
  // Fuobe Soul: what follows in the browser (the look's grade, an overlay, Soul Cinema's 21:9 crop), on each image;
  // API clients read it as meta.
  // A storyboard frame with a look gets the look's finish whatever model made it (a 21:9 board is cropped after).
  const board = (JSON.parse(r.request_json) as GenerationRequest).frame;
  const boardPost = board?.look ? soulPostSteps(SOUL_MODELS.soul, board.look) : undefined;
  const post = boardPost ? { ...boardPost, ...(board?.crop && { crop: board.crop }) } : soulPostSteps(r.model_id, r.preset_id, soulKind(r.model_id) ? requestAspect(r.request_json) : undefined);
  if (post) for (const [i, o] of outputs.entries()) if (o.kind === "image") outputs[i] = { ...o, meta: { ...o.meta, ...post } };
  // Fuobe DoP's colour-grade effects: the grade the browser applies to the clip (the result's "Apply the grade" step).
  const grade = isDop(r.model_id) && r.preset_id ? getPreset(r.preset_id)?.grade : undefined;
  if (grade) for (const [i, o] of outputs.entries()) if (o.kind === "video") outputs[i] = { ...o, meta: { ...o.meta, grade } };
  update(r.id, {
    status: "succeeded",
    outputs_json: JSON.stringify(outputs),
    progress: 1,
    message: null,
    completed_at: Date.now(),
  });
}

/**
 * The face mosaic's cloud step (fal's SAM 3.1 answered with the faces' masks): the picture it looked at, pixelated under
 * every mask, made here when the picture and the masks are PNGs (fal's Soul pictures are), so the Library, share links,
 * Canvas and API clients get the finished picture. A picture the server can't decode is kept as it is with the masks
 * (meta.mosaic) for the browser to pixelate (src/components/studio/soul-finish.ts). No face found: the picture as it is, as
 * the GPU graph returns it. The masks are kept as files of the generation (meta.masks).
 */
async function mosaicOutput(r: Row, given: RichOutput[]): Promise<OutputFile> {
  const req = JSON.parse(r.request_json) as GenerationRequest;
  const source = req.inputs?.images?.[0];
  if (!source) throw new Error("The face mosaic has no picture to pixelate");
  const asked = req.params?.extra?.mosaicScale;
  const scale = typeof asked === "number" && asked > 0 && asked < 1 ? asked : MOSAIC_SCALE;
  const links = given.flatMap((o) => (o.meta?.masks as unknown[]).filter((u): u is string => typeof u === "string" && !!u));
  const masks: string[] = [];
  for (const [i, url] of [...new Set(links)].entries()) masks.push(String(await keepLink(url, `mask-${i}`, r.id)));
  const picture = await readRef(source);
  let data = picture.data;
  let contentType = picture.contentType;
  let done = !masks.length;
  if (masks.length) {
    try {
      const img = decodePng(picture.data);
      const layers = await Promise.all(masks.map(async (m) => decodePng((await readRef(m)).data)));
      if (layers.some((l) => l.width !== img.width || l.height !== img.height)) throw new Error("The masks aren't the picture's size");
      const view = (b: Buffer) => new Uint8ClampedArray(b.buffer, b.byteOffset, b.byteLength);
      mosaicPixels(view(img.data), unionMasks(layers.map((l) => view(l.data))), img.width, img.height, scale);
      data = encodePng(img);
      contentType = "image/png";
      done = true;
    } catch (e) {
      console.warn(`[fuobe] face mosaic ${r.id} is left to the browser: ${(e as Error).message}`);
    }
  }
  const asset = saveFile({ data, contentType, source: "generation", generationId: r.id });
  return {
    url: asset.url,
    kind: "image",
    contentType: asset.contentType,
    assetId: asset.id,
    meta: { masks, faces: masks.length, ...(!done && { mosaic: { source: asset.url, masks, scale } }) },
  };
}

/** Outputs may carry text (transcripts, translations, scripts) and structured extras (layer boxes, cues, stems). */
type RichOutput = RemoteOutput & { text?: string; meta?: Record<string, unknown> };

/**
 * Text kept inline on the generation. Every list page and live event carries it, so longer text
 * (long transcripts, scripts) is cut there, marked `meta.truncated`, and read in full from its file.
 */
export const MAX_INLINE_TEXT = 64_000;

function inlineText(text: string | undefined, meta: Record<string, unknown> | undefined): Pick<OutputFile, "text" | "meta"> {
  if (text === undefined) return meta ? { meta } : {};
  if (text.length <= MAX_INLINE_TEXT) return { text, ...(meta && { meta }) };
  return { text: text.slice(0, MAX_INLINE_TEXT), meta: { ...meta, truncated: true } };
}

/**
 * Extra files a result carries as links are kept too, so the Library never depends on a provider's expiring URL:
 * meta.artifacts (LTX HDR's EXR zip, Higgsfield's fbx / zip), meta.formats (a 3D model's other formats, a rig's FBX
 * and its walk and run cycles, SAM 3D's splat) and meta.preview (a 3D model's render, the cut-out a splat was
 * made from). Links are streamed to disk (an EXR zip runs to gigabytes); one that can't be fetched stays as it
 * was (the result's actions still offer it). A link to the main file itself (`main`) is left for persistOutput.
 */
export async function persistArtifacts(meta: Record<string, unknown> | undefined, generationId: string, main?: string): Promise<Record<string, unknown> | undefined> {
  if (!meta) return meta;
  let out = meta;
  for (const key of LINK_MAPS) {
    const links = meta[key];
    if (!links || typeof links !== "object" || Array.isArray(links)) continue;
    const kept: Record<string, unknown> = {};
    for (const [k, v] of Object.entries(links as Record<string, unknown>)) kept[k] = v === main ? v : await keepLink(v, key === "artifacts" ? k : `${key}-${k}`, generationId);
    out = { ...out, [key]: kept };
  }
  for (const key of LINKS) if (typeof meta[key] === "string" && meta[key] !== main) out = { ...out, [key]: await keepLink(meta[key], key, generationId) };
  return out;
}

/** Maps of extra files by name, and single extra files, that a result links to (see persistArtifacts). */
const LINK_MAPS = ["artifacts", "formats"] as const;
const LINKS = ["preview"] as const;

/** A provider's link stored as a file of the generation (its local URL), or the link as it was when it can't be fetched. */
async function keepLink(v: unknown, label: string, generationId: string): Promise<unknown> {
  if (typeof v !== "string" || !/^(https?:|data:)/.test(v)) return v;
  try {
    if (v.startsWith("data:")) {
      const f = await readRef(v);
      return saveFile({ data: f.data, contentType: f.contentType, source: "generation", generationId }).url;
    }
    const dest = path.join(scratchDir(), `${generationId}-${label}-${nanoid(6)}`);
    const res = await fetchRemoteToFile(v, dest);
    const name = new URL(res.url).pathname.split("/").pop() || undefined;
    const header = res.contentType && res.contentType !== "application/octet-stream" ? res.contentType : null;
    return adoptFile({ from: dest, contentType: header ?? contentTypeFor(name ?? "", "application/octet-stream"), name, source: "generation", generationId }).url;
  } catch (e) {
    console.warn(`[fuobe] could not keep the ${label} file of ${generationId}: ${(e as Error).message}`);
    return v;
  }
}

/** The extra links that pointed at the main file point at its stored copy. */
function relinkMain(meta: Record<string, unknown> | undefined, from: string, to: string): Record<string, unknown> | undefined {
  if (!meta || !from) return meta;
  let out = meta;
  for (const key of LINK_MAPS) {
    const links = meta[key];
    if (!links || typeof links !== "object" || Array.isArray(links) || !Object.values(links).includes(from)) continue;
    out = { ...out, [key]: Object.fromEntries(Object.entries(links as Record<string, unknown>).map(([k, v]) => [k, v === from ? to : v])) };
  }
  for (const key of LINKS) if (meta[key] === from) out = { ...out, [key]: to };
  return out;
}

async function persistOutput(o: RichOutput, generationId: string): Promise<OutputFile> {
  const linked = await persistArtifacts(o.meta, generationId, o.url);
  let data: Buffer;
  let contentType = o.contentType;
  if (!o.url && o.text !== undefined) {
    data = Buffer.from(o.text);
    contentType ??= "text/plain";
  } else if (o.url.startsWith("sample:")) {
    const file = path.join(process.cwd(), "public", "samples", path.basename(o.url.slice(7)));
    data = fs.readFileSync(file);
    contentType ??= contentTypeFor(file);
  } else if (o.url.startsWith("data:")) {
    const f = await readRef(o.url);
    data = f.data;
    contentType ??= f.contentType;
  } else {
    const res = await fetch(o.url, { headers: o.headers });
    if (!res.ok) throw new Error(`download ${res.status}`);
    data = Buffer.from(await res.arrayBuffer());
    const header = res.headers.get("content-type")?.split(";")[0];
    contentType ??= header && header !== "application/octet-stream" ? header : contentTypeFor(new URL(o.url).searchParams.get("filename") ?? o.url);
  }
  const asset = saveFile({ data, contentType: contentType!, source: "generation", generationId });
  const meta = relinkMain(linked, o.url, asset.url);
  // A text file's words travel with the generation, so feeds and the next chained step can use them.
  const text = o.text ?? (asset.kind === "text" ? data.toString("utf8") : undefined);
  return {
    url: asset.url,
    kind: asset.kind,
    contentType: asset.contentType,
    assetId: asset.id,
    ...inlineText(text, meta),
    ...(o.draftId ? { draftId: o.draftId } : {}),
  };
}

export async function cancelGeneration(id: string): Promise<void> {
  const r = db().prepare("SELECT * FROM generations WHERE id = ?").get(id) as Row | undefined;
  if (!r || (r.status !== "queued" && r.status !== "running")) return;
  const model = getModel(r.model_id);
  // Without an external id the job is still being handed over: submit() cancels it as soon as it lands.
  if (r.external_id && model) {
    await provider(r.provider)
      .cancel?.(pollContext(r, model))
      .catch(() => {});
  }
  update(id, { status: "canceled", completed_at: Date.now(), message: null });
  // Steps waiting only to feed this one are dropped too (nothing was spent on them).
  dropUnused(depIds(r.depends_on));
}

// ---------------------------------------------------------------------------
// Fuobe Soul's post steps (the look's grade and overlay), made in the browser when the result arrives.

/** The aspect ratio a stored request asked for (Soul Cinema's 21:9 is made at 16:9 and cropped). */
function requestAspect(json: string): string | undefined {
  try {
    return (JSON.parse(json) as GenerationRequest).params?.aspectRatio;
  } catch {
    return undefined;
  }
}

export class FinishError extends Error {
  constructor(
    message: string,
    readonly status: number,
  ) {
    super(message);
  }
}

/**
 * Keep the finished picture of a Soul result in place of the raw one: the raw one stays as meta.original (its
 * file is still the generation's), meta.finished marks it done. The first finished copy wins: another tab's
 * answer is 409, and an output with nothing left to do is refused.
 */
export function finishOutput(id: string, index: number, png: Buffer): Generation {
  const r = db().prepare("SELECT * FROM generations WHERE id = ?").get(id) as Row | undefined;
  if (!r) throw new FinishError("Not found", 404);
  if (r.status !== "succeeded") throw new FinishError("The result isn't ready yet", 409);
  const outputs = JSON.parse(r.outputs_json) as OutputFile[];
  const o = outputs[index];
  if (!o || !Number.isInteger(index)) throw new FinishError("No such output", 404);
  if (o.meta?.finished) throw new FinishError("Already finished", 409);
  if (!finishSteps(o)) throw new FinishError("This output has no grade or overlay to apply", 400);
  const asset = saveFile({ data: png, contentType: "image/png", name: `${id}-${index}-finished.png`, source: "generation", generationId: id });
  outputs[index] = { ...o, url: asset.url, assetId: asset.id, contentType: "image/png", meta: { ...o.meta, finished: true, original: o.url } };
  update(id, { outputs_json: JSON.stringify(outputs) });
  return getGeneration(id, { includeDeleted: true })!;
}

// ---------------------------------------------------------------------------
// Results made in the browser (colour grading): stored as finished generations.

export function recordLocalGeneration(input: {
  feature: string;
  modelId: string;
  op: Generation["op"];
  prompt: string;
  inputs: GenerationRequest["inputs"];
  params?: GenerationRequest["params"];
  output: { url: string; kind: OutputFile["kind"]; contentType?: string };
}): Generation {
  const model = getModel(input.modelId);
  if (!model || !model.routes.some((r) => r.provider === "local")) throw new Error("Not a browser tool");
  const now = Date.now();
  const req: GenerationRequest = { feature: input.feature, modelId: input.modelId, op: input.op, prompt: input.prompt, inputs: input.inputs, params: input.params };
  const row: Row = {
    id: nanoid(12),
    batch_id: null,
    feature: input.feature,
    preset_id: null,
    model_id: model.id,
    engine: model.engine,
    provider: "local",
    op: input.op,
    kind: input.output.kind,
    status: "succeeded",
    progress: 1,
    message: null,
    prompt: input.prompt,
    request_json: JSON.stringify(req),
    provider_input_json: null,
    external_id: "local",
    external_meta_json: null,
    outputs_json: JSON.stringify([input.output]),
    error: null,
    cost_usd: 0,
    favorite: 0,
    created_at: now,
    updated_at: now,
    completed_at: now,
    depends_on: null,
  };
  db()
    .prepare(`INSERT INTO generations (${Object.keys(row).join(", ")}) VALUES (${Object.keys(row).map((k) => `@${k}`).join(", ")})`)
    .run(row);
  return toGeneration(row);
}
