/**
 * AI Extractor — Multi-source AI extraction layer for contact & person intelligence
 *
 * Five AI sources fire in parallel at Phase 0 of the enrichment pipeline:
 *
 *   SEARCH / RESEARCH (return structured answers directly):
 *   - Perplexity Sonar Pro — live web-search model; synthesises from real sources
 *   - Gemini 2.0 Flash    — Google Search grounding; different index from Perplexity
 *
 *   SEARCH + GROQ EXTRACTION (return raw text excerpts, Groq extracts structure):
 *   - Tavily              — AI-native search; 7 live sources per query
 *   - Exa                 — neural/semantic retrieval; strong for people & company lookups
 *
 *   TEXT EXTRACTION (reads accumulated scraped text from all other phases):
 *   - Groq llama-3.3-70b  — free, 6 000 req/day, 32k context; pulls out anything regex missed:
 *       emails in obfuscated form, phone numbers, social handles, owner names in any language
 *
 * Every source falls back silently if its key is unset or quota is hit.
 */

import { logger } from "./logger";

const GROQ_API        = "https://api.groq.com/openai/v1/chat/completions";
const GROQ_MODEL      = "llama-3.3-70b-versatile";
const GROQ_MODEL_FAST = "llama-3.1-8b-instant";

const OPENROUTER_API       = "https://openrouter.ai/api/v1/chat/completions";
const OPENROUTER_MODEL     = "meta-llama/llama-3.3-70b-instruct"; // fast + free-tier friendly
const PERPLEXITY_MODEL     = "perplexity/sonar-pro";               // via OpenRouter: live web-search (fallback only)
const PERPLEXITY_FALLBACK  = "perplexity/sonar";                   // via OpenRouter: cheaper fallback

// Direct Perplexity API — preferred over OpenRouter-routed Sonar (no per-key credit balance issues)
const PERPLEXITY_DIRECT_API      = "https://api.perplexity.ai/chat/completions";
const PERPLEXITY_DIRECT_MODEL    = "sonar-pro";   // model name WITHOUT the "perplexity/" prefix when calling directly
const PERPLEXITY_DIRECT_FALLBACK = "sonar";       // cheaper direct fallback

// Gemini Flash with Google Search Grounding — searches Google in real-time, different index from Perplexity
const GEMINI_API   = "https://generativelanguage.googleapis.com/v1beta/models/gemini-2.0-flash:generateContent";
const GEMINI_MODEL = "gemini-2.0-flash"; // used only for log labels

// Tavily — AI-native search API; returns clean excerpts; structure extracted by Groq
const TAVILY_API = "https://api.tavily.com/search";

// Exa — neural/semantic search API; excels at people + company lookups
const EXA_API = "https://api.exa.ai/search";

// Track which keys hit rate-limits. Map<key, expiresAtMs> — keys auto-recover after 5 min.
const EXHAUSTED_TTL_MS = 5 * 60 * 1000;

function isExhausted(map: Map<string, number>, key: string): boolean {
  const exp = map.get(key);
  if (!exp) return false;
  if (Date.now() > exp) { map.delete(key); return false; }
  return true;
}

// IMPORTANT: each provider uses a SEPARATE exhaustion map — a 429 on one must NOT block others.
const _exhaustedGroqKeys              = new Map<string, number>();
const _exhaustedORKeys                = new Map<string, number>(); // for llama text extraction only
const _exhaustedPerplexityKeys        = new Map<string, number>(); // for OpenRouter-routed Sonar only
const _exhaustedPerplexityDirectKeys  = new Map<string, number>(); // for direct Perplexity API only
const _exhaustedGeminiKeys            = new Map<string, number>(); // for Gemini Flash grounded search
const _exhaustedTavilyKeys            = new Map<string, number>(); // for Tavily search API
const _exhaustedExaKeys               = new Map<string, number>(); // for Exa neural search API

/** Returns all Groq API keys (GROQ_API_KEY, GROQ_API_KEY_1 … _8). */
function getGroqKeys(): string[] {
  const names = ["GROQ_API_KEY"];
  for (let i = 1; i <= 8; i++) names.push(`GROQ_API_KEY_${i}`);
  return names.map(k => process.env[k] ?? "").filter(k => k.length > 0);
}

function getOpenRouterKeys(): string[] {
  // Scan OPENROUTER_API_KEY, OPENROUTER_API_KEY_2 … OPENROUTER_API_KEY_8
  // Any new key added as a secret is picked up automatically on next restart.
  const names = ["OPENROUTER_API_KEY"];
  for (let i = 2; i <= 8; i++) names.push(`OPENROUTER_API_KEY_${i}`);
  return names.map(k => process.env[k] ?? "").filter(k => k.length > 0);
}

/** Returns all direct Perplexity API keys (PERPLEXITY_API_KEY, _1 … _8). */
function getPerplexityDirectKeys(): string[] {
  const names = ["PERPLEXITY_API_KEY"];
  for (let i = 1; i <= 8; i++) names.push(`PERPLEXITY_API_KEY_${i}`);
  return names.map(k => process.env[k] ?? "").filter(k => k.length > 0);
}

/** Returns all Gemini API keys (GEMINI_API_KEY, GEMINI_API_KEY_1 … _8). */
function getGeminiKeys(): string[] {
  const names = ["GEMINI_API_KEY"];
  for (let i = 1; i <= 8; i++) names.push(`GEMINI_API_KEY_${i}`);
  return names.map(k => process.env[k] ?? "").filter(k => k.length > 0);
}

/** Returns all Tavily API keys (TAVILY_API_KEY, TAVILY_API_KEY_1 … _8). */
function getTavilyKeys(): string[] {
  const names = ["TAVILY_API_KEY"];
  for (let i = 1; i <= 8; i++) names.push(`TAVILY_API_KEY_${i}`);
  return names.map(k => process.env[k] ?? "").filter(k => k.length > 0);
}

/** Returns all Exa API keys (EXA_API_KEY, EXA_API_KEY_1 … _8). */
function getExaKeys(): string[] {
  const names = ["EXA_API_KEY"];
  for (let i = 1; i <= 8; i++) names.push(`EXA_API_KEY_${i}`);
  return names.map(k => process.env[k] ?? "").filter(k => k.length > 0);
}

/** Personal contact vector for a named owner/founder discovered in text */
export interface OwnerContact {
  name:      string;        // Full name (First Last)
  instagram: string | null; // Personal Instagram URL — NOT the venue account
  twitter:   string | null; // Personal Twitter/X URL
  linkedin:  string | null; // Personal LinkedIn /in/ profile URL
  email:     string | null; // Personal or direct email if stated
}

export type OwnershipRole =
  | "owner"
  | "beneficial_owner"
  | "founder"
  | "controller"
  | "operator"
  | "director_officer"
  | "associated_person";

export interface OwnerResolution extends OwnerContact {
  role: OwnershipRole;
  ownershipStatus: "confirmed" | "probable" | "not_established";
  basis: string | null;
  sourceUrls: string[];
}

export interface AIExtractResult {
  // ── Org-level contact vectors (for the entity being researched) ─────────
  email:     string | null;
  phone:     string | null;
  linkedin:  string | null; // org LinkedIn /company/ page
  instagram: string | null; // venue/org Instagram
  twitter:   string | null; // venue/org Twitter
  // ── Person discoveries ──────────────────────────────────────────────────
  owners:        string[];        // flat list of owner names (backward compat)
  ownerContacts: OwnerContact[];  // structured per-owner data with personal handles
  ownerResolutions: OwnerResolution[]; // role + ownership basis; never auto-merged
  ownershipSummary: string | null;
  ownershipSources: string[];
  source:    "groq-llama-70b" | "groq-llama-8b" | "openrouter" | "perplexity-sonar" | "gemini-flash" | "tavily" | "exa" | "none";
  citations: string[];            // URLs the model actually searched — use as evidence sources
}

const EMPTY: AIExtractResult = {
  email: null, phone: null, linkedin: null,
  instagram: null, twitter: null,
  owners: [], ownerContacts: [], ownerResolutions: [],
  ownershipSummary: null, ownershipSources: [],
  source: "none",
  citations: [],
};


/**
 * Build the prompt. Ownership resolution is deliberately the first objective:
 * finding the public contact page without identifying who owns or controls the
 * business is an incomplete OSINT result.
 * Text is capped at 5 500 chars to leave room for the response.
 */
function buildPrompt(text: string, entityName: string, entityType: string, country: string | null): string {
  const ctx = country ? ` (${country})` : "";
  const truncated = text.slice(0, 7000);
  const isOrg = entityType === "Corporation" || entityType === "Trust";

  return `You are the ownership-resolution lead for an OSINT intelligence platform. Analyze this web text about "${entityName}"${ctx} (${entityType}).

PRIMARY OBJECTIVE — WHO OWNS, CONTROLS, OR RUNS THIS ENTITY?
Do not stop at an organisation email or phone number. Identify every named person explicitly connected to this entity and classify the connection:
- owner / beneficial_owner: the text explicitly says they own, hold, control, or beneficially own it
- founder: explicitly founded or co-founded it (not proof of current ownership)
- controller: explicitly controls the entity, parent, holding company, or operating group
- operator: explicitly runs, manages, or operates the venue/business (not proof of ownership)
- director_officer: an explicitly named director, president, CEO, officer, or legal representative (not proof of ownership)
- associated_person: named in a relevant business context when no stronger role is established

Ownership claims must be evidence-led. Never turn a director, manager, spokesperson, chef, investor, landlord, or person merely mentioned in an article into an owner. If ownership is not established, say so in the role/status fields while still returning the person and their weaker role.

SECONDARY OBJECTIVE — find the entity's public contact vectors and personal handles for the named principals.

TEXT:
${truncated}

Return ONLY valid JSON — no explanation, no markdown:
{
  "ownershipSummary": "one sentence stating the strongest ownership/control finding, or 'Ownership not established in the supplied text.'",
  "email": "venue/org contact email or null",
  "phone": "full international number with country code (e.g. +33 4 93 43 03 43) or null",
  "linkedin": "${isOrg ? "https://linkedin.com/company/... org page or null" : "https://linkedin.com/in/profile or null"}",
  "instagram": "${isOrg ? "venue/brand Instagram URL (e.g. https://instagram.com/baolicannes) or null" : "personal Instagram URL or null"}",
  "twitter": "venue/org Twitter/X URL or null",
  "ownerResolutions": [
    {
      "name": "Full Name (First Last minimum)",
      "role": "owner | beneficial_owner | founder | controller | operator | director_officer | associated_person",
      "ownershipStatus": "confirmed | probable | not_established",
      "basis": "short exact relationship/basis from the text, or null",
      "sourceUrls": ["https://source-url.example/article"],
      "instagram": "PERSONAL Instagram URL (not the venue account — e.g. https://instagram.com/christoph_cau) or null",
      "twitter": "personal Twitter/X URL or null",
      "linkedin": "personal LinkedIn /in/ profile URL or null",
      "email": "personal or direct email if explicitly stated or null"
    }
  ]
}

Rules:
- Only extract what is EXPLICITLY present in the text above — never guess or infer
- ownershipSummary must explicitly say when ownership is not established
- ownerResolutions is the primary output; return named people even when they are only directors/operators, but label those roles honestly
- basis must be a short quote or faithful paraphrase from the text, never an invented explanation
- sourceUrls must contain only URLs explicitly present in the text; return [] when none are present
- email/phone: prefer the primary business/venue contact (reservations@, contact@, info@)
- phone: must have ≥7 digits; include country code when present
- instagram/twitter (top level): the venue or org account (handle matches the business name)
- ownerResolutions: max 8 people; full name required (at least First + Last)
  * instagram/twitter in ownerResolutions: their PERSONAL handles (not the venue account)
    e.g. if text says "Christophe Caucino (@christoph_cau)" → instagram: "https://instagram.com/christoph_cau"
  * linkedin in ownerContacts: /in/ profiles only (not /company/)
  * email in ownerContacts: personal or named email only (not info@ or reservations@)
- Return null for any field not found; return [] for ownerResolutions if none found
- Do NOT invent anything not stated in the text`;
}

/** Parse the raw JSON response content into an AIExtractResult */
function parseAIResponse(raw: string, source: AIExtractResult["source"]): AIExtractResult | null {
  if (!raw) return null;
  try {
    const parsed = JSON.parse(raw) as Record<string, unknown>;

    const clean = (v: unknown): string | null => {
      if (typeof v !== "string" || !v.trim()) return null;
      const s = v.trim();
      return (s === "null" || s === "undefined" || s.length < 3) ? null : s;
    };

    // Reject emails that look like placeholders, templates, or shared role-based inboxes the AI invented
    const isPlaceholderEmail = (e: string): boolean => {
      if (!e) return false;
      const local = e.split("@")[0]?.toLowerCase() ?? "";
      const domain = (e.split("@")[1] ?? "").toLowerCase();
      // Classic placeholder patterns: jane.doe, j.doe, john.smith, jdoe, test.user, firstname.lastname etc.
      if (/^(jane\.?doe|john\.?doe|j\.?doe|test\.?user|sample|firstname|lastname|first\.last|f\.last|j\.smith|john\.smith|your\.name|name\.surname)$/i.test(local)) return true;
      // Generic placeholder domains
      if (/^(example|test|sample|placeholder|domain|email)\.(com|org|net)$/.test(domain)) return true;
      // Role-based / shared inboxes — never a personal direct contact
      if (/^(info|contact|hello|team|support|press|media|noreply|no[-.]?reply|admin|general|office|enquir|reception|mail|post|webmaster|marketing|sales|hr|legal|finance|invest|ir|pr|news|feedback|service|help|care|ops|inquir|request|apply|career|job|recruit)$/.test(local)) return true;
      // Financial aggregator / FSCS-type generic domains
      if (/\b(safeharb|fincen|nmlsr|creditunion|bankassoc|fdic\.gov|nacha\.org)\b/.test(domain)) return true;
      return false;
    };

    // Patterns for known data-aggregator, registry, or corporate-brand accounts
    // These are NEVER a personal social handle — reject them outright.
    const isCorporateHandle = (handle: string): boolean => {
      const h = handle.toLowerCase().replace(/^@/, "");
      // Known data aggregators and business registries
      if (/^(societe_com|societecom|infogreffe|pappers|bodacc|kompass|verif|societefr|societe|linkedin|facebook|instagram|twitter|youtube|tiktok|snapchat|google|apple|amazon|microsoft|forbes|bloomberg|reuters|guardian|bbc|cnn|nytimes|wsj|ft|economist|sothebys|christies|bonhams|bnpparibas|credit_suisse|hsbc|jpmorgan|goldmansachs|morganstanley|ubs|dbtrust|barclays|citibank|deloitte|pwc|kpmg|ey_|mckinsey|bcg|bain|rothschild|lazard|blackrock|blackstone|kkr|carlyle|apollo|vistacapital|merrilllynch|schwab|vanguard|fidelity|invesco|statestreet)/.test(h)) return true;
      // Handle ends in _com / _fr / _uk / _us / _de etc. — corporate brand account
      if (/_(com|fr|uk|us|de|it|es|ch|be|nl|au|ca|sg|hk|ae|sa)$/.test(h)) return true;
      // Handle contains obvious registry/aggregator keywords
      if (/\b(registry|register|registr|official|newsroom|presse|media|pr_|corp|group|global|international|holding|invest|capital|fund|asset|wealth|finance|bank)\b/.test(h)) return true;
      return false;
    };

    // Normalize @handle → full URL for instagram and twitter fields
    const normIG  = (v: unknown): string | null => {
      const s = clean(v);
      if (!s) return null;
      const url = s.startsWith("@") ? `https://instagram.com/${s.slice(1)}` : s.includes("instagram.com") ? s : null;
      if (!url) return null;
      const handle = url.split("/").pop() ?? "";
      return isCorporateHandle(handle) ? null : url;
    };
    const normTW  = (v: unknown): string | null => {
      const s = clean(v);
      if (!s) return null;
      const url = s.startsWith("@") ? `https://twitter.com/${s.slice(1)}` : (s.includes("twitter.com") || s.includes("x.com")) ? s : null;
      if (!url) return null;
      const handle = url.split("/").pop() ?? "";
      return isCorporateHandle(handle) ? null : url;
    };

    const owners: string[] = [];
    const ownerContacts: OwnerContact[] = [];
    const ownerResolutions: OwnerResolution[] = [];
    const validRoles = new Set<OwnershipRole>([
      "owner", "beneficial_owner", "founder", "controller", "operator",
      "director_officer", "associated_person",
    ]);
    const validStatuses = new Set<OwnerResolution["ownershipStatus"]>([
      "confirmed", "probable", "not_established",
    ]);

    const rawResolutions = Array.isArray(parsed["ownerResolutions"])
      ? parsed["ownerResolutions"]
      : parsed["ownerContacts"];
    if (Array.isArray(rawResolutions)) {
      for (const oc of rawResolutions) {
        if (typeof oc !== "object" || !oc) continue;
        const name = clean((oc as any)["name"]);
        if (!name || !name.includes(" ") || name.length < 4 || name.length > 80) continue;
        const rawLinkedin = clean((oc as any)["linkedin"]);
        const rawOwnerEmail = clean((oc as any)["email"]);
        const contact: OwnerContact = {
          name,
          instagram: normIG((oc as any)["instagram"]),
          twitter:   normTW((oc as any)["twitter"]),
          linkedin:  rawLinkedin?.includes("linkedin.com") ? rawLinkedin : null,
          email:     rawOwnerEmail && !isPlaceholderEmail(rawOwnerEmail) ? rawOwnerEmail : null,
        };
        ownerContacts.push(contact);
        owners.push(name);
        const rawRole = clean((oc as any)["role"])?.toLowerCase() as OwnershipRole | null;
        const rawStatus = clean((oc as any)["ownershipStatus"])?.toLowerCase() as OwnerResolution["ownershipStatus"] | null;
        const rawSources = Array.isArray((oc as any)["sourceUrls"])
          ? (oc as any)["sourceUrls"].filter((u: unknown): u is string => typeof u === "string" && /^https?:\/\//i.test(u)).slice(0, 8)
          : [];
        ownerResolutions.push({
          ...contact,
          role: rawRole && validRoles.has(rawRole) ? rawRole : "associated_person",
          ownershipStatus: rawStatus && validStatuses.has(rawStatus) ? rawStatus : "not_established",
          basis: clean((oc as any)["basis"]),
          sourceUrls: rawSources,
        });
      }
    }

    if (owners.length === 0 && Array.isArray(parsed["owners"])) {
      for (const o of parsed["owners"]) {
        if (typeof o === "string" && o.trim().includes(" ") && o.trim().length >= 4 && o.trim().length <= 60) {
          owners.push(o.trim());
        }
      }
    }

    const rawLinkedinTop = clean(parsed["linkedin"]);
    const rawTopEmail = clean(parsed["email"]);
    return {
      email:         rawTopEmail && !isPlaceholderEmail(rawTopEmail) ? rawTopEmail : null,
      phone:         clean(parsed["phone"]),
      linkedin:      rawLinkedinTop?.includes("linkedin.com") ? rawLinkedinTop : null,
      instagram:     normIG(parsed["instagram"]),
      twitter:       normTW(parsed["twitter"]),
      owners:        owners.slice(0, 5),
      ownerContacts: ownerContacts.slice(0, 5),
      ownerResolutions: ownerResolutions.slice(0, 8),
      ownershipSummary: clean(parsed["ownershipSummary"]),
      ownershipSources: Array.isArray(parsed["sources"])
        ? parsed["sources"]
          .filter((u: unknown): u is string => typeof u === "string" && /^https?:\/\//i.test(u))
          .slice(0, 8)
        : [],
      source,
      citations: [],
    };
  } catch {
    return null;
  }
}

/** Call one Groq key + model combination. Returns null on rate-limit (key marked exhausted). */
async function callGroq(
  text: string,
  entityName: string,
  entityType: string,
  country: string | null,
  key: string,
  model: string,
): Promise<AIExtractResult | null> {
  const prompt = buildPrompt(text, entityName, entityType, country);
  const body = JSON.stringify({
    model,
    messages: [{ role: "user", content: prompt }],
    temperature: 0,
    max_tokens: 1000,
    response_format: { type: "json_object" },
  });

  try {
    const resp = await fetch(GROQ_API, {
      method: "POST",
      headers: { "Authorization": `Bearer ${key}`, "Content-Type": "application/json" },
      body,
      signal: AbortSignal.timeout(20_000),
    });

    if (resp.status === 429) {
      _exhaustedGroqKeys.set(key, Date.now() + EXHAUSTED_TTL_MS);
      logger.debug({ model }, "Groq rate limit — key marked exhausted for 5 min");
      return null;
    }
    if (!resp.ok) {
      const err = await resp.text().catch(() => "");
      logger.debug({ status: resp.status, err: err.slice(0, 200), model }, "Groq API error");
      return null;
    }

    const data = await resp.json() as any;
    const raw: string = data?.choices?.[0]?.message?.content ?? "";
    const src: AIExtractResult["source"] = model === GROQ_MODEL ? "groq-llama-70b" : "groq-llama-8b";
    return parseAIResponse(raw, src);
  } catch (err: any) {
    logger.debug({ err: err?.message, model }, "Groq call failed");
    return null;
  }
}

/** Call one OpenRouter key. Returns null on rate-limit (key marked exhausted). */
async function callOpenRouter(
  text: string,
  entityName: string,
  entityType: string,
  country: string | null,
  key: string,
): Promise<AIExtractResult | null> {
  const prompt = buildPrompt(text, entityName, entityType, country);
  const body = JSON.stringify({
    model: OPENROUTER_MODEL,
    messages: [{ role: "user", content: prompt }],
    temperature: 0,
    max_tokens: 1000,
    response_format: { type: "json_object" },
  });

  try {
    const resp = await fetch(OPENROUTER_API, {
      method: "POST",
      headers: {
        "Authorization": `Bearer ${key}`,
        "Content-Type": "application/json",
        "HTTP-Referer": "https://apex-finder.replit.app",
        "X-Title": "ApexFinder OSINT",
      },
      body,
      signal: AbortSignal.timeout(25_000),
    });

    if (resp.status === 429) {
      _exhaustedORKeys.set(key, Date.now() + EXHAUSTED_TTL_MS);
      logger.debug("OpenRouter (llama) rate limit — key marked exhausted for 5 min");
      return null;
    }
    if (!resp.ok) {
      const err = await resp.text().catch(() => "");
      logger.debug({ status: resp.status, err: err.slice(0, 200) }, "OpenRouter API error");
      return null;
    }

    const data = await resp.json() as any;
    const raw: string = data?.choices?.[0]?.message?.content ?? "";
    return parseAIResponse(raw, "openrouter");
  } catch (err: any) {
    logger.debug({ err: err?.message }, "OpenRouter call failed");
    return null;
  }
}

// ─── Perplexity Sonar — live web research ────────────────────────────────────
// perplexity/sonar-pro via OpenRouter is a LIVE WEB-SEARCH model — it searches
// the internet and synthesises results exactly like Gemini AI Overview.
// Unlike extractWithAI (which reads text we already scraped), this sends a
// natural-language research question and Perplexity fetches and reads sources itself.
// This is how Gemini finds "Christophe Caucino" from Nice-Matin in <1 second.

export function buildPerplexityPrompt(
  entityName: string,
  entityType: string,
  country: string | null,
  context: { tradingName?: string | null; city?: string | null } = {},
): string {
  const ctx = country ? ` in ${country}` : "";
  const publicName = context.tradingName && context.tradingName !== entityName
    ? `"${context.tradingName}" (legal/entity name: "${entityName}")`
    : `"${entityName}"`;
  const city = context.city ? `\nKnown city/location context: ${context.city}` : "";
  const isOrg = entityType === "Corporation" || entityType === "Trust";

  // Strong geographic/sector scope guard — prevents name-clash contamination.
  // e.g. "Target Global" (Berlin VC) must not pull in Target Corporation (US retailer).
  const locationCtx = [context.city, country].filter(Boolean).join(", ");
  const disambig = locationCtx
    ? `\nSCOPE LOCK: You are researching ONLY the ${locationCtx}-based ${isOrg ? "company/institution" : "individual"} named ${publicName}. If any other entity (retailer, sports team, consumer brand, government body, etc.) shares this name or a similar name, IGNORE it entirely. Do NOT mix data from different entities. All output must relate exclusively to the ${locationCtx} entity.`
    : "";

  return `You are conducting Phase 0 OSINT for ${publicName}${ctx}. Goal: find every named human decision-maker and their direct contact path.${city}${disambig}

${isOrg ? `This is a company/business/institution. Execute this research in order:

STEP 1 — NAMED DECISION-MAKERS (highest priority for contact purposes):
Find ALL named partners, principals, and executives. For venture capital / private equity / investment firms specifically:
- Every General Partner (GP), Managing Partner, Founding Partner, Partner by full name
- Every Principal, Director, Vice President, Associate Partner involved in deals
- CEO, CFO, COO, and any C-suite if different from the partners
- Every named team member on the official team/people/partners page
- CRITICAL for PE/infrastructure/real assets firms: all strategy/sector heads — Head of Buyout, Head of Infrastructure, Head of Fund-of-Funds, Head of Secondaries, Head of Private Debt, Head of Real Estate, Head of Growth, Head of Credit, Head of each regional office (Head of US, Head of Germany, Head of Asia, etc.). These are Managing Directors or Senior MDs, one level below the firm-wide partners, and are the PRIMARY deal decision-makers for their asset class.

For other companies: CEO, Deputy CEO, Managing Director, all C-suite/Executive Committee (COMEX/EXCO) members, all named department/division heads.

For EVERY named person: their individual direct email (construct from verified domain pattern even if not explicit), personal LinkedIn /in/ URL, Twitter/X handle.
Search: official website team/people/partners page, LinkedIn company page team section, Crunchbase, press interviews, conference speaker bios, news articles, PitchBook/AngelList for VC firms.

STEP 2 — EMAIL PATTERN:
Identify the organisation's verified email format (e.g. firstname.lastname@domain.fr or f.lastname@domain.com).
Use this pattern to construct direct emails for every named executive even if not explicitly stated.
Include the pattern in ownershipSummary.

STEP 3 — OWNERSHIP / CONTROL (for institutional context):
Who owns, controls, or beneficially owns this entity? Parent company, holding, state body, or private shareholders.
Do not confuse a director/CEO with an owner unless a source explicitly says so.

STEP 4 — ORGANISATION CONTACT:
Official HQ address(es), main phone line(s), general email, LinkedIn company page.` 
  : `This is a high-net-worth individual. Find PERSONAL direct contact information ONLY.

STEP 1 — PERSONAL DIRECT EMAIL:
Their individual named email address (e.g. firstname.lastname@company.com). NOT info@, press@, media@, contact@, or any shared company inbox. Construct from known domain patterns if not explicit.

STEP 2 — PERSONAL MOBILE / DIRECT LINE:
Their personal cell phone or personal direct office extension ONLY.
⚠️ CRITICAL: DO NOT return a corporate headquarters number, company main switchboard, reception line, or any number that belongs to an organisation rather than this specific individual. If the only phone you can find is a company HQ/switchboard, return null for phone. Example of what NOT to return: "+1 (303) 404-1800" is Vail Resorts corporate HQ — not a personal number.

STEP 3 — PERSONAL LINKEDIN /in/ PROFILE:
Their personal /in/ profile URL. NOT a /company/ page.

STEP 4 — PERSONAL SOCIAL ACCOUNTS:
Instagram or Twitter/X accounts this individual personally manages and posts from themselves.
⚠️ NOT corporate brand accounts. NOT company social pages. Personal lifestyle/professional accounts only (e.g. @firstname_lastname style handles, not @companybrand).

STEP 5 — ASSOCIATED COMPANIES AND ROLES (context only, not contact purposes).`}

Return ONLY this JSON — no preamble, no explanation, no markdown:
{
  "ownershipSummary": "one sentence: email pattern + strongest ownership finding, e.g. 'Email pattern: firstname.lastname@bpifrance.fr; owned 50/50 by French State and Caisse des Dépôts.'",
  "email": "general org contact email or null",
  "phone": "+XX XXX XXX or null",
  "linkedin": "${isOrg ? "https://linkedin.com/company/... org page or null" : "https://linkedin.com/in/profile or null"}",
  "instagram": "org Instagram URL or null",
  "twitter": "org Twitter/X URL or null",
  "ownerResolutions": [
    {
      "name": "First Last",
      "role": "owner | beneficial_owner | founder | controller | operator | director_officer | associated_person",
      "ownershipStatus": "confirmed | probable | not_established",
      "basis": "their title and organisation, e.g. 'CEO of Bpifrance since 2013'",
      "sourceUrls": ["source URL"],
      "instagram": "personal Instagram URL or null",
      "twitter": "personal Twitter/X URL or null",
      "linkedin": "personal LinkedIn /in/ URL or null",
      "email": "direct personal email constructed from verified pattern, e.g. nicolas.dufourcq@bpifrance.fr, or null"
    }
  ],
  "sources": ["URLs used"]
}

Hard requirements:
- Return up to 12 named HUMAN individuals — sector/strategy heads and executives first, then owners.
- Named executives with director_officer role are MORE valuable than institutional shareholders for contact purposes. Always include them even when the beneficial owner is a state body or holding company.
- Construct direct individual emails from the verified pattern for every named executive.
- ownershipSummary MUST state the verified email pattern if found.
- sourceUrls and sources: only real URLs from your search.
- Return [] for ownerResolutions only if absolutely no named human is found anywhere.
`;
}

/**
 * Build a targeted sector/strategy head discovery prompt for PE/investment Corp entities.
 * Fires as Phase 7.7 when the main Phase 0 pass returned fewer than 6 named people —
 * asking specifically about the MD/sector-head layer rather than the top executive committee.
 */
export function buildSectorHeadPrompt(
  entityName: string,
  country: string | null,
  context: { city?: string | null } = {},
): string {
  const locationCtx = [context.city, country].filter(Boolean).join(", ");
  const scope = locationCtx
    ? `\nSCOPE LOCK: Research ONLY the ${locationCtx}-based firm named "${entityName}". Ignore any unrelated entity with the same name.`
    : "";
  return `You are researching the investment team structure at "${entityName}".${scope}

Find the sector/strategy heads and senior managing directors who run specific asset class verticals or regional offices — these are one level below the firm-wide CEO/Co-CEO layer.

Examples of roles to find: Head of Buyout, Head of Infrastructure, Head of Fund-of-Funds, Head of Secondaries, Head of Private Debt, Head of Real Estate, Head of Growth Equity, Head of Credit, Head of [Country/Region] Office (e.g. Head of Germany, Head of US, Head of Asia).

For EACH person found:
- Full name
- Exact role title
- Direct individual email (construct from the verified pattern e.g. firstname.lastname@${entityName.toLowerCase().replace(/\s+/g, "")}.com)
- Personal LinkedIn /in/ URL

Return ONLY this JSON — no preamble:
{
  "ownershipSummary": "email pattern confirmed or null",
  "email": null,
  "phone": null,
  "linkedin": null,
  "instagram": null,
  "twitter": null,
  "ownerResolutions": [
    {
      "name": "First Last",
      "role": "director_officer",
      "ownershipStatus": "not_established",
      "basis": "Head of [Strategy] at ${entityName}",
      "sourceUrls": ["source URL"],
      "instagram": null,
      "twitter": null,
      "linkedin": "personal LinkedIn /in/ URL or null",
      "email": "firstname.lastname@domain.com or null"
    }
  ],
  "sources": ["URLs used"]
}

Hard requirements:
- Return up to 8 sector/strategy heads.
- Do NOT repeat names already in the executive committee (CEO/Co-CEO/Chairman/President).
- Construct direct emails from verified pattern for every named person.
`;
}

/**
 * Fire a live Perplexity Sonar research query via OpenRouter.
 * Perplexity searches the web itself — this is the Google/Gemini AI Overview equivalent.
 * Returns structured contact + owner data with the URLs Perplexity actually read.
 */
export async function researchWithPerplexity(
  entityName: string,
  entityType: string,
  country: string | null = null,
  context: { tradingName?: string | null; city?: string | null } = {},
): Promise<AIExtractResult> {
  logger.info({ entityName, entityType, country }, "Phase 0: firing Perplexity Sonar research");
  const prompt = buildPerplexityPrompt(entityName, entityType, country, context);

  /** Shared response parser — same for both direct and OpenRouter paths. */
  function parsePerplexityResponse(
    data: any,
    label: string,
  ): AIExtractResult | null {
    const raw: string = data?.choices?.[0]?.message?.content ?? "";
    const citations: string[] = Array.isArray(data?.citations) ? data.citations.slice(0, 8) : [];
    logger.info({ entityName, rawLen: raw.length, citations: citations.length, label }, "Phase 0: Perplexity raw response received");

    const jsonMatch = raw.match(/\{[\s\S]*\}/);
    if (!jsonMatch) {
      logger.warn({ raw: raw.slice(0, 300), label }, "Phase 0: no JSON block in response");
      return null;
    }
    const parsed = parseAIResponse(jsonMatch[0], "perplexity-sonar");
    if (!parsed) {
      logger.warn({ json: jsonMatch[0].slice(0, 300), label }, "Phase 0: parseAIResponse returned null");
      return null;
    }
    logger.info(
      { entityName, hasEmail: !!parsed.email, hasPhone: !!parsed.phone, hasIG: !!parsed.instagram,
        hasLinkedIn: !!parsed.linkedin, owners: parsed.owners.length, ownerContacts: parsed.ownerContacts.length,
        citations: citations.length, model: label },
      "Phase 0: Perplexity Sonar research complete",
    );
    return {
      ...parsed, citations,
      ownershipSources: [...new Set([...parsed.ownershipSources, ...citations])].slice(0, 8),
      ownerResolutions: parsed.ownerResolutions.map(o => ({
        ...o, sourceUrls: o.sourceUrls.length > 0 ? o.sourceUrls : citations.slice(0, 4),
      })),
    };
  }

  // ── PATH A: Direct Perplexity API (preferred — no per-key credit balance issues) ──────────
  // Rotates through PERPLEXITY_API_KEY, PERPLEXITY_API_KEY_1 … _8 (any that are set).
  const directKeys = getPerplexityDirectKeys();
  for (const directKey of directKeys) {
    if (isExhausted(_exhaustedPerplexityDirectKeys, directKey)) continue;
    let keySucceeded = false;
    for (const [model, label, maxTokens] of [
      [PERPLEXITY_DIRECT_MODEL,    "sonar-pro[direct]", 2000],
      [PERPLEXITY_DIRECT_FALLBACK, "sonar[direct]",     1000],
    ] as [string, string, number][]) {
      try {
        const resp = await fetch(PERPLEXITY_DIRECT_API, {
          method: "POST",
          headers: {
            "Authorization": `Bearer ${directKey}`,
            "Content-Type": "application/json",
          },
          body: JSON.stringify({
            model,
            messages: [{ role: "user", content: prompt }],
            temperature: 0.1,
            max_tokens: maxTokens,
          }),
          signal: AbortSignal.timeout(35_000),
        });

        if (resp.status === 429) {
          _exhaustedPerplexityDirectKeys.set(directKey, Date.now() + EXHAUSTED_TTL_MS);
          logger.warn({ label }, "Phase 0: direct Perplexity rate limit — key exhausted 5 min");
          break; // try next key
        }
        if (resp.status === 402) {
          logger.warn({ label }, "Phase 0: direct Perplexity insufficient credits — trying cheaper model");
          continue; // try sonar fallback on same key
        }
        if (!resp.ok) {
          const errText = await resp.text().catch(() => "");
          logger.warn({ status: resp.status, err: errText.slice(0, 300), label }, "Phase 0: direct Perplexity API error");
          continue;
        }

        const data = await resp.json() as any;
        const parsed = parsePerplexityResponse(data, label);
        if (parsed) return { ...parsed, source: "perplexity-sonar" };
        keySucceeded = true;
      } catch (err: any) {
        logger.warn({ err: err?.message, label }, "Phase 0: direct Perplexity call threw");
      }
    }
    if (keySucceeded) break; // parsed returned null but key worked — don't burn remaining keys
  }
  if (directKeys.length > 0) {
    // Had direct keys but all failed or exhausted — fall through to OpenRouter
    logger.warn({ entityName, keyCount: directKeys.length }, "Phase 0: all direct Perplexity keys failed — falling back to OpenRouter-routed Sonar");
  }

  // ── PATH B: OpenRouter-routed Sonar (fallback — subject to per-account credit limits) ─────
  const perpKeys = getOpenRouterKeys();
  if (perpKeys.every(k => isExhausted(_exhaustedPerplexityKeys, k))) {
    logger.warn({ entityName }, "Phase 0: all OpenRouter keys exhausted for Perplexity — skipping");
    return EMPTY;
  }

  /** Call one OpenRouter-routed Perplexity model on one key. */
  async function callViaOpenRouter(
    model: string,
    label: string,
    key: string,
    maxTokens: number,
  ): Promise<{ parsed: AIExtractResult | null; hardFail: boolean }> {
    try {
      const resp = await fetch(OPENROUTER_API, {
        method: "POST",
        headers: {
          "Authorization": `Bearer ${key}`,
          "Content-Type": "application/json",
          "HTTP-Referer": "https://apex-finder.replit.app",
          "X-Title": "ApexFinder OSINT",
        },
        body: JSON.stringify({
          model,
          messages: [{ role: "user", content: prompt }],
          temperature: 0.1,
          max_tokens: maxTokens,
        }),
        signal: AbortSignal.timeout(35_000),
      });

      if (resp.status === 429) {
        _exhaustedPerplexityKeys.set(key, Date.now() + EXHAUSTED_TTL_MS);
        logger.warn({ label }, "Phase 0 [OR]: Perplexity rate limit — key exhausted 5 min");
        return { parsed: null, hardFail: true };
      }
      if (resp.status === 402) {
        const errText = await resp.text().catch(() => "");
        const affordMatch = errText.match(/can only afford (\d+)/);
        const canAfford = affordMatch ? parseInt(affordMatch[1]!) : 0;
        logger.warn({ label, canAfford, requested: maxTokens }, "Phase 0 [OR]: insufficient credits — trying cheaper model");
        return { parsed: null, hardFail: false };
      }
      if (!resp.ok) {
        const errText = await resp.text().catch(() => "");
        logger.warn({ status: resp.status, err: errText.slice(0, 300), label }, "Phase 0 [OR]: Perplexity API error");
        return { parsed: null, hardFail: false };
      }

      const data = await resp.json() as any;
      const parsed = parsePerplexityResponse(data, label);
      return { parsed, hardFail: false };
    } catch (err: any) {
      logger.warn({ err: err?.message, label }, "Phase 0 [OR]: Perplexity call threw");
      return { parsed: null, hardFail: false };
    }
  }

  // Per-key: try sonar-pro → fall back to sonar on the same key before moving to next key.
  for (const key of perpKeys) {
    if (isExhausted(_exhaustedPerplexityKeys, key)) continue;

    const pro = await callViaOpenRouter(PERPLEXITY_MODEL, "sonar-pro", key, 2000);
    if (pro.parsed) return { ...pro.parsed, source: "perplexity-sonar" };
    if (pro.hardFail) continue;

    const standard = await callViaOpenRouter(PERPLEXITY_FALLBACK, "sonar", key, 1000);
    if (standard.parsed) return { ...standard.parsed, source: "perplexity-sonar" };
    if (standard.hardFail) continue;
  }

  logger.warn({ entityName }, "Phase 0: Perplexity returned no usable data — all paths exhausted");
  return EMPTY;
}

/**
 * Fire a live Gemini Flash research query with Google Search Grounding.
 * Gemini searches Google in real-time — complementary to Perplexity (different search index).
 * Uses the same buildPerplexityPrompt so JSON schema is identical; results merge cleanly.
 * Returns structured contact + owner data with grounding URLs Gemini actually visited.
 */
export async function researchWithGemini(
  entityName: string,
  entityType: string,
  country: string | null = null,
  context: { tradingName?: string | null; city?: string | null } = {},
): Promise<AIExtractResult> {
  const keys = getGeminiKeys();
  if (keys.length === 0) return EMPTY;

  logger.info({ entityName, entityType, country }, `Phase 0 [${GEMINI_MODEL}]: firing Gemini grounded search`);
  const prompt = buildPerplexityPrompt(entityName, entityType, country, context);

  for (const key of keys) {
    if (isExhausted(_exhaustedGeminiKeys, key)) continue;
    try {
      const resp = await fetch(`${GEMINI_API}?key=${key}`, {
        method: "POST",
        headers: { "Content-Type": "application/json" },
        body: JSON.stringify({
          contents: [{ role: "user", parts: [{ text: prompt }] }],
          tools: [{ google_search: {} }],
          generationConfig: { temperature: 0.1, maxOutputTokens: 2000 },
        }),
        signal: AbortSignal.timeout(35_000),
      });

      if (resp.status === 429) {
        _exhaustedGeminiKeys.set(key, Date.now() + EXHAUSTED_TTL_MS);
        logger.warn(`Phase 0 [${GEMINI_MODEL}]: rate limit — key exhausted 5 min`);
        continue;
      }
      if (resp.status === 403) {
        const errText = await resp.text().catch(() => "");
        logger.warn({ err: errText.slice(0, 200) }, `Phase 0 [${GEMINI_MODEL}]: quota/auth error — skipping key`);
        continue;
      }
      if (!resp.ok) {
        const errText = await resp.text().catch(() => "");
        logger.warn({ status: resp.status, err: errText.slice(0, 300) }, `Phase 0 [${GEMINI_MODEL}]: API error`);
        continue;
      }

      const data = await resp.json() as any;
      const raw: string = data?.candidates?.[0]?.content?.parts?.[0]?.text ?? "";

      // Extract grounding citations from groundingMetadata
      const chunks: any[] = data?.candidates?.[0]?.groundingMetadata?.groundingChunks ?? [];
      const citations: string[] = chunks
        .map((c: any) => c?.web?.uri)
        .filter((u: unknown): u is string => typeof u === "string" && /^https?:\/\//i.test(u))
        .slice(0, 8);

      logger.info(
        { entityName, rawLen: raw.length, citations: citations.length },
        `Phase 0 [${GEMINI_MODEL}]: raw response received`,
      );

      const jsonMatch = raw.match(/\{[\s\S]*\}/);
      if (!jsonMatch) {
        logger.warn({ raw: raw.slice(0, 300) }, `Phase 0 [${GEMINI_MODEL}]: no JSON block in response`);
        continue;
      }

      const parsed = parseAIResponse(jsonMatch[0], "gemini-flash");
      if (!parsed) continue;

      logger.info(
        {
          entityName, hasEmail: !!parsed.email, hasPhone: !!parsed.phone,
          hasLinkedIn: !!parsed.linkedin, owners: parsed.owners.length, citations: citations.length,
        },
        `Phase 0 [${GEMINI_MODEL}]: research complete`,
      );

      return {
        ...parsed,
        citations,
        ownershipSources: [...new Set([...parsed.ownershipSources, ...citations])].slice(0, 8),
        ownerResolutions: parsed.ownerResolutions.map(o => ({
          ...o, sourceUrls: o.sourceUrls.length > 0 ? o.sourceUrls : citations.slice(0, 4),
        })),
      };
    } catch (err: any) {
      logger.warn({ err: err?.message }, `Phase 0 [${GEMINI_MODEL}]: call threw`);
    }
  }

  logger.warn({ entityName }, `Phase 0 [${GEMINI_MODEL}]: no usable data — all keys failed`);
  return EMPTY;
}

/**
 * Fire a Tavily AI-native search then extract structured contacts via Groq.
 * Tavily returns clean, LLM-ready excerpts from up to 7 live web sources.
 * Those excerpts are fed into Groq (llama-3.3-70b) using the same ownership/
 * contact extraction prompt as the rest of the pipeline.
 * Key rotation supports TAVILY_API_KEY through TAVILY_API_KEY_8.
 * Returns source: "tavily" with Tavily result URLs as citations.
 */
export async function researchWithTavily(
  entityName: string,
  entityType: string,
  country: string | null = null,
  context: { tradingName?: string | null; city?: string | null } = {},
): Promise<AIExtractResult> {
  const keys = getTavilyKeys();
  if (keys.length === 0) return EMPTY;

  // Build a targeted OSINT search query
  const queryParts: string[] = [entityName];
  if (context.tradingName && context.tradingName !== entityName) queryParts.push(context.tradingName);
  if (context.city) queryParts.push(context.city);
  if (country) queryParts.push(country);
  queryParts.push("owner contact email phone");
  const query = queryParts.join(" ");

  logger.info({ entityName, entityType, country, query }, "Phase 0 [tavily]: firing Tavily search");

  for (const key of keys) {
    if (isExhausted(_exhaustedTavilyKeys, key)) continue;
    try {
      const resp = await fetch(TAVILY_API, {
        method: "POST",
        headers: { "Content-Type": "application/json" },
        body: JSON.stringify({
          api_key: key,
          query,
          search_depth: "advanced",
          include_answer: true,
          max_results: 7,
          include_raw_content: false,
        }),
        signal: AbortSignal.timeout(30_000),
      });

      if (resp.status === 429) {
        _exhaustedTavilyKeys.set(key, Date.now() + EXHAUSTED_TTL_MS);
        logger.warn("Phase 0 [tavily]: rate limit — key exhausted 5 min");
        continue;
      }
      if (resp.status === 401 || resp.status === 403) {
        logger.warn({ status: resp.status }, "Phase 0 [tavily]: auth error — skipping key");
        continue;
      }
      if (!resp.ok) {
        const errText = await resp.text().catch(() => "");
        logger.warn({ status: resp.status, err: errText.slice(0, 200) }, "Phase 0 [tavily]: API error");
        continue;
      }

      const data = await resp.json() as {
        answer?: string;
        results?: { title: string; url: string; content: string; score: number }[];
      };

      const citations: string[] = (data.results ?? [])
        .map(r => r.url)
        .filter((u): u is string => typeof u === "string" && /^https?:\/\//i.test(u))
        .slice(0, 8);

      // Combine Tavily's synthesised answer + top per-source excerpts
      const textParts: string[] = [];
      if (data.answer) textParts.push(data.answer);
      for (const r of (data.results ?? []).slice(0, 6)) {
        if (r.content) textParts.push(`[${r.title}]\n${r.content}`);
      }
      const text = textParts.join("\n\n");

      if (text.length < 50) {
        logger.warn({ entityName }, "Phase 0 [tavily]: empty results");
        continue;
      }

      logger.info(
        { entityName, textLen: text.length, citations: citations.length },
        "Phase 0 [tavily]: results received — extracting structure",
      );

      // Feed Tavily excerpts into Groq for structured contact/owner extraction
      const extracted = await extractWithAI(text, entityName, entityType, country);

      logger.info(
        {
          entityName, hasEmail: !!extracted.email, hasPhone: !!extracted.phone,
          owners: extracted.owners.length, citations: citations.length,
        },
        "Phase 0 [tavily]: extraction complete",
      );

      return {
        ...extracted,
        source: "tavily",
        citations,
        ownershipSources: [...new Set([...extracted.ownershipSources, ...citations])].slice(0, 8),
        ownerResolutions: extracted.ownerResolutions.map(o => ({
          ...o, sourceUrls: o.sourceUrls.length > 0 ? o.sourceUrls : citations.slice(0, 4),
        })),
      };
    } catch (err: any) {
      logger.warn({ err: err?.message }, "Phase 0 [tavily]: call threw");
    }
  }

  logger.warn({ entityName }, "Phase 0 [tavily]: no usable data — all keys failed");
  return EMPTY;
}

/**
 * Fire an Exa neural/semantic search then extract structured contacts via Groq.
 * Exa's neural index excels at people + company lookups — different retrieval
 * model from both Perplexity (sonar) and Tavily (BM25-hybrid).
 * Returns clean per-source excerpts fed into Groq (llama-3.3-70b).
 * Key rotation supports EXA_API_KEY through EXA_API_KEY_8.
 * Returns source: "exa" with Exa result URLs as citations.
 */
export async function researchWithExa(
  entityName: string,
  entityType: string,
  country: string | null = null,
  context: { tradingName?: string | null; city?: string | null } = {},
): Promise<AIExtractResult> {
  const keys = getExaKeys();
  if (keys.length === 0) return EMPTY;

  // Build a targeted OSINT search query — Exa's autoprompt will further refine it
  const queryParts: string[] = [entityName];
  if (context.tradingName && context.tradingName !== entityName) queryParts.push(context.tradingName);
  if (context.city) queryParts.push(context.city);
  if (country) queryParts.push(country);
  queryParts.push("owner contact email");
  const query = queryParts.join(" ");

  logger.info({ entityName, entityType, country, query }, "Phase 0 [exa]: firing Exa neural search");

  for (const key of keys) {
    if (isExhausted(_exhaustedExaKeys, key)) continue;
    try {
      const resp = await fetch(EXA_API, {
        method: "POST",
        headers: {
          "x-api-key": key,
          "Content-Type": "application/json",
        },
        body: JSON.stringify({
          query,
          numResults: 7,
          useAutoprompt: true,
          type: "neural",
          contents: { text: { maxCharacters: 1000 } },
        }),
        signal: AbortSignal.timeout(30_000),
      });

      if (resp.status === 429) {
        _exhaustedExaKeys.set(key, Date.now() + EXHAUSTED_TTL_MS);
        logger.warn("Phase 0 [exa]: rate limit — key exhausted 5 min");
        continue;
      }
      if (resp.status === 401 || resp.status === 403) {
        logger.warn({ status: resp.status }, "Phase 0 [exa]: auth error — skipping key");
        continue;
      }
      if (!resp.ok) {
        const errText = await resp.text().catch(() => "");
        logger.warn({ status: resp.status, err: errText.slice(0, 200) }, "Phase 0 [exa]: API error");
        continue;
      }

      const data = await resp.json() as {
        results?: { url: string; title: string; text?: string; score?: number }[];
      };

      const citations: string[] = (data.results ?? [])
        .map(r => r.url)
        .filter((u): u is string => typeof u === "string" && /^https?:\/\//i.test(u))
        .slice(0, 8);

      // Concatenate per-source excerpts — Exa returns page text, not a synthesised answer
      const textParts: string[] = [];
      for (const r of (data.results ?? []).slice(0, 7)) {
        if (r.text) textParts.push(`[${r.title ?? r.url}]\n${r.text}`);
      }
      const text = textParts.join("\n\n");

      if (text.length < 50) {
        logger.warn({ entityName }, "Phase 0 [exa]: empty results");
        continue;
      }

      logger.info(
        { entityName, textLen: text.length, citations: citations.length },
        "Phase 0 [exa]: results received — extracting structure",
      );

      const extracted = await extractWithAI(text, entityName, entityType, country);

      logger.info(
        {
          entityName, hasEmail: !!extracted.email, hasPhone: !!extracted.phone,
          owners: extracted.owners.length, citations: citations.length,
        },
        "Phase 0 [exa]: extraction complete",
      );

      return {
        ...extracted,
        source: "exa",
        citations,
        ownershipSources: [...new Set([...extracted.ownershipSources, ...citations])].slice(0, 8),
        ownerResolutions: extracted.ownerResolutions.map(o => ({
          ...o, sourceUrls: o.sourceUrls.length > 0 ? o.sourceUrls : citations.slice(0, 4),
        })),
      };
    } catch (err: any) {
      logger.warn({ err: err?.message }, "Phase 0 [exa]: call threw");
    }
  }

  logger.warn({ entityName }, "Phase 0 [exa]: no usable data — all keys failed");
  return EMPTY;
}

/**
 * Main extraction entry point.
 *
 * Strategy (in order):
 *   1. Each Groq key (GROQ_API_KEY, _2, _3) — tries llama-3.3-70b first, then llama-3.1-8b-instant
 *   2. Each OpenRouter key (OPENROUTER_API_KEY, _2) — llama-3.3-70b-instruct
 *
 * A key that returns 429 is marked exhausted for 5 minutes, then auto-recovers.
 * Falls back silently to EMPTY if all providers are exhausted or unavailable.
 * NOTE: OpenRouter exhaustion here (_exhaustedORKeys) is INDEPENDENT of Perplexity Sonar
 *       exhaustion (_exhaustedPerplexityKeys). A 429 on llama extraction never blocks Sonar.
 */
export async function extractWithAI(
  text: string,
  entityName: string,
  entityType: string,
  country: string | null = null,
): Promise<AIExtractResult> {
  if (!text || text.trim().length < 50) return EMPTY;

  try {
    // ── 1. Try all Groq keys ────────────────────────────────────────────────
    for (const key of getGroqKeys()) {
      if (isExhausted(_exhaustedGroqKeys, key)) continue;

      // Primary model
      const result = await callGroq(text, entityName, entityType, country, key, GROQ_MODEL);
      if (result) {
        logger.debug({ entityName, source: result.source, hasEmail: !!result.email, owners: result.owners.length }, "AI extraction complete");
        return result;
      }

      // Fast fallback on same key (if not exhausted by the primary call)
      if (!isExhausted(_exhaustedGroqKeys, key)) {
        const fast = await callGroq(text, entityName, entityType, country, key, GROQ_MODEL_FAST);
        if (fast) {
          logger.debug({ entityName, source: fast.source, hasEmail: !!fast.email }, "AI extraction (fast model) complete");
          return fast;
        }
      }
    }

    // ── 2. Fall back to OpenRouter (llama extraction — separate from Perplexity) ──
    for (const key of getOpenRouterKeys()) {
      if (isExhausted(_exhaustedORKeys, key)) continue;
      const result = await callOpenRouter(text, entityName, entityType, country, key);
      if (result) {
        logger.debug({ entityName, source: result.source, hasEmail: !!result.email }, "AI extraction (OpenRouter) complete");
        return result;
      }
    }
  } catch (err: any) {
    logger.debug({ err: err?.message }, "AI extractor outer catch");
  }

  return EMPTY;
}

// ── Key status snapshot (for /api/system/status) ─────────────────────────────

export interface AIKeySlot {
  index:     number;
  state:     "active" | "exhausted" | "missing";
  expiresAt: string | null;
}

export interface AIKeyStatus {
  groq:       AIKeySlot[];
  perplexity: AIKeySlot[];
  gemini:     AIKeySlot[];
  tavily:     AIKeySlot[];
  exa:        AIKeySlot[];
}

/**
 * Returns a per-slot snapshot of every AI provider key pool:
 * active, exhausted (with expiry timestamp), or missing (env var not set).
 */
export function getAIKeyStatus(): AIKeyStatus {
  const now = Date.now();

  function slotState(
    envName:   string,
    exhausted: Map<string, number>,
    index:     number,
  ): AIKeySlot {
    const val = process.env[envName];
    if (!val) return { index, state: "missing", expiresAt: null };
    const exp = exhausted.get(val);
    if (exp && exp > now) return { index, state: "exhausted", expiresAt: new Date(exp).toISOString() };
    return { index, state: "active", expiresAt: null };
  }

  const groqNames = ["GROQ_API_KEY", "GROQ_API_KEY_1", "GROQ_API_KEY_2", "GROQ_API_KEY_3"];
  const pplxNames = ["PERPLEXITY_API_KEY", ...Array.from({ length: 8 }, (_, i) => `PERPLEXITY_API_KEY_${i + 1}`)];
  const gemNames  = ["GEMINI_API_KEY",     ...Array.from({ length: 8 }, (_, i) => `GEMINI_API_KEY_${i + 1}`)];
  const tavNames  = ["TAVILY_API_KEY",     ...Array.from({ length: 8 }, (_, i) => `TAVILY_API_KEY_${i + 1}`)];
  const exaNames  = ["EXA_API_KEY",        ...Array.from({ length: 8 }, (_, i) => `EXA_API_KEY_${i + 1}`)];

  return {
    groq:       groqNames.map((n, i) => slotState(n, _exhaustedGroqKeys,             i)),
    perplexity: pplxNames.map((n, i) => slotState(n, _exhaustedPerplexityDirectKeys, i)),
    gemini:     gemNames .map((n, i) => slotState(n, _exhaustedGeminiKeys,           i)),
    tavily:     tavNames .map((n, i) => slotState(n, _exhaustedTavilyKeys,           i)),
    exa:        exaNames .map((n, i) => slotState(n, _exhaustedExaKeys,              i)),
  };
}
