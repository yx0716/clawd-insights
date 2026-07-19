// src/analytics-ai.js — Multi-provider AI insights (Claude, OpenAI-compatible, Ollama)
//
// Supported providers:
//   "claude"   — Anthropic Claude API (api.anthropic.com)
//   "openai"   — OpenAI-compatible API (also works with Qwen, DeepSeek, etc.)
//   "ollama"   — Local Ollama (default http://localhost:11434)

const { execFileSync, spawn } = require("child_process");
const fs = require("fs");
const path = require("path");
const os = require("os");
const net = require("net");

// Default provider configs
const PROVIDERS = {
  claude: {
    label: "Claude (Anthropic)",
    baseUrl: "https://api.anthropic.com",
    defaultModel: "claude-haiku-4-5-20251001",
    needsKey: true,
  },
  openai: {
    label: "OpenAI-Compatible (Qwen, DeepSeek, etc.)",
    baseUrl: "https://api.openai.com",
    defaultModel: "gpt-4o-mini",
    needsKey: true,
  },
  ollama: {
    label: "Ollama (Local)",
    baseUrl: "http://localhost:11434",
    defaultModel: "qwen2.5:7b",
    needsKey: false,
  },
};

const INTERNAL_ANALYTICS_SUMMARY_MARKER = "[clawd-analytics-internal-summary-task]";

// ── Provider Registry Data Structures ──

/**
 * @typedef {Object} Provider
 * @property {string} id - Unique identifier (UUID)
 * @property {string} name - User-friendly name (e.g., "Zhipu AI GLM-4-Flash")
 * @property {'claude'|'openai'|'ollama'} type - Provider type
 * @property {string} baseUrl - API endpoint (e.g., "https://api.zhipuai.com")
 * @property {string} [apiKey] - API key (optional for ollama)
 * @property {string} model - Model identifier (e.g., "glm-4-flash", "gpt-4o-mini")
 * @property {boolean} enabled - Whether provider is enabled
 * @property {Object.<string, string>} [customHeaders] - Custom headers for API requests
 * @property {number} [createdAt] - Timestamp when provider was added
 * @property {number} [updatedAt] - Timestamp when provider was last updated
 */

/**
 * @typedef {Object} ProviderRegistry
 * @property {Provider[]} providers - Array of configured providers
 * @property {Object.<string, string>} defaultProviders - Default provider IDs by analysis mode
 * @property {string} [defaultProviders.brief] - Default provider for brief analysis
 * @property {string} [defaultProviders.detail] - Default provider for detail analysis
 * @property {string} [defaultProviders.batch] - Default provider for batch analysis
 */

/**
 * Generate a UUID v4 string
 * @returns {string} UUID v4 format string
 */
function generateUUID() {
  return 'xxxxxxxx-xxxx-4xxx-yxxx-xxxxxxxxxxxx'.replace(/[xy]/g, (c) => {
    const r = Math.random() * 16 | 0;
    const v = c === 'x' ? r : (r & 0x3 | 0x8);
    return v.toString(16);
  });
}

/**
 * Validate a provider object
 * @param {Provider} provider - Provider to validate
 * @returns {boolean} true if valid
 * @throws {Error} if validation fails
 */
function validateProvider(provider) {
  if (!provider || typeof provider !== 'object') {
    throw new Error('Provider must be an object');
  }
  
  if (!provider.name || typeof provider.name !== 'string' || provider.name.trim().length === 0) {
    throw new Error('Provider name is required and must be a non-empty string');
  }
  
  if (!provider.type || !['claude', 'openai', 'ollama'].includes(provider.type)) {
    throw new Error('Provider type must be one of: claude, openai, ollama');
  }
  
  if (!provider.baseUrl || typeof provider.baseUrl !== 'string' || provider.baseUrl.trim().length === 0) {
    throw new Error('Provider baseUrl is required and must be a non-empty string');
  }
  
  // Validate baseUrl format (basic check)
  try {
    new URL(provider.baseUrl);
  } catch {
    throw new Error('Provider baseUrl must be a valid URL');
  }
  
  if (provider.type !== 'ollama' && (!provider.apiKey || typeof provider.apiKey !== 'string')) {
    throw new Error(`Provider type ${provider.type} requires an apiKey`);
  }
  
  if (!provider.model || typeof provider.model !== 'string' || provider.model.trim().length === 0) {
    throw new Error('Provider model is required and must be a non-empty string');
  }
  
  if (provider.customHeaders && typeof provider.customHeaders !== 'object') {
    throw new Error('Provider customHeaders must be an object');
  }
  
  return true;
}

function buildInternalCliAnalysisPrompt(prompt) {
  return `${INTERNAL_ANALYTICS_SUMMARY_MARKER}
Ignore the marker above. It is only used by Clawd to hide this internal summary session from analytics scans.

${prompt}`;
}

// On Windows, `where <cmd>` returns every matching file in PATH. npm-installed
// CLIs produce three sibling shims side-by-side: an extensionless POSIX script
// (`claude`), a `.cmd`, and a `.ps1`. `where` lists the extensionless one
// first, but Node's spawn() without shell:true can't execute a POSIX shell
// script on Windows — it throws ENOENT with the extensionless path. Prefer
// .cmd/.bat/.exe/.ps1 when present so downstream spawn() calls work out of
// the box (the existing isWindowsShellShim check already adds shell:true for
// .cmd/.bat).
function preferWindowsExecutable(paths) {
  if (!paths || !paths.length) return null;
  const windowsExec = paths.find(p => /\.(cmd|bat|exe|ps1)$/i.test(p));
  return windowsExec || paths[0];
}

function resolvePreferredAnalysisProvider(options, config) {
  const opts = Array.isArray(options) ? options : [];
  if (!opts.length) return null;
  const saved = config && config.defaultAnalysisProvider;
  if (saved) {
    const matched = opts.find(opt => (opt.id || opt.provider) === saved);
    if (matched) return matched;
  }
  return opts[0] || null;
}

function getDetailContextEntryCount(detail) {
  if (detail && Array.isArray(detail.conversation) && detail.conversation.length) {
    return detail.conversation.length;
  }
  return Array.isArray(detail && detail.userMessages) ? detail.userMessages.length : 0;
}

function buildSessionContext(detail) {
  let p = "";
  p += `Agent: ${detail.agent}\n`;
  if (detail.title) p += `Title: ${detail.title}\n`;
  if (detail.cwd) p += `Project: ${detail.cwd}\n`;
  if (detail.scope && Number.isFinite(detail.scope.start) && Number.isFinite(detail.scope.end)) {
    p += `Scope: ${new Date(detail.scope.start).toISOString()} - ${new Date(detail.scope.end).toISOString()}\n`;
  }
  if (detail.timestamps.length >= 2) {
    const sorted = [...detail.timestamps].sort((a, b) => a - b);
    const mins = Math.round((sorted[sorted.length - 1] - sorted[0]) / 60000);
    p += `Duration: ${mins} minutes\n`;
  }

  const conversation = Array.isArray(detail.conversation) ? detail.conversation : [];
  if (conversation.length) {
    p += "\n## Conversation\n";
    for (const m of conversation.slice(0, 40)) {
      if (!m || !m.text) continue;
      const speaker = m.role === "assistant" ? "助手" : "用户";
      p += `- ${speaker}: ${m.text}\n`;
    }
    return p;
  }

  p += "\n## User Messages\n";
  for (const m of (detail.userMessages || []).slice(0, 30)) {
    if (m.text) p += `- ${m.text}\n`;
  }
  return p;
}

module.exports = function initAnalyticsAI(ctx) {
  const analysisCachePath = ctx.analysisCachePath || path.join(os.homedir(), ".clawd", "analysis-cache.json");
  const isWin = process.platform === "win32";
  // Hoisted CLI lookup caches — keep at the top of the closure so
  // invalidateCliCaches() (called from setConfig) never trips a TDZ if a
  // hot-reload happens to invoke setConfig before the original `let` lines
  // further down in the file are executed.
  let cachedClaudePath = undefined; // undefined = not searched, null = not found
  let cachedTclaudePath = undefined;
  let cachedCodexPath = undefined;
  // Per-binary CLI capability cache (Map<binaryPath, Set<flag>>). Populated
  // lazily by getCliCapabilities() the first time a CLI is invoked, so we can
  // skip flags the user's installed version doesn't recognize. Cleared by
  // invalidateCliCaches() when the user re-points a custom CLI path.
  const cliCapabilitiesCache = new Map();
  const PROVIDER_COOLDOWN_MS = 5 * 60 * 1000;
  const providerCooldowns = new Map();
  const loggedCliBinaries = new Set();
  const loggedProviderCooldowns = new Set();
  const loggedProxyStrips = new Set();

  function getConfig() {
    return ctx.getAIConfig ? ctx.getAIConfig() : null;
  }

  function setConfig(config) {
    if (ctx.setAIConfig) ctx.setAIConfig(config);
    // The custom CLI paths live in config — invalidating the binary lookup
    // cache here is what makes "Settings → Save → providers refresh" work
    // without an app restart. Without this, findClaudeBinary/findCodexBinary
    // would keep returning whatever they cached on first call.
    invalidateCliCaches();
    // Also drop any cooldown for CLIs the user is trying to fix — otherwise
    // a previously-failing CLI is still locked out for ~5 min after the user
    // points it at a working binary.
    providerCooldowns.clear();
    loggedProviderCooldowns.clear();
  }

  // Legacy compat
  function getApiKey() {
    const cfg = getConfig();
    return cfg ? cfg.apiKey : null;
  }

  function setApiKey(key) {
    const cfg = getConfig() || { provider: "claude" };
    cfg.apiKey = key;
    setConfig(cfg);
  }

  // ── Provider-specific request builders ──

  async function callClaude(apiKey, model, prompt, maxTokens = 500, baseUrlOverride = null) {
    const cfg = getConfig() || {};
    const baseUrl = baseUrlOverride || cfg.baseUrl || PROVIDERS.claude.baseUrl;
    const response = await fetch(`${baseUrl}/v1/messages`, {
      method: "POST",
      headers: {
        "Content-Type": "application/json",
        "User-Agent": "clawd-insights/1.0",
        "x-api-key": apiKey,
        "anthropic-version": "2023-06-01",
      },
      body: JSON.stringify({
        model: model || PROVIDERS.claude.defaultModel,
        max_tokens: maxTokens,
        messages: [{ role: "user", content: prompt }],
      }),
    });

    if (!response.ok) {
      const errText = await response.text();
      throw new Error(`Claude API ${response.status}: ${errText.slice(0, 200)}`);
    }

    const data = await response.json();
    return data.content && data.content[0] && data.content[0].text;
  }

  async function callOpenAICompat(apiKey, model, prompt, baseUrl, maxTokens = 500) {
    const rawUrl = baseUrl || PROVIDERS.openai.baseUrl;
    // Normalize the base URL to a full chat/completions endpoint.
    // Handles several common patterns:
    //   .../v1/chat/completions  → use as-is
    //   .../chat/completions     → use as-is (user already gave full path)
    //   .../v<N>  (e.g. /v1, /v4, /v2) → append /chat/completions
    //   anything else            → append /v1/chat/completions
    const trimmed = rawUrl.replace(/\/+$/, "");
    let url;
    if (trimmed.endsWith("/chat/completions")) {
      url = trimmed;
    } else if (/\/v\d+$/.test(trimmed)) {
      // Ends with /v1, /v4, /v2, etc. — just append the path
      url = `${trimmed}/chat/completions`;
    } else {
      url = `${trimmed}/v1/chat/completions`;
    }
    const headers = { "Content-Type": "application/json", "User-Agent": "clawd-insights/1.0" };
    if (apiKey) headers["Authorization"] = `Bearer ${apiKey}`;

    const response = await fetch(url, {
      method: "POST",
      headers,
      body: JSON.stringify({
        model: model || PROVIDERS.openai.defaultModel,
        max_tokens: maxTokens,
        messages: [{ role: "user", content: prompt }],
      }),
    });

    if (!response.ok) {
      const errText = await response.text();
      throw new Error(`API ${response.status}: ${errText.slice(0, 200)}`);
    }

    const data = await response.json();
    return data.choices && data.choices[0] && data.choices[0].message && data.choices[0].message.content;
  }

  async function callOllama(model, prompt, baseUrl) {
    const url = baseUrl || PROVIDERS.ollama.baseUrl;
    const response = await fetch(`${url}/api/chat`, {
      method: "POST",
      headers: { "Content-Type": "application/json" },
      body: JSON.stringify({
        model: model || PROVIDERS.ollama.defaultModel,
        messages: [{ role: "user", content: prompt }],
        stream: false,
      }),
    });

    if (!response.ok) {
      const errText = await response.text();
      throw new Error(`Ollama ${response.status}: ${errText.slice(0, 200)}`);
    }

    const data = await response.json();
    return data.message && data.message.content;
  }

  // ── Provider Registry Management ──

  /**
   * Get the provider registry from config
   * @returns {Provider[]} Array of configured providers
   */
  function getProviderRegistry() {
    const cfg = getConfig();
    return (cfg && cfg.providers) || [];
  }

  /**
   * Add a new provider to the registry
   * @param {Omit<Provider, 'id'|'createdAt'|'updatedAt'>} provider - Provider data (without id)
   * @returns {Provider} The created provider with id and timestamps
   * @throws {Error} if validation fails or name already exists
   */
  function addProvider(provider) {
    validateProvider(provider);
    
    const cfg = getConfig() || { providers: [] };
    if (!cfg.providers) cfg.providers = [];
    
    // Check for duplicate names
    if (cfg.providers.some(p => p.name === provider.name)) {
      throw new Error(`Provider name "${provider.name}" already exists`);
    }
    
    const now = Date.now();
    const newProvider = {
      id: generateUUID(),
      ...provider,
      enabled: provider.enabled !== false,
      createdAt: now,
      updatedAt: now,
    };
    
    // Spread to a new object so the store detects a change (avoids noop on same reference)
    setConfig({ ...cfg, providers: [...cfg.providers, newProvider] });
    return newProvider;
  }

  /**
   * Update an existing provider
   * @param {string} id - Provider ID
   * @param {Partial<Omit<Provider, 'id'|'createdAt'>>} updates - Fields to update
   * @returns {Provider} The updated provider
   * @throws {Error} if provider not found or validation fails
   */
  function updateProvider(id, updates) {
    const cfg = getConfig() || { providers: [] };
    if (!cfg.providers) cfg.providers = [];
    
    const index = cfg.providers.findIndex(p => p.id === id);
    if (index === -1) {
      throw new Error(`Provider with id "${id}" not found`);
    }
    
    const existing = cfg.providers[index];
    const updated = { ...existing, ...updates, id: existing.id, createdAt: existing.createdAt };
    
    // Validate the updated provider
    validateProvider(updated);
    
    // Check for duplicate names (excluding self)
    if (updates.name && cfg.providers.some(p => p.id !== id && p.name === updates.name)) {
      throw new Error(`Provider name "${updates.name}" already exists`);
    }
    
    updated.updatedAt = Date.now();
    const newProviders = cfg.providers.map((p, i) => i === index ? updated : p);
    setConfig({ ...cfg, providers: newProviders });
    return updated;
  }

  /**
   * Delete a provider from the registry
   * @param {string} id - Provider ID
   * @throws {Error} if provider not found
   */
  function deleteProvider(id) {
    const cfg = getConfig() || { providers: [] };
    if (!cfg.providers) cfg.providers = [];
    
    const index = cfg.providers.findIndex(p => p.id === id);
    if (index === -1) {
      throw new Error(`Provider with id "${id}" not found`);
    }
    
    const newProviders = cfg.providers.filter((_, i) => i !== index);
    
    // Clean up default provider references if this provider was set as default
    const newDefaultProviders = { ...(cfg.defaultProviders || {}) };
    for (const mode of ['brief', 'detail', 'batch']) {
      if (newDefaultProviders[mode] === id) {
        delete newDefaultProviders[mode];
      }
    }
    
    setConfig({ ...cfg, providers: newProviders, defaultProviders: newDefaultProviders });
  }

  /**
   * Get a provider by ID
   * @param {string} id - Provider ID
   * @returns {Provider|null} The provider or null if not found
   */
  function getProvider(id) {
    const registry = getProviderRegistry();
    return registry.find(p => p.id === id) || null;
  }

  /**
   * Test a provider connection
   * @param {Omit<Provider, 'id'|'enabled'|'createdAt'|'updatedAt'>} provider - Provider to test
   * @returns {Promise<{success: boolean, error?: string, model?: string, latencyMs?: number}>}
   */
  async function testProvider(provider) {
    try {
      validateProvider(provider);
    } catch (err) {
      return { success: false, error: err.message };
    }
    
    const startTime = Date.now();
    const testPrompt = "Say 'OK' in one word.";
    
    // Build the actual URL that will be used so we can show it on failure
    let resolvedUrl = provider.baseUrl || "";
    if (provider.type === "openai") {
      const trimmed = resolvedUrl.replace(/\/+$/, "");
      if (trimmed.endsWith("/chat/completions")) resolvedUrl = trimmed;
      else if (/\/v\d+$/.test(trimmed)) resolvedUrl = `${trimmed}/chat/completions`;
      else resolvedUrl = `${trimmed}/v1/chat/completions`;
    }
    
    try {
      let result;
      if (provider.type === 'claude') {
        result = await callClaude(provider.apiKey, provider.model, testPrompt, 10, provider.baseUrl);
      } else if (provider.type === 'ollama') {
        result = await callOllama(provider.model, testPrompt, provider.baseUrl);
      } else {
        result = await callOpenAICompat(provider.apiKey, provider.model, testPrompt, provider.baseUrl, 10);
      }
      
      if (!result) {
        return { success: false, error: `No response from provider (URL: ${resolvedUrl})` };
      }
      
      return {
        success: true,
        model: provider.model,
        latencyMs: Date.now() - startTime,
      };
    } catch (err) {
      // Attach the resolved URL to the error so the user knows what was actually called
      const detail = err.message || "Unknown error";
      return { success: false, error: `${detail} (URL: ${resolvedUrl})` };
    }
  }

  /**
   * Get the default provider for a given analysis mode
   * @param {string} mode - Analysis mode ('brief', 'detail', 'batch')
   * @returns {string|null} Provider ID or null if not set
   */
  function getDefaultProvider(mode) {
    const cfg = getConfig();
    if (!cfg || !cfg.defaultProviders) return null;
    return cfg.defaultProviders[mode] || null;
  }

  /**
   * Set the default provider for a given analysis mode
   * @param {string} mode - Analysis mode ('brief', 'detail', 'batch')
   * @param {string} providerId - Provider ID
   * @throws {Error} if provider not found
   */
  function setDefaultProvider(mode, providerId) {
    if (!['brief', 'detail', 'batch'].includes(mode)) {
      throw new Error(`Invalid analysis mode: ${mode}`);
    }
    
    // Verify provider exists
    const provider = getProvider(providerId);
    if (!provider) {
      throw new Error(`Provider with id "${providerId}" not found`);
    }
    
    const cfg = getConfig() || {};
    setConfig({ ...cfg, defaultProviders: { ...(cfg.defaultProviders || {}), [mode]: providerId } });
  }

  function uniqueExistingPaths(candidates) {
    const seen = new Set();
    const results = [];
    for (const file of candidates || []) {
      if (!file || seen.has(file)) continue;
      seen.add(file);
      if (fs.existsSync(file)) results.push(file);
    }
    return results;
  }

  function getCommonCliSearchDirs() {
    const home = os.homedir();
    const dirs = [
      path.join(home, ".npm-global", "bin"),
      path.join(home, ".local", "bin"),
      path.join(home, "bin"),
    ];
    if (isWin) {
      const appData = process.env.APPDATA || path.join(home, "AppData", "Roaming");
      dirs.unshift(path.join(appData, "npm"));
    } else {
      dirs.unshift("/opt/homebrew/bin", "/usr/local/bin", "/usr/bin", "/bin");
    }
    // Node version managers — Codex (and other npm-installed CLIs) end up
    // here when the user manages Node via NVM / Volta / fnm / asdf instead
    // of system Node. Without these, `findInLoginShell` is the only fallback
    // and it routinely fails because most NVM users put `nvm.sh` in
    // `~/.zshrc` (interactive) while we spawn `-l` (login) shells.
    try {
      const nvmDir = process.env.NVM_DIR || path.join(home, ".nvm");
      const nvmNodes = path.join(nvmDir, "versions", "node");
      const versions = fs.readdirSync(nvmNodes).sort().reverse();
      for (const v of versions) dirs.push(path.join(nvmNodes, v, "bin"));
    } catch { /* no nvm */ }
    try {
      const fnmRoot = process.env.FNM_DIR || path.join(home, ".fnm", "node-versions");
      const versions = fs.readdirSync(fnmRoot).sort().reverse();
      for (const v of versions) dirs.push(path.join(fnmRoot, v, "installation", "bin"));
    } catch { /* no fnm */ }
    try {
      const voltaHome = process.env.VOLTA_HOME || path.join(home, ".volta");
      dirs.push(path.join(voltaHome, "bin"));
    } catch { /* no volta */ }
    try {
      const asdfData = process.env.ASDF_DATA_DIR || path.join(home, ".asdf");
      dirs.push(path.join(asdfData, "shims"));
    } catch { /* no asdf */ }
    // pnpm / Yarn / Bun globals — covers users who installed Codex via
    // alternative package managers
    try { dirs.push(path.join(home, ".bun", "bin")); } catch { }
    try { dirs.push(path.join(home, ".yarn", "bin")); } catch { }
    if (process.env.PNPM_HOME) dirs.push(process.env.PNPM_HOME);
    try { dirs.push(path.join(home, "Library", "pnpm")); } catch { } // pnpm default on macOS
    return uniqueExistingPaths(dirs);
  }

  function buildCliEnv(extraEnv = {}) {
    const env = { ...process.env, ...extraEnv };
    const delimiter = path.delimiter;
    const current = String(env.PATH || "").split(delimiter).filter(Boolean);
    env.PATH = [...new Set([...getCommonCliSearchDirs(), ...current])].join(delimiter);
    return env;
  }

  const PROXY_ENV_KEYS = [
    "HTTPS_PROXY",
    "https_proxy",
    "HTTP_PROXY",
    "http_proxy",
    "ALL_PROXY",
    "all_proxy",
  ];

  function parseProxyUrl(value) {
    if (!value) return null;
    try {
      const url = new URL(String(value));
      const protocol = url.protocol.replace(/:$/, "");
      const defaultPort = protocol === "https" ? 443 : protocol.startsWith("socks") ? 1080 : 80;
      const port = Number(url.port || defaultPort);
      if (!url.hostname || !port) return null;
      return { host: url.hostname, port, protocol, raw: String(value) };
    } catch {
      return null;
    }
  }

  function isLoopbackHost(host) {
    return host === "127.0.0.1" || host === "localhost" || host === "::1";
  }

  function canConnect(host, port, timeoutMs = 400) {
    return new Promise(resolve => {
      let settled = false;
      const socket = net.createConnection({ host, port });
      const finish = (ok) => {
        if (settled) return;
        settled = true;
        try { socket.destroy(); } catch { /* ignore */ }
        resolve(ok);
      };
      socket.setTimeout(timeoutMs);
      socket.once("connect", () => finish(true));
      socket.once("timeout", () => finish(false));
      socket.once("error", () => finish(false));
    });
  }

  async function sanitizeCliProxyEnv(env, cliName) {
    const nextEnv = { ...env };
    const proxyEntries = PROXY_ENV_KEYS
      .map(key => ({ key, parsed: parseProxyUrl(nextEnv[key]) }))
      .filter(entry => entry.parsed && isLoopbackHost(entry.parsed.host));
    if (!proxyEntries.length) return nextEnv;

    const reachability = new Map();
    for (const entry of proxyEntries) {
      const target = `${entry.parsed.host}:${entry.parsed.port}`;
      if (!reachability.has(target)) {
        reachability.set(target, await canConnect(entry.parsed.host, entry.parsed.port));
      }
    }

    for (const entry of proxyEntries) {
      const target = `${entry.parsed.host}:${entry.parsed.port}`;
      if (reachability.get(target)) continue;
      delete nextEnv[entry.key];
      const logKey = `${cliName}:${entry.key}:${target}`;
      if (!loggedProxyStrips.has(logKey)) {
        loggedProxyStrips.add(logKey);
        console.warn(`Clawd analytics: ignoring unavailable local proxy ${target} for ${cliName}`);
      }
    }

    return nextEnv;
  }

  function isWindowsShellShim(filePath) {
    return isWin && /\.(cmd|bat)$/i.test(filePath || "");
  }

  function spawnCli(filePath, args, options = {}) {
    return spawn(filePath, args, {
      ...options,
      shell: options.shell ?? isWindowsShellShim(filePath),
    });
  }

  function parseLocatorOutput(output) {
    return String(output || "")
      .split(/\r?\n/)
      .map(line => line.trim().replace(/^"+|"+$/g, ""))
      .filter(Boolean);
  }

  function findOnPath(commandName) {
    try {
      const lookupCmd = isWin ? "where" : "which";
      const result = execFileSync(lookupCmd, [commandName], {
        encoding: "utf8",
        timeout: 3000,
        env: buildCliEnv(),
      });
      const lines = parseLocatorOutput(result);
      const existing = lines.filter(file => fs.existsSync(file));
      if (!existing.length) return null;
      return isWin ? preferWindowsExecutable(existing) : existing[0];
    } catch { /* not in PATH */ }
    return null;
  }

  function findInLoginShell(commandName) {
    if (isWin) return null;
    const shell = process.env.SHELL || "/bin/sh";
    // Try login + interactive in turn. Most NVM/Volta/fnm users init their
    // version manager from `~/.zshrc` (interactive), so a pure `-l` (login)
    // invocation misses Codex even though `which codex` works in the user's
    // own terminal. We try the most aggressive combo first, then fall back.
    const attempts = [
      ["-l", "-i", "-c", `command -v ${commandName} 2>/dev/null`],
      ["-i", "-c", `command -v ${commandName} 2>/dev/null`],
      ["-l", "-c", `command -v ${commandName} 2>/dev/null`],
    ];
    for (const args of attempts) {
      try {
        const result = execFileSync(shell, args, {
          encoding: "utf8",
          timeout: 5000,
          env: buildCliEnv(),
          stdio: ["ignore", "pipe", "ignore"], // suppress shell rc noise
        });
        const lines = parseLocatorOutput(result).filter(line => line.startsWith("/"));
        const hit = lines[lines.length - 1];
        if (hit && fs.existsSync(hit)) return hit;
      } catch { /* try next combo */ }
    }
    return null;
  }

  function getDefaultNpmCommandCandidates(commandName) {
    const home = os.homedir();
    if (isWin) {
      const appData = process.env.APPDATA || path.join(home, "AppData", "Roaming");
      return [
        path.join(appData, "npm", `${commandName}.cmd`),
        path.join(appData, "npm", `${commandName}.exe`),
      ];
    }
    return [
      path.join(home, ".npm-global", "bin", commandName),
      path.join(home, ".local", "bin", commandName),
    ];
  }

  function findCommandBinary(commandName, extraCandidates = []) {
    return (
      findOnPath(commandName) ||
      findInLoginShell(commandName) ||
      uniqueExistingPaths([...extraCandidates, ...getDefaultNpmCommandCandidates(commandName)])[0] ||
      null
    );
  }

  // ── Local Claude CLI detection ──
  // (cachedClaudePath is hoisted to the top of the closure — see comment there)

  // Read user-supplied override (set via Settings UI). Returns the path if it
  // exists on disk, otherwise null. Bypasses every search heuristic so users
  // with exotic install layouts (NVM in non-standard dir, custom prefix, etc.)
  // have a guaranteed escape hatch.
  function getCustomCliPath(key) {
    const cfg = getConfig();
    if (!cfg || !cfg.customCliPaths) return null;
    const candidate = cfg.customCliPaths[key];
    if (typeof candidate !== "string" || !candidate.trim()) return null;
    const expanded = candidate.trim().replace(/^~(?=[/\\])/, os.homedir());
    try { if (fs.existsSync(expanded)) return expanded; } catch { }
    return null;
  }

  // Invalidate cached binary lookups when the user changes their custom path
  // (or any other config) — without this, switching from "wrong path" to
  // "right path" would still report the old result until app restart.
  function invalidateCliCaches() {
    cachedClaudePath = undefined;
    cachedTclaudePath = undefined;
    cachedCodexPath = undefined;
    // Drop the capability cache too — when the user re-points a CLI, the new
    // binary might be a totally different version with a different flag set.
    cliCapabilitiesCache.clear();
  }

  function findClaudeBinary() {
    if (ctx.disableCliDiscoveryForTests) return null;
    const custom = getCustomCliPath("claude");
    if (custom) return custom;
    if (cachedClaudePath !== undefined) return cachedClaudePath;
    const extraCandidates = [];

    // Homebrew (macOS) — standalone Mach-O binary, most reliable
    const brewDirs = ["/opt/homebrew/Caskroom/claude-code", "/usr/local/Caskroom/claude-code"];
    for (const brewDir of brewDirs) {
      try {
        const versions = fs.readdirSync(brewDir).sort().reverse();
        for (const v of versions) {
          extraCandidates.push(path.join(brewDir, v, "claude"));
        }
      } catch { /* dir doesn't exist */ }
    }

    // Claude Desktop managed (macOS) — .app bundle only
    const claudeCodeDir = path.join(os.homedir(), "Library", "Application Support", "Claude", "claude-code");
    try {
      const versions = fs.readdirSync(claudeCodeDir).sort().reverse();
      for (const v of versions) {
        extraCandidates.push(path.join(claudeCodeDir, v, "claude.app", "Contents", "MacOS", "claude"));
      }
    } catch { /* dir doesn't exist */ }

    // Windows npm / installer candidates
    if (isWin) {
      const home = os.homedir();
      const localAppData = process.env.LOCALAPPDATA || path.join(home, "AppData", "Local");
      extraCandidates.push(path.join(localAppData, "Programs", "Claude Code", "claude.exe"));
      const progFiles = process.env.PROGRAMFILES || "C:\\Program Files";
      extraCandidates.push(path.join(progFiles, "Claude Code", "claude.exe"));
      const progFilesX86 = process.env["PROGRAMFILES(X86)"] || "C:\\Program Files (x86)";
      extraCandidates.push(path.join(progFilesX86, "Claude Code", "claude.exe"));
    }

    // Linux-specific paths
    if (process.platform === "linux") {
      extraCandidates.push("/usr/local/bin/claude");
      extraCandidates.push("/opt/claude-code/bin/claude");
      // Linuxbrew
      const linuxbrew = "/home/linuxbrew/.linuxbrew/bin/claude";
      extraCandidates.push(linuxbrew);
      // Snap
      extraCandidates.push("/snap/claude/current/bin/claude");
    }

    cachedClaudePath = findCommandBinary("claude", extraCandidates);
    return cachedClaudePath;
  }

  // ── tclaude CLI detection ──
  // tclaude is the Tencent fork of Claude Code: same CLI protocol, different
  // binary name (`tclaude`) and config dir (~/.tclaude). We reuse the exact
  // Claude Code invocation path (callClaudeCLI / callClaudeCLIWithSystem) and
  // only need to locate the binary + read its default model.
  function findTclaudeBinary() {
    if (ctx.disableCliDiscoveryForTests) return null;
    const custom = getCustomCliPath("tclaude");
    if (custom) return custom;
    if (cachedTclaudePath !== undefined) return cachedTclaudePath;
    const extraCandidates = [];

    // Homebrew (macOS)
    const brewDirs = ["/opt/homebrew/bin/tclaude", "/usr/local/bin/tclaude"];
    for (const p of brewDirs) extraCandidates.push(p);

    // Windows npm / installer candidates
    if (isWin) {
      const home = os.homedir();
      const localAppData = process.env.LOCALAPPDATA || path.join(home, "AppData", "Local");
      extraCandidates.push(path.join(localAppData, "Programs", "tclaude", "tclaude.exe"));
      const progFiles = process.env.PROGRAMFILES || "C:\\Program Files";
      extraCandidates.push(path.join(progFiles, "tclaude", "tclaude.exe"));
    }

    // Linux-specific paths
    if (process.platform === "linux") {
      extraCandidates.push("/usr/local/bin/tclaude");
      extraCandidates.push("/home/linuxbrew/.linuxbrew/bin/tclaude");
    }

    cachedTclaudePath = findCommandBinary("tclaude", extraCandidates);
    return cachedTclaudePath;
  }

  // ── Codex CLI detection ──
  // (cachedCodexPath is hoisted to the top of the closure — see comment there)

  // Many users install Codex via the OpenAI desktop app (Codex.app) or the
  // OpenAI ChatGPT plugin for Cursor/VS Code instead of `npm i -g @openai/codex`.
  // Both bundle a fully working `codex-cli` binary that we can call directly,
  // but `which codex` returns nothing because nothing is on PATH. Enumerate
  // the known bundle locations so auto-detection covers these cases without
  // requiring the user to set a manual override.
  function getBundledCodexCandidates() {
    const home = os.homedir();
    const out = [];
    const exe = isWin ? "codex.exe" : "codex";

    // Mac app bundle (system + user-local Applications). Codex.app drops a
    // standalone Mach-O at Contents/Resources/codex; the .app shell is just
    // the launcher GUI. Verified on Codex.app 0.118.0-alpha.2 (Mar 2026).
    if (process.platform === "darwin") {
      out.push(`/Applications/Codex.app/Contents/Resources/codex`);
      out.push(path.join(home, "Applications", "Codex.app", "Contents", "Resources", "codex"));
    }

    // Cursor / VS Code "OpenAI ChatGPT" extension (publisher: openai.chatgpt).
    // The extension ships per-platform binaries under `bin/<platform>-<arch>/codex`.
    // Folder name encodes the version + platform: openai.chatgpt-26.325.31654-darwin-arm64
    // We glob the parent extensions dir, then dive into bin/* to find the binary.
    const extRoots = [
      path.join(home, ".cursor", "extensions"),
      path.join(home, ".vscode", "extensions"),
      path.join(home, ".vscode-insiders", "extensions"),
      path.join(home, ".windsurf", "extensions"), // Codeium fork
    ];
    for (const extRoot of extRoots) {
      try {
        const entries = fs.readdirSync(extRoot);
        for (const entry of entries) {
          // Match the OpenAI publisher prefix — covers `openai.chatgpt-*`
          // and any future Codex-branded extension under the same publisher.
          if (!/^openai\./i.test(entry) && !/codex/i.test(entry)) continue;
          const binDir = path.join(extRoot, entry, "bin");
          try {
            const archDirs = fs.readdirSync(binDir);
            for (const archDir of archDirs) {
              out.push(path.join(binDir, archDir, exe));
            }
          } catch { /* no bin dir */ }
        }
      } catch { /* no extensions dir */ }
    }

    return out;
  }

  function findCodexBinary() {
    if (ctx.disableCliDiscoveryForTests) return null;
    const custom = getCustomCliPath("codex");
    if (custom) return custom;
    if (cachedCodexPath !== undefined) return cachedCodexPath;
    const extras = [
      "/opt/homebrew/bin/codex",
      "/usr/local/bin/codex",
      ...getBundledCodexCandidates(),
    ];
    // Linux-specific Codex paths
    if (process.platform === "linux") {
      extras.push("/home/linuxbrew/.linuxbrew/bin/codex");
      extras.push("/snap/codex/current/bin/codex");
      extras.push("/opt/codex/bin/codex");
    }
    // Windows Program Files
    if (isWin) {
      const progFiles = process.env.PROGRAMFILES || "C:\\Program Files";
      extras.push(path.join(progFiles, "Codex", "codex.exe"));
    }
    cachedCodexPath = findCommandBinary("codex", extras);
    return cachedCodexPath;
  }

  // Probe a CLI binary for the long-flags it accepts on a given subcommand.
  // Used to skip version-gated flags (e.g. --ephemeral on codex < 0.118,
  // --output-schema on codex < 0.118, --tools "" on older claude versions)
  // that would otherwise hard-fail with `error: unexpected argument`.
  //
  // Result is a Set<string> of flag names including the leading `--`. An
  // empty set means probing failed — callers must treat that as "I don't know,
  // omit any version-gated flag" rather than "no flags supported", since
  // forcing the legacy minimal arg set always works.
  function getCliCapabilities(binaryPath, subcommand) {
    const cacheKey = `${binaryPath}::${subcommand || ""}`;
    if (cliCapabilitiesCache.has(cacheKey)) return cliCapabilitiesCache.get(cacheKey);
    const supported = new Set();
    try {
      const args = subcommand ? [subcommand, "--help"] : ["--help"];
      const output = execFileSync(binaryPath, args, {
        encoding: "utf8",
        timeout: 5000,
        env: buildCliEnv(),
        stdio: ["ignore", "pipe", "pipe"],
        maxBuffer: 1024 * 1024,
      });
      // Match `--flag-name` at the start of help lines (optionally preceded by
      // `-x, ` short alias). Walks both `--help` body and any "Options:" block.
      for (const m of String(output || "").matchAll(/^\s*(?:-\w[, ]+)?(--[a-z][a-z0-9-]*)/gim)) {
        supported.add(m[1]);
      }
    } catch (err) {
      // Don't spam — log once per binary
      const logKey = `caps:${cacheKey}`;
      if (!loggedCliBinaries.has(logKey)) {
        loggedCliBinaries.add(logKey);
        console.warn(`Clawd analytics: failed to probe ${binaryPath} ${subcommand || ""} --help:`, err.message);
      }
    }
    cliCapabilitiesCache.set(cacheKey, supported);
    return supported;
  }

  function getProviderCooldown(providerId) {
    const cooldown = providerCooldowns.get(providerId);
    if (!cooldown) return null;
    if (cooldown.until <= Date.now()) {
      providerCooldowns.delete(providerId);
      loggedProviderCooldowns.delete(providerId);
      return null;
    }
    return cooldown;
  }

  function disableProviderTemporarily(providerId, reason) {
    providerCooldowns.set(providerId, {
      reason,
      until: Date.now() + PROVIDER_COOLDOWN_MS,
    });
  }

  function isLikelyCliNetworkFailure(message) {
    const text = String(message || "");
    return [
      /failed to refresh available models/i,
      /stream disconnected before completion/i,
      /error sending request/i,
      /transport channel closed/i,
      /connection refused/i,
      /connectfailed/i,
      /tcp connect error/i,
      /wham\/apps/i,
      /backend-api/i,
      /proxy/i,
    ].some(re => re.test(text));
  }

  // Detect "you need to log in again" style errors. Both Claude and Codex CLIs
  // surface these via different wording depending on version, so be inclusive.
  // When matched, friendlyCliError returns an actionable hint instead of the
  // raw upstream message — fixing the bad UX where `code 1` left users guessing.
  function isLikelyCliAuthFailure(message) {
    const text = String(message || "");
    return [
      /not (?:authenticated|logged in|signed in)/i,
      /please (?:log ?in|sign ?in|authenticate)/i,
      /(?:login|session|token|credential|auth(?:entication)?)\s+(?:expired|invalid|missing|required)/i,
      /(?:invalid|missing|expired|revoked)\s+(?:api[\s_-]?key|token|credential)/i,
      /authentication\s+(?:failed|required|error)/i,
      /unauthori[sz]ed/i,
      /401\b/,
      /OAuth\s+token/i,
      /run\s+`?claude(?:\s+login)?`?\s+to/i,
    ].some(re => re.test(text));
  }

  function friendlyCliError(cliName, message) {
    const text = String(message || "").trim();
    const proxyTarget = text.match(/\b(?:127\.0\.0\.1|localhost|\[::1\]|::1):(\d+)\b/i);
    if (proxyTarget && /connection refused/i.test(text)) {
      const host = proxyTarget[0].replace(/^\[|\]$/g, "");
      return `${cliName} 无法连接本地代理 ${host}。请确认代理已启动，或关闭该代理配置后重试。`;
    }
    if (isLikelyCliAuthFailure(text)) {
      const cmd = /codex/i.test(cliName) ? "codex login" : "claude";
      return `${cliName} 登录态失效或未认证。请在终端运行 \`${cmd}\` 重新登录后再试。`;
    }
    if (isLikelyCliNetworkFailure(text)) {
      return `${cliName} 网络初始化失败。请检查代理、登录状态或外网连通性后重试。`;
    }
    return text || `${cliName} 执行失败`;
  }

  function stripAnsi(text) {
    return String(text || "").replace(/\u001b\[[0-9;]*m/g, "");
  }

  function summarizeCodexError(stderr, fallback) {
    const lines = stripAnsi(stderr)
      .split("\n")
      .map(line => line.trim())
      .filter(Boolean);

    if (!lines.length) return fallback || "Codex CLI failed";

    const ignore = [
      /^WARNING: proceeding, even though we could not update PATH:/,
      /^Reading additional input from stdin\.\.\.$/,
      /^note: run with `RUST_BACKTRACE=1` environment variable to display a backtrace$/,
    ];
    const important = [
      /\bERROR\b/i,
      /\bfailed\b/i,
      /\bpanic/i,
      /\bCould not\b/i,
      /\bnot found\b/i,
      /\bdenied\b/i,
      /\btimeout\b/i,
      /\bunauthorized\b/i,
      /\bforbidden\b/i,
      /\bdns error\b/i,
      /\breadonly database\b/i,
      /\bwebsocket\b/i,
    ];

    const cleaned = lines
      .filter(line => !ignore.some(re => re.test(line)))
      .map(line => line
        .replace(/^\d{4}-\d{2}-\d{2}T\S+\s+(WARN|ERROR)\s+\S+:\s*/, "$1: ")
        .replace(/^thread '[^']+' \([^)]*\) panicked at .*?:\d+:\d+:\s*/, "panic: ")
      );

    const prioritized = cleaned.filter(line => important.some(re => re.test(line)));
    const selected = (prioritized.length ? prioritized : cleaned).slice(0, 6).join(" | ");
    return selected || fallback || "Codex CLI failed";
  }

  // Best-effort error extraction from Claude CLI's stream-json output. Claude
  // streams everything to stdout as NDJSON (including failures), so when exit
  // code != 0 the real cause is usually buried in a `result` event with
  // `is_error: true` while stderr is empty. This walks the NDJSON, surfaces the
  // most informative error string we can find, and falls back to a stdout tail
  // so users at least see *something* instead of the bare `code 1`.
  function summarizeClaudeError(stdout, stderr, fallback) {
    const stderrTrim = String(stderr || "").trim();
    const stdoutText = String(stdout || "");

    // Pass 1: scan NDJSON for error-bearing events.
    const errorMessages = [];
    const lines = stdoutText.split("\n").filter(Boolean);
    for (const line of lines) {
      let obj;
      try { obj = JSON.parse(line); } catch { continue; }
      if (!obj || typeof obj !== "object") continue;

      // result event flagged as error (most common path)
      if (obj.type === "result" && (obj.is_error === true || /error/i.test(obj.subtype || ""))) {
        const msg = obj.result || obj.error || obj.message;
        if (typeof msg === "string" && msg.trim()) errorMessages.push(msg.trim());
      }
      // system / init events with subtype=error (rare but possible)
      if (obj.type === "system" && /error/i.test(obj.subtype || "")) {
        const msg = obj.error || obj.message || obj.result;
        if (typeof msg === "string" && msg.trim()) errorMessages.push(msg.trim());
      }
      // assistant message with is_error flag
      if (obj.type === "assistant" && obj.is_error === true && obj.message) {
        const content = obj.message.content;
        if (Array.isArray(content)) {
          for (const c of content) {
            if (c && c.type === "text" && typeof c.text === "string") errorMessages.push(c.text.trim());
          }
        }
      }
      // top-level error field on any event
      if (typeof obj.error === "string" && obj.error.trim() && !errorMessages.includes(obj.error.trim())) {
        errorMessages.push(obj.error.trim());
      }
    }
    if (errorMessages.length) {
      return errorMessages.slice(0, 2).join(" | ").slice(0, 400);
    }

    // Pass 2: stderr (in case claude wrote anything there)
    if (stderrTrim) return stderrTrim.slice(0, 400);

    // Pass 3: stdout tail — strips JSON noise, keeps the last ~200 visible chars
    const tail = stdoutText.replace(/\s+/g, " ").trim().slice(-200);
    if (tail) return `${fallback || "claude exec failed"} (stdout tail: ${tail})`;

    return fallback || "claude exec failed";
  }

  // Extract and parse the first complete top-level JSON object from a free-form
  // text blob. The previous implementation used a greedy `/\{[\s\S]*\}/` regex
  // that grabbed from the FIRST `{` to the LAST `}`, which broke whenever the
  // model wrapped its JSON in markdown explanation that contained any other
  // `}` (think "outcomes": [{...}], or trailing "Note: see {related}").
  //
  // Strategy: walk char-by-char tracking string state and brace depth. Skip
  // until the first unquoted `{`, then read until the matching `}`. Try to
  // JSON.parse — if that succeeds, return the object; if it fails, continue
  // scanning past that block in case there's a *better* candidate later. On
  // total failure return null so callers fall through to a text-summary.
  // Attempt to fix unescaped double quotes inside JSON string values.
  // Common model mistake: {"detail":"确定以飞书"Home"主文档"} → parser breaks at inner "
  // Strategy: replace inner unescaped " with 「」 between JSON structural quotes.
  // Strip ```json ... ``` (or any ``` ... ```) wrapper. Claude/Codex CLI
  // sometimes ignore the "no code block" instruction and wrap JSON in fences.
  function stripJsonFence(s) {
    if (!s || typeof s !== "string") return s;
    // Match a leading fence (with optional language tag) and trailing fence.
    // Use a non-greedy capture so a fence pair at the start gets picked even
    // when there's surrounding prose.
    const fence = s.match(/```(?:json|JSON)?\s*([\s\S]*?)```/);
    if (fence && fence[1]) return fence[1].trim();
    return s;
  }

  // Remove `,` before `}` or `]` — a common LLM mistake that vanilla JSON.parse
  // rejects even though the structure is otherwise valid.
  function fixTrailingCommas(s) {
    if (!s || typeof s !== "string") return s;
    return s.replace(/,(\s*[}\]])/g, "$1");
  }

  // Escape raw newlines, carriage returns, and tabs that appear INSIDE string
  // values. JSON forbids literal control chars in strings but LLMs frequently
  // leak them when paraphrasing user messages or quoting code.
  function escapeNewlinesInStrings(s) {
    if (!s || typeof s !== "string") return s;
    let out = "";
    let inStr = false, escaped = false;
    for (let i = 0; i < s.length; i++) {
      const ch = s[i];
      if (escaped) { out += ch; escaped = false; continue; }
      if (ch === "\\") { out += ch; escaped = true; continue; }
      if (ch === '"') { out += ch; inStr = !inStr; continue; }
      if (inStr) {
        if (ch === "\n") { out += "\\n"; continue; }
        if (ch === "\r") { out += "\\r"; continue; }
        if (ch === "\t") { out += "\\t"; continue; }
      }
      out += ch;
    }
    return out;
  }

  // Best-effort recovery for truncated output (e.g. CLI killed before the
  // response finished). Closes any open string, then balances braces/brackets.
  function repairTruncation(s) {
    if (!s || typeof s !== "string") return s;
    let opens = 0, bracketOpens = 0, inStr = false, escaped = false;
    for (let i = 0; i < s.length; i++) {
      const ch = s[i];
      if (escaped) { escaped = false; continue; }
      if (inStr) {
        if (ch === "\\") escaped = true;
        else if (ch === '"') inStr = false;
        continue;
      }
      if (ch === '"') inStr = true;
      else if (ch === "{") opens++;
      else if (ch === "}") opens--;
      else if (ch === "[") bracketOpens++;
      else if (ch === "]") bracketOpens--;
    }
    let repaired = s;
    if (inStr) repaired += '"';
    while (bracketOpens-- > 0) repaired += "]";
    while (opens-- > 0) repaired += "}";
    return repaired;
  }

  // Try a sequence of progressively-more-lenient transforms. Returns the first
  // candidate that parses to a non-null object, or null. Order matters: cheap
  // / safe transforms first, structural surgery last.
  function tryParseLenientJson(text) {
    if (!text || typeof text !== "string") return null;
    const attempts = [];
    attempts.push(text);
    const dequoted = sanitizeJsonQuotes(text);
    if (dequoted !== text) attempts.push(dequoted);
    const fenced = stripJsonFence(text);
    if (fenced !== text) attempts.push(fenced);
    const trailing = fixTrailingCommas(fenced || text);
    if (trailing !== (fenced || text)) attempts.push(trailing);
    const escaped = escapeNewlinesInStrings(trailing || fenced || text);
    if (escaped !== (trailing || fenced || text)) attempts.push(escaped);
    const combined = fixTrailingCommas(escapeNewlinesInStrings(sanitizeJsonQuotes(stripJsonFence(text))));
    attempts.push(combined);
    const repaired = repairTruncation(combined);
    if (repaired !== combined) attempts.push(repaired);
    for (const cand of attempts) {
      try {
        const obj = JSON.parse(cand);
        if (obj && typeof obj === "object") return obj;
      } catch { /* try next */ }
    }
    return null;
  }

  function sanitizeJsonQuotes(raw) {
    // Replace smart/curly quotes with Chinese quotes (they're unambiguous)
    let s = raw.replace(/[\u201C\u201D]/g, "\u300C").replace(/[\u2018\u2019]/g, "\u300E");
    // For straight double quotes inside string values: walk through and fix
    // This is a best-effort heuristic — not a full JSON parser
    const result = [];
    let inStr = false, escaped = false;
    for (let i = 0; i < s.length; i++) {
      const ch = s[i];
      if (escaped) { result.push(ch); escaped = false; continue; }
      if (ch === "\\") { result.push(ch); escaped = true; continue; }
      if (ch === '"') {
        if (!inStr) { result.push(ch); inStr = true; continue; }
        // We're inside a string and hit a ". Is this the closing quote?
        // Heuristic: closing quote is followed by :, ,, }, ], or whitespace
        const next = s[i + 1];
        if (!next || /[,:}\]\s]/.test(next)) {
          result.push(ch); inStr = false; // legitimate close
        } else {
          result.push("\u300C"); // replace rogue " with「
          // Find the matching close of this rogue quote pair
          const closeIdx = s.indexOf('"', i + 1);
          if (closeIdx > i + 1) {
            const afterClose = s[closeIdx + 1];
            if (afterClose && !/[,:}\]\s]/.test(afterClose)) {
              // The close quote is also rogue, replace it too
              // (handled naturally in the next iteration)
            }
          }
        }
      } else {
        result.push(ch);
      }
    }
    return result.join("");
  }

  function extractFirstJsonObject(text) {
    const s = String(text || "");
    // Fast path: strip a markdown fence and try the whole text directly. LLMs
    // overwhelmingly emit either a clean JSON or a fenced JSON; whole-text
    // lenient parse covers both without scanning brace-by-brace.
    const fastPath = tryParseLenientJson(stripJsonFence(s));
    if (fastPath) return fastPath;

    let i = 0;
    while (i < s.length) {
      while (i < s.length && s[i] !== "{") i++;
      if (i >= s.length) return null;
      const start = i;
      let depth = 0;
      let inString = false;
      let escape = false;
      for (; i < s.length; i++) {
        const ch = s[i];
        if (escape) { escape = false; continue; }
        if (inString) {
          if (ch === "\\") escape = true;
          else if (ch === '"') inString = false;
          continue;
        }
        if (ch === '"') { inString = true; continue; }
        if (ch === "{") depth++;
        else if (ch === "}") {
          depth--;
          if (depth === 0) {
            const candidate = s.slice(start, i + 1);
            const parsed = tryParseLenientJson(candidate);
            if (parsed) return parsed;
            i++; // step past this `}` and look for the next `{`
            break;
          }
        }
      }
      if (depth !== 0) {
        // Unbalanced (likely truncated). Try repair on the slice from start.
        const repaired = tryParseLenientJson(s.slice(start));
        if (repaired) return repaired;
        return null;
      }
    }
    return null;
  }

  function resolveCodexWorkingDir(preferredCwd) {
    if (preferredCwd && fs.existsSync(preferredCwd)) return preferredCwd;
    return process.cwd();
  }

  // JSON Schema for analysis output. When passed to codex via --output-schema,
  // OpenAI's strict mode forces the model to emit exactly this shape and skip
  // unstructured "thinking out loud" — significantly cuts output tokens.
  // NOTE: every nested object must have additionalProperties:false for strict mode.
  const ANALYSIS_OUTPUT_SCHEMA = {
    type: "object",
    additionalProperties: false,
    properties: {
      summary: { type: "string" },
      keyTopics: { type: "array", items: { type: "string" } },
      outcomes: {
        type: "array",
        items: {
          type: "object",
          additionalProperties: false,
          properties: {
            headline: { type: "string" },
            detail: { type: "string" },
          },
          required: ["headline", "detail"],
        },
      },
      timeBreakdown: {
        type: "array",
        items: {
          type: "object",
          additionalProperties: false,
          properties: {
            activity: { type: "string" },
            percent: { type: "number" },
          },
          required: ["activity", "percent"],
        },
      },
      suggestions: { type: "array", items: { type: "string" } },
    },
    required: ["summary", "keyTopics", "outcomes", "timeBreakdown", "suggestions"],
  };

  // Detail-mode variant: STAR structure. situation/task/actions carry S/T/A;
  // R is the existing outcomes array. Strict mode requires every property to
  // be listed in `required`, so this must stay a separate schema — forcing
  // these fields on brief mode would make it emit empty strings for them.
  const ANALYSIS_OUTPUT_SCHEMA_DETAIL = {
    ...ANALYSIS_OUTPUT_SCHEMA,
    properties: {
      ...ANALYSIS_OUTPUT_SCHEMA.properties,
      situation: { type: "string" },
      task: { type: "string" },
      actions: { type: "array", items: { type: "string" } },
    },
    required: [...ANALYSIS_OUTPUT_SCHEMA.required, "situation", "task", "actions"],
  };

  // Knowledge compound output schema — passed to codex via --output-schema so
  // strict mode produces topAssets/unlinkedConnections/behaviorObservation
  // (matches the renderer in analytics.html). Without this, codex returns the
  // session-analysis schema (summary/keyTopics/outcomes) and the renderer is
  // empty.
  const KNOWLEDGE_COMPOUND_OUTPUT_SCHEMA = {
    type: "object",
    additionalProperties: false,
    properties: {
      topAssets: {
        type: "array",
        items: {
          type: "object",
          additionalProperties: false,
          properties: {
            title: { type: "string" },
            sessions: { type: "array", items: { type: "string" } },
            why: { type: "string" },
          },
          required: ["title", "sessions", "why"],
        },
      },
      unlinkedConnections: {
        type: "array",
        items: {
          type: "object",
          additionalProperties: false,
          properties: {
            a: { type: "string" },
            b: { type: "string" },
            insight: { type: "string" },
          },
          required: ["a", "b", "insight"],
        },
      },
      behaviorObservation: { type: "string" },
    },
    required: ["topAssets", "unlinkedConnections", "behaviorObservation"],
  };

  // callCodexCLI(codexPath, prompt, options?)
  //   options.cwd          — working dir for codex
  //   options.outputSchema — override default ANALYSIS_OUTPUT_SCHEMA;
  //                          pass `null` to omit --output-schema entirely.
  async function callCodexCLI(codexPath, prompt, options = {}) {
    const env = await sanitizeCliProxyEnv(buildCliEnv(), "codex");
    return new Promise((resolve, reject) => {
      const fullPrompt = buildInternalCliAnalysisPrompt(prompt);
      const tmpDir = fs.mkdtempSync(path.join(os.tmpdir(), "clawd-codex-"));
      const outputFile = path.join(tmpDir, "last-message.txt");
      const schemaFile = path.join(tmpDir, "output-schema.json");
      // Resolve schema: explicit null = skip; undefined = default; object = use as-is
      const effectiveSchema = options && Object.prototype.hasOwnProperty.call(options, "outputSchema")
        ? options.outputSchema
        : ANALYSIS_OUTPUT_SCHEMA;
      if (effectiveSchema) {
        try { fs.writeFileSync(schemaFile, JSON.stringify(effectiveSchema)); } catch { /* ignore */ }
      }
      // Probe the installed codex once for the long-flags it supports — older
      // codex (≤ 0.117) doesn't recognize --ephemeral or --output-schema and
      // hard-fails with "error: unexpected argument" if we hand it the
      // 0.118+ arg set unconditionally.
      const caps = getCliCapabilities(codexPath, "exec");
      // Phase 0 cost/speed optimization (2026-04-07): force codex into fast
      // analysis mode. Without these, gpt-5.4 with `xhigh` reasoning_effort
      // routinely takes 90+ seconds. With them, the same task finishes in ~10s.
      const args = [
        "exec",
        "--skip-git-repo-check",
        "--json",
      ];
      // codex 0.118+ only — without it codex writes a session file to
      // ~/.codex/sessions/ which is harmless (codex JSONL monitor is fine
      // with extra entries), so degrading silently is acceptable.
      if (caps.has("--ephemeral")) args.push("--ephemeral");
      args.push(
        "--sandbox", "read-only",                // forbid any writes
        "-c", "model_reasoning_effort=low",      // gpt-5.4 default is xhigh — way too deep for analysis
        "-c", "tools.web_search=false",          // also avoids 'minimal' incompat error
      );
      // codex 0.118+ only — without strict schema we rely on the prompt
      // wording + extractFirstJsonObject() fallback to recover usable JSON.
      if (caps.has("--output-schema") && effectiveSchema) args.push("--output-schema", schemaFile);
      args.push(
        "-o", outputFile,
        "-",
      );
      const child = spawnCli(codexPath, args, {
        cwd: resolveCodexWorkingDir(options.cwd),
        env,
        stdio: ["pipe", "pipe", "pipe"],
      });
      const timeoutMs = 90000;
      const maxBytes = 2 * 1024 * 1024;
      let stdout = "";
      let stderr = "";
      let settled = false;

      function cleanup() {
        try { fs.rmSync(tmpDir, { recursive: true, force: true }); } catch { /* ignore */ }
      }

      function fail(message, extra = {}) {
        if (settled) return;
        settled = true;
        cleanup();
        const err = new Error(message);
        Object.assign(err, extra);
        reject(err);
      }

      const timer = setTimeout(() => {
        try { child.kill("SIGTERM"); } catch { /* ignore */ }
        fail(summarizeCodexError(stderr, `codex exec 超时（${Math.round(timeoutMs / 1000)}s）`), { stdout, stderr, timedOut: true });
      }, timeoutMs);

      child.on("error", (err) => {
        clearTimeout(timer);
        fail(err.message, { stdout, stderr });
      });

      child.stdout.on("data", (buf) => {
        stdout += buf.toString();
        if (Buffer.byteLength(stdout, "utf8") > maxBytes) {
          clearTimeout(timer);
          try { child.kill("SIGTERM"); } catch { /* ignore */ }
          fail("Codex CLI 输出过大", { stdout, stderr });
        }
      });

      child.stderr.on("data", (buf) => {
        stderr += buf.toString();
        if (Buffer.byteLength(stderr, "utf8") > maxBytes) {
          stderr = stderr.slice(-maxBytes);
        }
      });

      child.on("close", (code, signal) => {
        if (settled) return;
        clearTimeout(timer);
        let text = fs.existsSync(outputFile) ? fs.readFileSync(outputFile, "utf8") : "";
        if (code === 0) {
          settled = true;
          cleanup();
          // Parse codex 0.118+ JSONL output. Two output schemas exist depending
          // on flags (`exec` vs `exec --json` modes), so we handle both.
          let usage = null;
          let model = null;
          try {
            const lines = stdout.split("\n").filter(Boolean);
            for (const line of lines) {
              try {
                const obj = JSON.parse(line);

                // ── model name (best effort, often missing in exec --json) ──
                // Schema A: codex < 0.118 — wrapped in payload
                if (obj.type === "turn_context" && obj.payload && obj.payload.model) model = obj.payload.model;
                // Schema B: codex 0.118+ — flat top-level model field on turn.started
                if (obj.type === "turn.started" && obj.model) model = obj.model;

                // ── output text fallback (when -o file is empty) ──
                // codex 0.118+ emits `item.completed` for the final agent message
                if (obj.type === "item.completed" && obj.item && obj.item.type === "agent_message" && typeof obj.item.text === "string" && !text) {
                  text = obj.item.text;
                }

                // ── token usage ──
                // Schema A (older): event_msg.token_count.info.total_token_usage
                if (obj.type === "event_msg" && obj.payload && obj.payload.type === "token_count" && obj.payload.info && obj.payload.info.total_token_usage) {
                  const t = obj.payload.info.total_token_usage;
                  usage = {
                    input_tokens: t.input_tokens || 0,
                    cached_input_tokens: t.cached_input_tokens || 0,
                    output_tokens: (t.output_tokens || 0) + (t.reasoning_output_tokens || 0),
                  };
                }
                // Schema B (codex 0.118+): turn.completed.usage (flat)
                if (obj.type === "turn.completed" && obj.usage) {
                  const u = obj.usage;
                  usage = {
                    input_tokens: u.input_tokens || 0,
                    cached_input_tokens: u.cached_input_tokens || 0,
                    output_tokens: (u.output_tokens || 0) + (u.reasoning_output_tokens || 0),
                  };
                }
              } catch { /* skip non-json lines */ }
            }
          } catch { /* ignore parse errors */ }
          return resolve({ text, usage, model, stderr });
        }
        fail(
          summarizeCodexError(stderr, text.trim() || `codex exec 退出异常${code !== null ? `（code ${code}）` : signal ? `（signal ${signal}）` : ""}`),
          { stdout, stderr, code, signal }
        );
      });

      child.stdin.end(fullPrompt);
    });
  }

  // ── Model + pricing detection ──
  //
  // Pricing table (USD per 1M tokens). Update as needed.
  // Prefer "alias" keys (haiku/sonnet/opus/gpt-5/etc) so user-config aliases work.
  // Each entry: { input, cachedInput (cache_read), cacheWrite (cache_creation), output }
  // cacheWrite defaults to 1.25× input (Anthropic 5-min cache); cachedInput defaults to 0.1× input.
  const MODEL_PRICING = {
    // Claude — official Anthropic prices per 1M tokens
    "claude-haiku-4-5": { input: 1.00, cachedInput: 0.10, cacheWrite: 1.25, output: 5.00 },
    "claude-sonnet-4-5": { input: 3.00, cachedInput: 0.30, cacheWrite: 3.75, output: 15.00 },
    "claude-opus-4-6": { input: 15.00, cachedInput: 1.50, cacheWrite: 18.75, output: 75.00 },
    "haiku": { input: 1.00, cachedInput: 0.10, cacheWrite: 1.25, output: 5.00 },
    "sonnet": { input: 3.00, cachedInput: 0.30, cacheWrite: 3.75, output: 15.00 },
    "opus": { input: 15.00, cachedInput: 1.50, cacheWrite: 18.75, output: 75.00 },
    // OpenAI — GPT-5 family per 1M tokens
    "gpt-5": { input: 1.25, cachedInput: 0.13, cacheWrite: 1.25, output: 10.00 },
    "gpt-5-mini": { input: 0.25, cachedInput: 0.025, cacheWrite: 0.25, output: 2.00 },
    "gpt-5.4": { input: 1.25, cachedInput: 0.13, cacheWrite: 1.25, output: 10.00 },
    "gpt-4o": { input: 2.50, cachedInput: 1.25, cacheWrite: 2.50, output: 10.00 },
    "gpt-4o-mini": { input: 0.15, cachedInput: 0.075, cacheWrite: 0.15, output: 0.60 },
  };

  // Resolve a model id (e.g. "claude-haiku-4-5-20251001", "gpt-5.4", "haiku")
  // to a canonical pricing key. Falls back to broad family match.
  function resolvePricingKey(modelId) {
    if (!modelId) return null;
    const m = String(modelId).toLowerCase();
    if (MODEL_PRICING[m]) return m;
    // Strip date suffix on Anthropic models (e.g. claude-haiku-4-5-20251001 → claude-haiku-4-5)
    const stripped = m.replace(/-\d{8}$/, "");
    if (MODEL_PRICING[stripped]) return stripped;
    // Family match
    if (m.includes("haiku")) return "haiku";
    if (m.includes("sonnet")) return "sonnet";
    if (m.includes("opus")) return "opus";
    if (m.includes("gpt-5-mini") || m.includes("gpt-5.4-mini")) return "gpt-5-mini";
    if (m.includes("gpt-5")) return "gpt-5";
    if (m.includes("gpt-4o-mini")) return "gpt-4o-mini";
    if (m.includes("gpt-4o")) return "gpt-4o";
    return null;
  }

  // Compute USD cost from a usage object. Handles both Claude and Codex shapes.
  // usage shape (normalized): { input_tokens, output_tokens, cache_read_input_tokens?, cache_creation_input_tokens?, cached_input_tokens? }
  function estimateCost(usage, modelId) {
    if (!usage) return null;
    const key = resolvePricingKey(modelId);
    if (!key) return null;
    const p = MODEL_PRICING[key];
    const fresh = usage.input_tokens || 0;
    const out = usage.output_tokens || 0;
    const cacheRead = usage.cache_read_input_tokens || usage.cached_input_tokens || 0;
    const cacheWrite = usage.cache_creation_input_tokens || 0;
    const cost =
      (fresh * p.input
        + cacheRead * p.cachedInput
        + cacheWrite * p.cacheWrite
        + out * p.output) / 1_000_000;
    return { usd: cost, pricingKey: key };
  }

  // Get CLI version (cached). `claude --version` / `codex --version`.
  const cliVersionCache = new Map();
  function getCliVersion(binPath) {
    if (!binPath) return null;
    if (cliVersionCache.has(binPath)) return cliVersionCache.get(binPath);
    let version = null;
    try {
      const out = execFileSync(binPath, ["--version"], { encoding: "utf8", timeout: 3000, stdio: ["ignore", "pipe", "pipe"] });
      const m = out.match(/(\d+\.\d+\.\d+(?:[-+][\w.]+)?)/);
      version = m ? m[1] : out.trim().split("\n")[0].slice(0, 50);
    } catch { /* ignore */ }
    cliVersionCache.set(binPath, version);
    return version;
  }

  // Read default model from local CLI config files.
  function getClaudeDefaultModel() {
    try {
      const settingsPath = path.join(os.homedir(), ".claude", "settings.json");
      const text = fs.readFileSync(settingsPath, "utf8");
      const cfg = JSON.parse(text);
      if (cfg && typeof cfg.model === "string") return cfg.model;
    } catch { /* ignore */ }
    return null;
  }

  // tclaude keeps its config in ~/.tclaude/settings.json (same shape as Claude Code).
  function getTclaudeDefaultModel() {
    try {
      const settingsPath = path.join(os.homedir(), ".tclaude", "settings.json");
      const text = fs.readFileSync(settingsPath, "utf8");
      const cfg = JSON.parse(text);
      if (cfg && typeof cfg.model === "string") return cfg.model;
    } catch { /* ignore */ }
    return null;
  }

  function getCodexDefaultModel() {
    try {
      const cfgPath = path.join(os.homedir(), ".codex", "config.toml");
      const text = fs.readFileSync(cfgPath, "utf8");
      // Cheap TOML scrape: first top-level `model = "..."` line
      const m = text.match(/^model\s*=\s*"([^"]+)"/m);
      if (m) return m[1];
    } catch { /* ignore */ }
    return null;
  }

  // Diagnostic helper for the Settings UI: report which CLIs were detected,
  // where they were found, and what search paths were tried for the missing
  // ones. Lets the user see "ah Codex isn't in any of these dirs, I'll point
  // it manually at /Users/me/.fnm/.../bin/codex".
  function getCliDiagnostics() {
    const out = {
      claude: null,
      tclaude: null,
      codex: null,
      searchDirs: [],
      bundleCandidates: [],
      shell: process.env.SHELL || null,
    };
    try { out.searchDirs = getCommonCliSearchDirs(); } catch { }
    // Surface the Codex.app + Cursor/VS Code extension candidates so users
    // can verify Clawd checked the right place. We show all candidates (even
    // non-existent ones) so users on a fresh machine can see the search
    // surface area instead of an empty list.
    try { out.bundleCandidates = getBundledCodexCandidates(); } catch { }

    const claudePath = findClaudeBinary();
    out.claude = {
      found: !!claudePath,
      path: claudePath || null,
      version: claudePath ? getCliVersion(claudePath) : null,
      custom: !!getCustomCliPath("claude"),
      cooldown: getProviderCooldown("claude-code"),
    };

    const tclaudePath = findTclaudeBinary();
    out.tclaude = {
      found: !!tclaudePath,
      path: tclaudePath || null,
      version: tclaudePath ? getCliVersion(tclaudePath) : null,
      custom: !!getCustomCliPath("tclaude"),
      cooldown: getProviderCooldown("tclaude"),
    };

    const codexPath = findCodexBinary();
    out.codex = {
      found: !!codexPath,
      path: codexPath || null,
      version: codexPath ? getCliVersion(codexPath) : null,
      custom: !!getCustomCliPath("codex"),
      cooldown: getProviderCooldown("codex"),
    };

    return out;
  }

  // Test whether a user-supplied path is a valid CLI binary. Used by the
  // Settings UI's "Test" button so users can verify their custom path before
  // saving. Returns { ok, version, error }.
  function testCliPath(rawPath) {
    if (!rawPath || typeof rawPath !== "string") {
      return { ok: false, error: "empty path" };
    }
    const expanded = rawPath.trim().replace(/^~(?=\/)/, os.homedir());
    try {
      if (!fs.existsSync(expanded)) return { ok: false, error: "file not found: " + expanded };
      const version = getCliVersion(expanded);
      if (!version) return { ok: false, error: "binary did not respond to --version" };
      return { ok: true, version, path: expanded };
    } catch (e) {
      return { ok: false, error: e.message || String(e) };
    }
  }

  function getAvailableAnalysisProviders() {
    const options = [];
    const claudePath = findClaudeBinary();
    if (claudePath && !getProviderCooldown("claude-code")) {
      const version = getCliVersion(claudePath);
      const model = getClaudeDefaultModel();
      const pricingKey = resolvePricingKey(model);
      options.push({
        id: "claude-code",
        type: "claude-cli",
        label: "Claude Code",
        path: claudePath,
        version,
        model,
        pricingKey,
      });
    }
    const tclaudePath = findTclaudeBinary();
    if (tclaudePath && !getProviderCooldown("tclaude")) {
      const version = getCliVersion(tclaudePath);
      const model = getTclaudeDefaultModel();
      const pricingKey = resolvePricingKey(model);
      options.push({
        id: "tclaude",
        type: "claude-cli",
        label: "tclaude",
        path: tclaudePath,
        version,
        model,
        pricingKey,
      });
    }
    const codexPath = findCodexBinary();
    if (codexPath && !getProviderCooldown("codex")) {
      const version = getCliVersion(codexPath);
      const model = getCodexDefaultModel();
      const pricingKey = resolvePricingKey(model);
      options.push({
        id: "codex",
        type: "codex-cli",
        label: "Codex",
        path: codexPath,
        version,
        model,
        pricingKey,
      });
    }
    // Custom providers from the registry (added in v2)
    const customProviders = getProviderRegistry();
    for (const p of customProviders) {
      if (!p.enabled) continue;
      // Only skip if the exact same UUID id is already listed (avoid true duplicates).
      // Don't filter by type — multiple custom providers can share the same type (e.g. openai).
      const alreadyListed = options.some((o) => o.id === p.id);
      if (alreadyListed) continue;
      options.push({
        id: p.id,
        type: "api-custom",
        provider: p.type,
        label: p.name,
        model: p.model,
        baseUrl: p.baseUrl,
        pricingKey: resolvePricingKey(p.model),
      });
    }
    return options;
  }

  // ── Session-level AI analysis ──

  // v3: prompt rewrite — plain-spoken tone (no forced warmth/exclamations),
  // natural-phrase headlines instead of forced 3-4 char verb-object compounds
  // v4: summary covers the main thread only (side work goes to outcomes) and
  // must be fluent prose — hard length caps were producing telegraphic Chinese
  // v5: detail mode is STAR-structured (situation/task/actions + outcomes as R)
  // v6: fluency — every clause needs an explicit subject; no coined verb
  // abbreviations (补同步/漏跑-style); cause/process details belong to
  // situation/actions, not the summary
  // 2026-07: static-first prompt reorder (rules before context) for prompt-
  // cache prefix reuse — output contract unchanged, so no version bump.
  // v7: brief mode rewrite — subject is the work itself (no '对话确认了…'
  // meta-narration), no vague filler verbs (梳理/沉淀), headlines read like
  // speech instead of stacked-nominal report style (工期风险重新校准)
  const ANALYSIS_CACHE_VERSION = 7;
  const sessionAnalysisCache = new Map(); // `${sessionId}:${provider}` → result

  function analysisCacheKey(sessionId, provider) {
    return `${sessionId}:${provider || "claude-code"}`;
  }

  function isTransientAnalysisFailure(result) {
    const summary = result && typeof result.summary === "string" ? result.summary : "";
    if (!summary) return false;
    return (
      summary.includes("执行失败:") ||
      summary.startsWith("分析失败:") ||
      summary.includes("未找到本地 CLI") ||
      summary.includes("未配置 API Key") ||
      summary.includes("Codex CLI 未找到") ||
      summary.includes("无法连接本地代理") ||
      summary.includes("网络初始化失败")
    );
  }

  function maybeCacheAnalysisResult(cacheKey, result) {
    if (!result) return result;
    result._analysisCacheVersion = ANALYSIS_CACHE_VERSION;
    result._cacheable = !isTransientAnalysisFailure(result);
    if (result._cacheable) sessionAnalysisCache.set(cacheKey, result);
    else sessionAnalysisCache.delete(cacheKey);
    // Persist cacheable results to disk so daily reflection can read them after restart
    if (result._cacheable) _persistAnalysisResult(cacheKey, result);
    return result;
  }

  // ── Disk persistence for daily reflection ──

  let _diskCacheDebounce = null;

  function _persistAnalysisResult(cacheKey, result) {
    // Debounce writes — multiple analyses may run in quick succession (batch mode)
    if (_diskCacheDebounce) clearTimeout(_diskCacheDebounce);
    _diskCacheDebounce = setTimeout(() => {
      _diskCacheDebounce = null;
      try {
        const dir = path.dirname(analysisCachePath);
        if (!fs.existsSync(dir)) fs.mkdirSync(dir, { recursive: true });
        let cache = {};
        try { cache = JSON.parse(fs.readFileSync(analysisCachePath, "utf8")); } catch { /* fresh */ }
        if (!cache.sessions) cache.sessions = {};
        // Strip internal fields, keep only what daily reflection needs
        const slim = {
          summary: result.summary || "",
          situation: result.situation || "",
          task: result.task || "",
          actions: result.actions || [],
          keyTopics: result.keyTopics || [],
          outcomes: result.outcomes || [],
          timeBreakdown: result.timeBreakdown || [],
          suggestions: result.suggestions || [],
          _mode: result._mode || "brief",
          _provider: result._provider || "",
          _ts: Date.now(),
        };
        cache.sessions[cacheKey] = slim;
        // Prune entries older than 7 days to prevent unbounded growth
        const cutoff = Date.now() - 7 * 24 * 60 * 60 * 1000;
        for (const [k, v] of Object.entries(cache.sessions)) {
          if (v._ts && v._ts < cutoff) delete cache.sessions[k];
        }
        fs.writeFileSync(analysisCachePath, JSON.stringify(cache));
      } catch (err) {
        console.warn("Clawd: failed to persist analysis cache:", err.message);
      }
    }, 500);
  }

  function loadPersistedAnalyses(startTs, endTs) {
    try {
      if (!fs.existsSync(analysisCachePath)) return [];
      const cache = JSON.parse(fs.readFileSync(analysisCachePath, "utf8"));
      if (!cache.sessions) return [];
      const results = [];
      for (const [key, entry] of Object.entries(cache.sessions)) {
        if (entry._ts && entry._ts >= startTs && entry._ts < endTs) {
          results.push({ cacheKey: key, ...entry });
        }
      }
      return results;
    } catch { return []; }
  }

  function clearAnalysisCaches() {
    sessionAnalysisCache.clear();
    onelinerCache.clear();
    return { ok: true };
  }

  // ── Brief mode prompt (default: concise, plain-spoken) ──
  // Prompt layout: ALL static text (instructions + JSON format + rules) comes
  // first, the per-session context goes last. Backends with prefix-based
  // prompt caching (Ollama KV reuse, OpenAI-compat auto caching) can then
  // share the whole static block across sessions; with context in the middle
  // the common prefix ended after two lines.
  function buildSessionBriefPrompt(detail) {
    let p = "你是用户的编程搭档。下面会给出用户与 AI agent 的对话摘要。\n";
    p += "请用平实的中文总结这段对话：用户做了什么，结果如何。\n\n";
    p += "请返回 JSON（不要 markdown code block），格式：\n";
    p += '{"summary":"1 句话：做了什么+结果如何"';
    p += ',"keyTopics":["话题1","话题2"]';
    p += ',"outcomes":[{"headline":"成果短语","detail":"一句话具体说明"}]}\n';
    p += "要求：\n";
    p += "- summary：≤ 40 字，写给没看过这段对话的同事：点名具体对象（哪个项目/脚本/问题），说清它最后的状态。先说准，再求短；多件事只说主线，次要的放 outcomes，不要塞成一句。\n";
    p += "- 主语写事情本身，不要写'对话''本次会话'：写'确认了中继应在远端启动'，不要写'对话确认了中继应在远端启动'。\n";
    p += "- 句子要通顺：分句有主语、保留'把、到、的、了'这类虚词；不生造缩略动词（'补同步'）；不用'梳理''沉淀''完善'这类空泛动词——说不出具体干了什么，就删掉这半句。\n";
    p += "- 禁止：感叹号；'搞定了''辛苦了'这类寒暄；比喻和俏皮话。宁可平淡，不要俏皮。\n";
    p += "  例：写'每日 review 自动同步到 GitHub，不再因电脑重启中断'，不要写'搞定了！合盖也不怕断更了'。\n";
    p += "- keyTopics：2-3 个，每个 ≤ 8 字。\n";
    p += "- outcomes：最多 2 条。headline ≤ 10 字，像平常说话（'权重传完了''排期重排了'），不要报告腔的名词堆叠（'工期风险重新校准''方法沉淀复用'），不加标点；detail 一句话，带上具体名称或数字。\n";
    p += "- 所有字段用中文。不要返回 suggestions 和 timeBreakdown。\n";
    p += "- **重要**：JSON 字符串值里不要出现未转义的双引号。引用名称请用「」或『』代替双引号。\n\n";
    p += "## 对话摘要\n\n";
    p += buildSessionContext(detail);
    p += "\n（请按上面给定的 JSON 格式输出）";
    return p;
  }

  // ── Detail mode prompt (full analysis, STAR-structured) ──
  // Same static-first layout as buildSessionBriefPrompt — see comment there.
  function buildSessionDetailPrompt(detail) {
    let p = "你是一个对话分析助手。下面会给出用户与 AI 编程 agent 的对话记录摘要。\n";
    p += "请从**用户视角**按 STAR 梳理这次会话：背景（situation）、目标（task）、做法（actions）、结果（outcomes），以及时间花在哪里。\n";
    p += "不要描述 agent 的工作流程，而是关注用户的意图和收获。\n\n";
    p += "请返回 JSON（不要 markdown code block），格式：\n";
    p += '{"summary":"≤60字概括主线成果"';
    p += ',"situation":"背景","task":"目标"';
    p += ',"actions":["关键动作或决策"]';
    p += ',"keyTopics":["话题1","话题2","话题3"]';
    p += ',"outcomes":[{"headline":"成果短语","detail":"展开说明关键认知"}]';
    p += ',"timeBreakdown":[{"activity":"活动描述","percent":百分比}]';
    p += ',"suggestions":["建议"]}\n';
    p += "要求：\n";
    p += "- summary：≤ 60 字，说清'做了什么 + 结果如何'。多件事只讲主线的一两件（次要的交给 outcomes），原因和过程细节交给 situation 和 actions，不要都挤进 summary。可以用分号拆成两个短句。\n";
    p += "- summary 必须是通顺的白话句子：每个分句都有明确的主语，保留'把、到、的、了'这类虚词，动词带完整宾语——写'电脑睡眠后 cron 没有执行'，不要写'合盖睡眠导致 cron 漏跑'。\n";
    p += "- 所有字段都不要生造缩略动词，用常规说法：'补齐了缺失内容'而非'补同步'，'同步中断'而非'断更'，'改用 launchd'而非'迁 launchd'。字数不够就少讲一件事，不要靠造词压缩。\n";
    p += "- situation（S 背景）：≤ 40 字，说清为什么做这件事——用户当时面对的问题或状态。\n";
    p += "- task（T 目标）：≤ 30 字，用户这次想达成什么。不要和 situation 重复。\n";
    p += "- actions（A 做法）：2-4 条，按先后顺序写关键动作和决策，中途的改道要点出来（如'发现 cron 合盖后不执行，改用 launchd'）；每条 ≤ 25 字，写通顺短句，不要电报体。\n";
    p += "- outcomes（R 结果）：3-5 条。headline 是概括该成果的自然短语（≤ 10 字，如'权限弹窗去重''同步任务上线'），不加标点，不要千篇一律压成三字动宾词；detail 一句话展开关键认知。\n";
    p += "- keyTopics：3-5 个关键话题，每个 ≤ 10 字。\n";
    p += "- timeBreakdown：3-5 条，从用户视角描述时间分配（'讨论架构设计'而非'调用 Read 工具'）。\n";
    p += "- suggestions：1-2 条简短实用的建议。做得好可以返回空数组。\n";
    p += "- 语言平实准确，不用感叹号、寒暄语和比喻；宁可平淡，不要俏皮。\n";
    p += "- 所有字段用中文。确保 JSON 完整闭合。\n";
    p += "- **重要**：JSON 字符串值里不要出现未转义的双引号。引用名称请用「」或『』代替双引号。\n\n";
    p += "## 对话记录摘要\n\n";
    p += buildSessionContext(detail);
    p += "\n（请按上面给定的 JSON 格式输出）";
    return p;
  }

  // Append-mode system prompt that nudges Claude Code into pure-analysis mode
  // WITHOUT replacing the default system prompt entirely (which would kill the
  // ~6K cache_read benefit). Combined with --tools "" + --disable-slash-commands,
  // this is the winning Phase 0 configuration.
  //
  // Real benchmark vs default `-p` (haiku-4-5, identical user prompt, warm cache):
  //   baseline:   $0.01076 / 14.2s / 1513 out / 31,879 cache_read
  //   optimized:  $0.00640 / 12.2s / 1146 out /  6,622 cache_read
  //   savings:    -40% cost, -14% duration, -24% output tokens
  //
  // Why each flag matters:
  //   --verbose              → REQUIRED on Claude CLI 2.2+ when combining
  //                            -p / --print with --output-format=stream-json.
  //                            Older versions (≤2.1.x) implicitly enabled it,
  //                            newer versions hard-error without it:
  //                            "Error: When using --print, --output-format=
  //                            stream-json requires --verbose". The flag does
  //                            not change the NDJSON shape we already parse —
  //                            metadata events (system/init, hook_*, rate_limit_event)
  //                            were already streamed in 2.1.x and are skipped
  //                            by our parser's type-switch.
  //   --append-system-prompt → tells the model "no tools, JSON only" while
  //                            keeping the default system prompt cacheable
  //   --tools ""             → drops 25K of tool definitions from the prompt
  //   --disable-slash-commands → drops the skill registry (lark-* etc)
  const ANALYSIS_APPEND_SYSTEM_PROMPT =
    "IMPORTANT: For this conversation only — you are operating in pure analysis mode. " +
    "Do NOT use any tool, do NOT investigate, do NOT search files. " +
    "The user message contains all the data you need. " +
    "Respond with ONLY the requested JSON object, no markdown fences, no preamble.";

  function callClaudeCLI(claudePath, prompt) {
    return new Promise((resolve, reject) => {
      const fullPrompt = buildInternalCliAnalysisPrompt(prompt);
      // On Windows, spawning the .cmd shim requires shell:true, which routes
      // through cmd.exe. cmd.exe truncates multi-line args at the first
      // newline (our analysis prompt has 20+ lines), so Claude only sees the
      // internal marker and replies "What would you like me to do?". Pipe the
      // prompt via stdin to bypass the cmd.exe parser entirely. Other
      // platforms keep the -p path (no shell, no truncation, and stdin-based
      // invocation has subtly different behavior with some CLI versions).
      const viaStdin = isWindowsShellShim(claudePath);
      const args = [
        "-p", ...(viaStdin ? [""] : [fullPrompt]),
        "--output-format", "stream-json",
        "--verbose",                                            // required by Claude CLI 2.2+ with -p + stream-json
        "--tools", "",                                          // disable all built-in tools (-25K tokens)
        "--disable-slash-commands",                             // skip skill loading
        "--append-system-prompt", ANALYSIS_APPEND_SYSTEM_PROMPT, // nudge to JSON-only mode
      ];
      const child = spawnCli(claudePath, args, {
        env: buildCliEnv({ CLAUDE_CODE_ENTRYPOINT: "cli" }),
        stdio: [viaStdin ? "pipe" : "ignore", "pipe", "pipe"],
      });
      const timeoutMs = 90000;
      const maxBytes = 2 * 1024 * 1024;
      let stdout = "";
      let stderr = "";
      let settled = false;

      function fail(message, extra = {}) {
        if (settled) return;
        settled = true;
        const err = new Error(message);
        Object.assign(err, extra);
        reject(err);
      }

      const timer = setTimeout(() => {
        try { child.kill("SIGTERM"); } catch { /* ignore */ }
        fail(
          summarizeClaudeError(stdout, stderr, `claude exec 超时（${Math.round(timeoutMs / 1000)}s）`),
          { stdout, stderr, timedOut: true }
        );
      }, timeoutMs);

      child.on("error", (err) => {
        clearTimeout(timer);
        fail(err.message, { stdout, stderr });
      });

      child.stdout.on("data", (buf) => {
        stdout += buf.toString();
        if (Buffer.byteLength(stdout, "utf8") > maxBytes) {
          clearTimeout(timer);
          try { child.kill("SIGTERM"); } catch { /* ignore */ }
          fail("Claude CLI 输出过大", { stdout, stderr });
        }
      });

      child.stderr.on("data", (buf) => {
        stderr += buf.toString();
        if (Buffer.byteLength(stderr, "utf8") > maxBytes) {
          stderr = stderr.slice(-maxBytes);
        }
      });

      child.on("close", (code, signal) => {
        if (settled) return;
        clearTimeout(timer);
        if (code !== 0) {
          const fallbackMsg = `claude exec 退出异常${code !== null ? `（code ${code}）` : signal ? `（signal ${signal}）` : ""}`;
          return fail(
            summarizeClaudeError(stdout, stderr, fallbackMsg),
            { stdout, stderr, code, signal }
          );
        }

        // stream-json outputs one JSON object per line (NDJSON)
        // The last "result" message contains the text and usage
        let text = "";
        let usage = null;
        let model = null;
        let costUsd = null;
        try {
          const lines = stdout.split("\n").filter(Boolean);
          for (const line of lines) {
            try {
              const obj = JSON.parse(line);
              if (obj.type === "result") {
                text = obj.result || "";
                if (typeof obj.total_cost_usd === "number") costUsd = obj.total_cost_usd;
                if (obj.usage) usage = { ...(usage || {}), ...obj.usage };
              } else if (obj.type === "assistant" && obj.message) {
                const content = obj.message.content;
                if (Array.isArray(content)) {
                  for (const c of content) {
                    if (c.type === "text") text = c.text;
                  }
                }
                if (obj.message.model) model = obj.message.model;
                if (obj.message.usage) usage = obj.message.usage;
              }
            } catch { /* skip unparseable lines */ }
          }
        } catch {
          text = stdout;
        }
        if (!text) text = stdout;
        settled = true;
        resolve({ text, usage, model, costUsd });
      });

      if (viaStdin) {
        child.stdin.on("error", (err) => fail(`claude stdin error: ${err.message}`, { stdout, stderr }));
        try {
          child.stdin.end(fullPrompt);
        } catch (err) {
          fail(`claude stdin write failed: ${err.message}`, { stdout, stderr });
        }
      }
    });
  }

  async function analyzeSession(detail, mode) {
    // Wrapper: guarantee _mode is on every result, regardless of which code path produced it
    const result = await _analyzeSessionImpl(detail, mode);
    if (result && typeof result === "object") result._mode = mode || "brief";
    return result;
  }

  async function _analyzeSessionImpl(detail, mode) {
    if (!detail) return null;
    const analysisMode = mode || "brief";
    const preferredProvider = detail._preferredProvider || "claude-code";
    const analysisSubjectId = detail.analysisId || detail.sessionId;

    // Check cache — invalidate if message count or provider changed
    const cacheKey = analysisCacheKey(analysisSubjectId, preferredProvider) + ":" + analysisMode;
    if (sessionAnalysisCache.has(cacheKey)) {
      const cached = sessionAnalysisCache.get(cacheKey);
      if (
        cached._analysisCacheVersion === ANALYSIS_CACHE_VERSION &&
        cached._msgCount === getDetailContextEntryCount(detail)
      ) {
        return cached;
      }
      // Content changed — re-analyze
      console.log(`Clawd analytics: session ${cacheKey} grew (${cached._msgCount} → ${getDetailContextEntryCount(detail)} entries), re-analyzing`);
      sessionAnalysisCache.delete(cacheKey);
    }

    const startTime = Date.now();
    const prompt = analysisMode === "detail" ? buildSessionDetailPrompt(detail) : buildSessionBriefPrompt(detail);
    let cliError = null;

    // Pick CLI binary based on preference — no auto-fallback
    let cliPath = null, cliName = null, callFn = null, cliProviderId = null;
    let forcedApiProvider = null;
    if (preferredProvider === "codex") {
      cliProviderId = "codex";
      cliPath = findCodexBinary();
      cliName = "codex";
      callFn = callCodexCLI;
      const cooldown = getProviderCooldown(cliProviderId);
      if (cooldown) {
        cliError = cooldown.reason;
        if (!loggedProviderCooldowns.has(cliProviderId)) {
          loggedProviderCooldowns.add(cliProviderId);
          console.warn(`Clawd analytics: ${cliProviderId} temporarily disabled:`, cooldown.reason);
        }
        cliPath = null;
        callFn = null;
      }
      if (!cliPath) {
        if (!cliError) {
          return maybeCacheAnalysisResult(cacheKey, {
            summary: "Codex CLI 未找到。请确认已安装 codex（npm install -g @openai/codex）。",
            keyTopics: [],
            outcomes: [],
            timeBreakdown: [],
            suggestions: [],
            _provider: "codex-not-found",
          });
        }
      }
    } else if (preferredProvider === "claude-code") {
      cliProviderId = "claude-code";
      cliPath = findClaudeBinary();
      cliName = "claude-cli";
      callFn = callClaudeCLI;
      const cooldown = getProviderCooldown(cliProviderId);
      if (cooldown) {
        cliError = cooldown.reason;
        if (!loggedProviderCooldowns.has(cliProviderId)) {
          loggedProviderCooldowns.add(cliProviderId);
          console.warn(`Clawd analytics: ${cliProviderId} temporarily disabled:`, cooldown.reason);
        }
        cliPath = null;
        callFn = null;
      }
    } else if (preferredProvider === "tclaude") {
      // tclaude speaks the same CLI protocol as Claude Code — reuse callClaudeCLI.
      cliProviderId = "tclaude";
      cliPath = findTclaudeBinary();
      cliName = "tclaude-cli";
      callFn = callClaudeCLI;
      const cooldown = getProviderCooldown(cliProviderId);
      if (cooldown) {
        cliError = cooldown.reason;
        if (!loggedProviderCooldowns.has(cliProviderId)) {
          loggedProviderCooldowns.add(cliProviderId);
          console.warn(`Clawd analytics: ${cliProviderId} temporarily disabled:`, cooldown.reason);
        }
        cliPath = null;
        callFn = null;
      }
      if (!cliPath && !cliError) {
        return maybeCacheAnalysisResult(cacheKey, {
          summary: "tclaude CLI 未找到。请确认已安装 tclaude，或在设置中手动指定其可执行路径。",
          keyTopics: [],
          outcomes: [],
          timeBreakdown: [],
          suggestions: [],
          _provider: "tclaude-not-found",
        });
      }
    } else if (preferredProvider.startsWith("api:")) {
      forcedApiProvider = preferredProvider.slice(4);
    } else {
      cliProviderId = "claude-code";
      cliPath = findClaudeBinary();
      cliName = "claude-cli";
      callFn = callClaudeCLI;
    }
    if (cliPath && cliName) {
      const logKey = `${cliName}:${cliPath}`;
      if (!loggedCliBinaries.has(logKey)) {
        loggedCliBinaries.add(logKey);
        console.log(`Clawd analytics: using ${cliName} binary =`, cliPath);
      }
    }

    if (cliPath && callFn) {
      try {
        // Detail mode carries the STAR fields — codex strict mode needs the
        // matching schema or it would reject/drop them (callClaudeCLI ignores
        // the extra option).
        const cliResult = await callFn(cliPath, prompt, analysisMode === "detail"
          ? { cwd: detail.cwd, outputSchema: ANALYSIS_OUTPUT_SCHEMA_DETAIL }
          : { cwd: detail.cwd });
        const text = cliResult.text;
        const usage = cliResult.usage;
        // Resolve model: prefer runtime (from jsonl events), fall back to
        // configured default (~/.claude/settings.json or ~/.codex/config.toml).
        // Without this fallback, codex 0.117 and earlier (no turn_context.model)
        // would lose cost display entirely.
        let runtimeModel = cliResult.model || null;
        if (!runtimeModel) {
          if (cliProviderId === "codex") runtimeModel = getCodexDefaultModel();
          else if (cliProviderId === "claude-code") runtimeModel = getClaudeDefaultModel();
          else if (cliProviderId === "tclaude") runtimeModel = getTclaudeDefaultModel();
        }
        const runtimeCostUsd = typeof cliResult.costUsd === "number" ? cliResult.costUsd : null;
        // Compute estimated cost: prefer CLI-provided cost, else use pricing table
        let estCost = null;
        if (runtimeCostUsd !== null) {
          estCost = { usd: runtimeCostUsd, source: "cli" };
        } else if (usage) {
          const c = estimateCost(usage, runtimeModel);
          if (c) estCost = { usd: c.usd, source: "estimate", pricingKey: c.pricingKey };
        }

        const attachMeta = (obj) => {
          if (usage) obj._usage = usage;
          if (runtimeModel) obj._model = runtimeModel;
          if (estCost) obj._cost = estCost;
          obj._provider = cliName;
          obj._msgCount = getDetailContextEntryCount(detail);
          obj._analysisMs = Date.now() - startTime;
          obj._mode = analysisMode;
          return obj;
        };
        if (text) {
          // Try to extract a usable JSON object. extractFirstJsonObject() is
          // now lenient — fence-strip, trailing-comma fix, newline escape,
          // truncation repair, smart-quote sanitization. Each candidate goes
          // through the whole chain before we give up.
          const parsed = extractFirstJsonObject(text);
          if (parsed) {
            const result = attachMeta(parsed);
            return maybeCacheAnalysisResult(cacheKey, result);
          }
          // Salvage attempt failed. Classify the failure so we don't pollute
          // the cache with garbage and so the user gets actionable feedback.
          const trimmed = text.trim();
          const preview = trimmed.slice(0, 120).replace(/\s+/g, " ");
          const isShort = trimmed.length < 30;
          const hasBrace = trimmed.includes("{");
          let summary;
          let transient = true;
          if (isShort) {
            // Common cause: CLI bailed early ("Sorry, I cannot..." / blank).
            console.warn(`Clawd analytics: ${cliName} returned ${trimmed.length} chars (likely failure). preview: ${JSON.stringify(preview)}`);
            summary = `分析失败: ${cliName} 只返回了 ${trimmed.length} 个字符，请重试。`;
          } else if (!hasBrace) {
            // Model emitted plain prose instead of JSON. Surface it but mark
            // as transient so a retry can get a structured response.
            console.warn(`Clawd analytics: ${cliName} returned plain text (${trimmed.length} chars), no JSON detected. preview: ${JSON.stringify(preview)}`);
            summary = `分析失败: ${cliName} 返回了纯文本而非 JSON，请重试。原文：${trimmed.slice(0, 200)}`;
          } else {
            // Looked JSON-shaped but couldn't be salvaged. Cache OK to spare
            // re-spawn cost — likely a stable model quirk for this conversation.
            console.warn(`Clawd analytics: ${cliName} returned unparseable JSON (${trimmed.length} chars). preview: ${JSON.stringify(preview)}`);
            summary = trimmed.slice(0, 300);
            transient = false;
          }
          const fallback = attachMeta({ summary, keyTopics: [], outcomes: [], timeBreakdown: [], suggestions: [] });
          if (transient) {
            // Force-skip cache so the next click retries.
            fallback._cacheable = false;
            return fallback;
          }
          return maybeCacheAnalysisResult(cacheKey, fallback);
        }
      } catch (err) {
        cliError = friendlyCliError(cliName, err.message);
        console.warn(`Clawd analytics: ${cliName} failed:`, cliError);
        if (cliProviderId && isLikelyCliNetworkFailure(err.message)) {
          disableProviderTemporarily(cliProviderId, cliError);
          loggedProviderCooldowns.delete(cliProviderId);
        }
        // Fall through to API providers
      }
    }

    // Fallback to configured API provider
    const cfg = getConfig();
    // Check if preferredProvider is a custom registry provider UUID
    const customProvider = getProvider(preferredProvider);
    if (customProvider && !forcedApiProvider) {
      try {
        let text;
        if (customProvider.type === "claude") {
          text = await callClaude(customProvider.apiKey, customProvider.model, prompt, 500, customProvider.baseUrl);
        } else if (customProvider.type === "ollama") {
          text = await callOllama(customProvider.model, prompt, customProvider.baseUrl);
        } else {
          text = await callOpenAICompat(customProvider.apiKey, customProvider.model, prompt, customProvider.baseUrl);
        }
        if (!text) return null;
        const result = extractFirstJsonObject(text);
        if (!result) {
          const fallback = { summary: text.slice(0, 300), timeBreakdown: [], insights: [], suggestions: [], _msgCount: getDetailContextEntryCount(detail), _analysisMs: Date.now() - startTime };
          return maybeCacheAnalysisResult(cacheKey, fallback);
        }
        result._msgCount = getDetailContextEntryCount(detail);
        result._analysisMs = Date.now() - startTime;
        result._provider = customProvider.name;
        result._model = customProvider.model;
        return maybeCacheAnalysisResult(cacheKey, result);
      } catch (err) {
        return maybeCacheAnalysisResult(cacheKey, { summary: `分析失败 (${customProvider.name}): ${err.message}`, timeBreakdown: [], insights: [], suggestions: [] });
      }
    }

    const provider = forcedApiProvider || (cfg && cfg.provider) || "claude";
    const providerDef = PROVIDERS[provider];
    const apiKey = cfg && cfg.apiKey;

    if (providerDef && providerDef.needsKey && !apiKey) {
      const msg = forcedApiProvider
        ? `${providerDef.label} 未配置 API Key。请先在设置中配置后再分析。`
        : cliPath
          ? `${cliName} 执行失败: ${cliError || "unknown error"}。可配置 API Key 作为备选。`
          : cliError
            ? `${cliError} 可配置 API Key 作为备选。`
            : "未找到本地 CLI，且未配置 API Key。请安装 Claude Code 或配置 API Key。";
      return maybeCacheAnalysisResult(cacheKey, { summary: msg, keyTopics: [], outcomes: [], timeBreakdown: [], suggestions: [], _provider: cliName || provider });
    }

    try {
      const model = (cfg && cfg.model) || (providerDef && providerDef.defaultModel);
      const baseUrl = (cfg && cfg.baseUrl) || (providerDef && providerDef.baseUrl);
      let text;
      if (provider === "claude") {
        text = await callClaude(apiKey, model, prompt);
      } else if (provider === "ollama") {
        text = await callOllama(model, prompt, baseUrl);
      } else {
        text = await callOpenAICompat(apiKey, model, prompt, baseUrl);
      }

      if (!text) return null;
      // Use balanced-brace extractor; falls back to text summary on parse failure
      // instead of throwing into the outer catch (which would otherwise hide the
      // real reason behind a generic "分析失败" message).
      const result = extractFirstJsonObject(text);
      if (!result) {
        const fallback = { summary: text.slice(0, 300), timeBreakdown: [], insights: [], suggestions: [], _msgCount: getDetailContextEntryCount(detail), _analysisMs: Date.now() - startTime };
        return maybeCacheAnalysisResult(cacheKey, fallback);
      }
      result._msgCount = getDetailContextEntryCount(detail);
      result._analysisMs = Date.now() - startTime;
      return maybeCacheAnalysisResult(cacheKey, result);
    } catch (err) {
      return maybeCacheAnalysisResult(cacheKey, { summary: `分析失败: ${err.message}`, timeBreakdown: [], insights: [], suggestions: [] });
    }
  }

  function getAnalysisProvider() {
    return resolvePreferredAnalysisProvider(getAvailableAnalysisProviders(), getConfig());
  }

  // ── One-liner summaries (lightweight, for event cards) ──

  const onelinerCache = new Map();

  // Per-message char cap for one-liner context. Scan already caps messages at
  // 400 chars for full analysis; a topic one-liner needs far less, and in
  // batch mode this cap directly bounds the merged prompt size.
  const ONELINER_MSG_CAP = 160;

  function buildOnelinerSnippet(detail) {
    return ((detail.conversation && detail.conversation.length)
      ? detail.conversation.slice(0, 6).map(m => (m && m.text ? `${m.role === "assistant" ? "助手" : "用户"}: ${String(m.text).slice(0, ONELINER_MSG_CAP)}` : ""))
      : (detail.userMessages || []).slice(0, 5).map(m => String((m && m.text) || "").slice(0, ONELINER_MSG_CAP)))
      .filter(Boolean)
      .join("\n");
  }

  function cleanOnelinerText(text) {
    return String(text || "").trim().split("\n")[0].replace(/^["'""'']|["'""'']$/g, "").trim();
  }

  // Shared provider chain for one-liner prompts: local Claude CLI first, then
  // the "brief" registry provider, then legacy config fields. Returns the raw
  // response text, or null when no backend is available / every one failed.
  async function callOnelinerBackend(prompt, maxTokens = 500) {
    const claudePath = findClaudeBinary();
    if (claudePath) {
      try {
        const { text } = await callClaudeCLI(claudePath, prompt);
        if (text) return text;
      } catch { /* fall through */ }
    }

    // Fallback to API — registry-first, then legacy fields
    const registryProvider = getProvider(getDefaultProvider("brief"));
    if (registryProvider) {
      try {
        let text;
        if (registryProvider.type === "claude") {
          text = await callClaude(registryProvider.apiKey, registryProvider.model, prompt, maxTokens, registryProvider.baseUrl);
        } else if (registryProvider.type === "ollama") {
          text = await callOllama(registryProvider.model, prompt, registryProvider.baseUrl);
        } else {
          text = await callOpenAICompat(registryProvider.apiKey, registryProvider.model, prompt, registryProvider.baseUrl, maxTokens);
        }
        if (text) return text;
      } catch { /* fall through to legacy */ }
    }

    // Legacy fallback (for users not yet on v3 or with no registry provider)
    const cfg = getConfig();
    const provider = (cfg && cfg.provider) || "claude";
    const apiKey = cfg && cfg.apiKey;
    if (!apiKey && PROVIDERS[provider] && PROVIDERS[provider].needsKey) return null;
    try {
      const model = (cfg && cfg.model) || PROVIDERS[provider].defaultModel;
      const baseUrl = (cfg && cfg.baseUrl) || PROVIDERS[provider].baseUrl;
      if (provider === "claude") return await callClaude(apiKey, model, prompt, maxTokens);
      if (provider === "ollama") return await callOllama(model, prompt, baseUrl);
      return await callOpenAICompat(apiKey, model, prompt, baseUrl, maxTokens);
    } catch { return null; }
  }

  async function getSessionOneLiner(detail) {
    if (!detail) return null;
    if (onelinerCache.has(detail.sessionId)) return onelinerCache.get(detail.sessionId);
    const msgs = buildOnelinerSnippet(detail);
    if (!msgs) return null;
    const prompt = `用一句中文（15-25字）概括以下对话的主题，不要加标点符号结尾：\n${msgs}`;
    const line = cleanOnelinerText(await callOnelinerBackend(prompt));
    if (line) { onelinerCache.set(detail.sessionId, line); return line; }
    return null;
  }

  // Batched one-liners: one provider call covers up to ONELINER_BATCH_SIZE
  // sessions (numbered snippets in, numbered JSON out) instead of one CLI
  // spawn per session — spawn + handshake dominates each call, so N sessions
  // collapse from N calls to ceil(N/batch). Chunks run sequentially, so chunk
  // 2+ also reads the prompt cache entry chunk 1 just wrote.
  const ONELINER_BATCH_SIZE = 10;

  function buildOnelinerBatchPrompt(chunk) {
    // Static-first layout (rules before content) — same prefix-cache
    // rationale as buildSessionBriefPrompt.
    let p = "下面会给出多段用户与 AI agent 的对话片段，每段有一个编号。\n";
    p += "请为每一段对话分别用一句中文（15-25字）概括主题，句末不要加标点符号。\n\n";
    p += "请返回 JSON（不要 markdown code block），格式：\n";
    p += '{"1":"第一段的概括","2":"第二段的概括"}\n';
    p += "要求：\n";
    p += "- 键是对话编号，每个编号都要有对应的概括，不要遗漏、不要合并。\n";
    p += "- **重要**：JSON 字符串值里不要出现未转义的双引号。引用名称请用「」或『』代替双引号。\n";
    for (let i = 0; i < chunk.length; i++) {
      p += `\n### 对话 ${i + 1}\n${chunk[i].snippet}\n`;
    }
    p += "\n（请按上面给定的 JSON 格式输出）";
    return p;
  }

  async function getSessionOneLiners(details) {
    const results = {};
    const misses = [];
    for (const detail of Array.isArray(details) ? details : []) {
      if (!detail || !detail.sessionId) continue;
      if (onelinerCache.has(detail.sessionId)) {
        results[detail.sessionId] = onelinerCache.get(detail.sessionId);
        continue;
      }
      const snippet = buildOnelinerSnippet(detail);
      if (!snippet) { results[detail.sessionId] = null; continue; }
      misses.push({ sessionId: detail.sessionId, snippet });
    }

    for (let start = 0; start < misses.length; start += ONELINER_BATCH_SIZE) {
      const chunk = misses.slice(start, start + ONELINER_BATCH_SIZE);
      const text = await callOnelinerBackend(buildOnelinerBatchPrompt(chunk), Math.max(500, 80 * chunk.length));
      const parsed = text ? extractFirstJsonObject(text) : null;
      for (let i = 0; i < chunk.length; i++) {
        const raw = Array.isArray(parsed) ? parsed[i] : parsed && parsed[String(i + 1)];
        const line = typeof raw === "string" ? cleanOnelinerText(raw) : "";
        if (line) {
          onelinerCache.set(chunk[i].sessionId, line);
          results[chunk[i].sessionId] = line;
        } else {
          // Not cached — a later invocation retries this session.
          results[chunk[i].sessionId] = null;
        }
      }
    }
    return results;
  }

  // ── Knowledge Compound Interest (multi-session cross-analysis) ──

  const KNOWLEDGE_COMPOUND_SYSTEM_PROMPT =
    "你的任务是分析一组对话记录，从中提炼出对话者的「知识复利资产」。\n\n" +
    "分析分三个层次：\n\n" +
    "1. 原子知识点：对话中明确学到或讨论过的具体事实、技术细节、方法论。\n" +
    "   列出每个知识点及其来源对话。\n\n" +
    "2. 隐含模式：\n" +
    "   - 跨对话反复出现的主题和关注点\n" +
    "   - 对话者做判断/决策时的隐含偏好和思维框架\n" +
    "   - 不同对话中的知识点之间存在但尚未被显式建立的连接\n" +
    "   - 对话者擅长但可能自己没意识到的思维能力\n\n" +
    "3. 复利潜力评估：\n" +
    "   对上述发现按「复利潜力」排序。高复利的标准是：\n" +
    "   - 跨领域可迁移（不只在一个场景有用）\n" +
    "   - 半衰期长（一年后还有用）\n" +
    "   - 已有多次复现（在不同对话中反复出现）\n" +
    "   - 可以形成网络效应（与其他知识点连接越多价值越大）\n\n" +
    "最终输出 JSON，格式如下：\n" +
    '{"topAssets":[{"title":"资产名","sessions":["会话标题1","会话标题2"],"why":"为什么有高复利潜力"}],' +
    '"unlinkedConnections":[{"a":"知识点A","b":"知识点B","insight":"为什么应该关联"}],' +
    '"behaviorObservation":"对话者在习惯层面可以调整的一件事"}\n\n' +
    "要求：\n" +
    "- topAssets：3-5 条最高复利资产\n" +
    "- unlinkedConnections：2-3 条未建立的连接\n" +
    "- behaviorObservation：1 条行为模式观察\n" +
    "- 所有字段用中文\n" +
    "- **重要**：JSON 字符串值里不要出现未转义的双引号。引用名称请用「」或『』代替双引号。";

  function buildKnowledgeCompoundPrompt(details) {
    let p = "以下是用户与 AI agent 的多段对话记录。请综合分析。\n\n";
    for (let i = 0; i < details.length; i++) {
      const d = details[i];
      p += `--- 对话 ${i + 1}`;
      if (d.title) p += `: ${d.title}`;
      p += " ---\n";
      p += buildSessionContext(d);
      p += "\n";
    }
    p += "\n请返回 JSON（不要 markdown code block）。";
    return p;
  }

  // analyzeKnowledgeCompound(details, options?)
  //   options.systemPrompt: override default system prompt
  //   options.provider: "claude-code" | "codex" | "api:claude" | "api:openai" | "api:ollama"
  //                     when omitted, auto-pick first available CLI, then config API.
  async function analyzeKnowledgeCompound(details, options = {}) {
    if (!details || !details.length) return null;
    const startTime = Date.now();
    const systemPrompt = (options && typeof options.systemPrompt === "string" && options.systemPrompt.trim())
      ? options.systemPrompt
      : KNOWLEDGE_COMPOUND_SYSTEM_PROMPT;
    const prompt = buildKnowledgeCompoundPrompt(details);

    // Resolve preferred provider
    let preferred = options && typeof options.provider === "string" ? options.provider : "";
    if (!preferred) {
      const available = getAvailableAnalysisProviders();
      const firstCli = available.find((p) => p.id === "claude-code" || p.id === "tclaude" || p.id === "codex");
      if (firstCli) preferred = firstCli.id;
      else {
        const cfg = getConfig();
        preferred = cfg && cfg.provider ? `api:${cfg.provider}` : "claude-code";
      }
    }

    // Route 1: Claude CLI with --append-system-prompt (preserves system/user separation)
    if (preferred === "claude-code") {
      const claudePath = findClaudeBinary();
      if (!claudePath) return { error: true, summary: "Claude CLI 未找到。请安装 Claude Code 或改用其他 provider。" };
      try {
        const { text, usage, model, costUsd } = await callClaudeCLIWithSystem(claudePath, prompt, systemPrompt);
        const parsed = extractFirstJsonObject(text);
        if (parsed) {
          parsed._provider = "claude-code";
          parsed._model = model || getClaudeDefaultModel() || "unknown";
          parsed._analysisMs = Date.now() - startTime;
          if (usage) parsed._usage = usage;
          if (typeof costUsd === "number") parsed._cost = { usd: costUsd, source: "cli" };
          return parsed;
        }
        return { error: true, summary: "Claude CLI 返回内容无法解析为 JSON。" };
      } catch (err) {
        console.warn("Clawd knowledge-compound claude-code error:", err.message);
        return { error: true, summary: `Claude CLI 执行失败：${err.message}` };
      }
    }

    // Route 1b: tclaude CLI — Tencent fork of Claude Code, same CLI protocol.
    if (preferred === "tclaude") {
      const tclaudePath = findTclaudeBinary();
      if (!tclaudePath) return { error: true, summary: "tclaude CLI 未找到。请安装 tclaude 或改用其他 provider。" };
      try {
        const { text, usage, model, costUsd } = await callClaudeCLIWithSystem(tclaudePath, prompt, systemPrompt);
        const parsed = extractFirstJsonObject(text);
        if (parsed) {
          parsed._provider = "tclaude";
          parsed._model = model || getTclaudeDefaultModel() || "unknown";
          parsed._analysisMs = Date.now() - startTime;
          if (usage) parsed._usage = usage;
          if (typeof costUsd === "number") parsed._cost = { usd: costUsd, source: "cli" };
          return parsed;
        }
        return { error: true, summary: "tclaude CLI 返回内容无法解析为 JSON。" };
      } catch (err) {
        console.warn("Clawd knowledge-compound tclaude error:", err.message);
        return { error: true, summary: `tclaude CLI 执行失败：${err.message}` };
      }
    }

    // Route 2: Codex CLI — no --append-system-prompt; fold system prompt into user prompt
    if (preferred === "codex") {
      const codexPath = findCodexBinary();
      if (!codexPath) return { error: true, summary: "Codex CLI 未找到。请安装 Codex 或改用其他 provider。" };
      try {
        const combined = systemPrompt + "\n\n" + prompt;
        // Override default analysis schema so codex returns
        // topAssets/unlinkedConnections/behaviorObservation; otherwise
        // strict-mode coerces output into summary/keyTopics/outcomes and the
        // renderer shows an empty card.
        const cliResult = await callCodexCLI(codexPath, combined, {
          outputSchema: KNOWLEDGE_COMPOUND_OUTPUT_SCHEMA,
        });
        const parsed = extractFirstJsonObject(cliResult.text);
        if (parsed) {
          parsed._provider = "codex-cli";
          parsed._model = cliResult.model || getCodexDefaultModel() || "unknown";
          parsed._analysisMs = Date.now() - startTime;
          if (cliResult.usage) parsed._usage = cliResult.usage;
          if (typeof cliResult.costUsd === "number") {
            parsed._cost = { usd: cliResult.costUsd, source: "cli" };
          } else if (cliResult.usage) {
            const est = estimateCost(cliResult.usage, parsed._model);
            if (est) parsed._cost = { usd: est.usd, source: "estimate", pricingKey: est.pricingKey };
          }
          return parsed;
        }
        return { error: true, summary: "Codex CLI 返回内容无法解析为 JSON。" };
      } catch (err) {
        console.warn("Clawd knowledge-compound codex error:", err.message);
        return { error: true, summary: `Codex CLI 执行失败：${err.message}` };
      }
    }

    // Route 3: API provider — registry-first, then legacy fields
    let apiProviderId = preferred;
    if (apiProviderId.startsWith("api:")) apiProviderId = apiProviderId.slice(4);
    const cfg = getConfig();

    // Try registry: explicit preferred provider, then "detail" mode default
    const registryProvider = getProvider(apiProviderId) || getProvider(getDefaultProvider("detail"));
    if (registryProvider) {
      try {
        const fullPrompt = systemPrompt + "\n\n" + prompt;
        const MAX_TOKENS = 2000;
        let text;
        if (registryProvider.type === "claude") {
          text = await callClaude(registryProvider.apiKey, registryProvider.model, fullPrompt, MAX_TOKENS, registryProvider.baseUrl);
        } else if (registryProvider.type === "ollama") {
          text = await callOllama(registryProvider.model, fullPrompt, registryProvider.baseUrl);
        } else {
          text = await callOpenAICompat(registryProvider.apiKey, registryProvider.model, fullPrompt, registryProvider.baseUrl, MAX_TOKENS);
        }
        const parsed = extractFirstJsonObject(text);
        if (parsed) {
          parsed._provider = registryProvider.name;
          parsed._model = registryProvider.model;
          parsed._analysisMs = Date.now() - startTime;
          return parsed;
        }
        return { error: true, summary: "API 返回内容无法解析为 JSON。" };
      } catch (err) {
        console.warn("Clawd knowledge-compound API error:", err.message);
        return { error: true, summary: `API 调用失败：${err.message}` };
      }
    }

    // Legacy fallback (for users not yet on v3 or with no registry provider)
    const provider = (PROVIDERS[apiProviderId] ? apiProviderId : (cfg && cfg.provider) || "claude");
    const apiKey = cfg && cfg.apiKey;
    if (PROVIDERS[provider] && PROVIDERS[provider].needsKey && !apiKey) {
      return { error: true, summary: "未配置 API Key，请先在设置中配置。" };
    }
    try {
      const model = (cfg && cfg.model) || (PROVIDERS[provider] && PROVIDERS[provider].defaultModel);
      const baseUrl = (cfg && cfg.baseUrl) || (PROVIDERS[provider] && PROVIDERS[provider].baseUrl);
      const fullPrompt = systemPrompt + "\n\n" + prompt;
      // Knowledge compound output is larger than brief analysis; bump max_tokens to 2000.
      const MAX_TOKENS = 2000;
      let text;
      if (provider === "claude") text = await callClaude(apiKey, model, fullPrompt, MAX_TOKENS);
      else if (provider === "ollama") text = await callOllama(model, fullPrompt, baseUrl);
      else text = await callOpenAICompat(apiKey, model, fullPrompt, baseUrl, MAX_TOKENS);
      const parsed = extractFirstJsonObject(text);
      if (parsed) {
        parsed._provider = provider;
        parsed._model = model;
        parsed._analysisMs = Date.now() - startTime;
        return parsed;
      }
      return { error: true, summary: "API 返回内容无法解析为 JSON。" };
    } catch (err) {
      console.warn("Clawd knowledge-compound API error:", err.message);
      return { error: true, summary: `API 调用失败：${err.message}` };
    }
  }

  // callClaudeCLI variant with custom system prompt for knowledge compound
  function callClaudeCLIWithSystem(claudePath, prompt, systemPrompt) {
    return new Promise((resolve, reject) => {
      const fullPrompt = buildInternalCliAnalysisPrompt(prompt);
      // See callClaudeCLI for rationale: cmd.exe truncates multi-line args.
      const viaStdin = isWindowsShellShim(claudePath);
      const args = [
        "-p", ...(viaStdin ? [""] : [fullPrompt]),
        "--output-format", "stream-json",
        "--verbose",
        "--tools", "",
        "--disable-slash-commands",
        "--append-system-prompt", systemPrompt,
      ];
      const child = spawnCli(claudePath, args, {
        env: buildCliEnv({ CLAUDE_CODE_ENTRYPOINT: "cli" }),
        stdio: [viaStdin ? "pipe" : "ignore", "pipe", "pipe"],
      });
      const timeoutMs = 120000; // longer timeout for multi-session
      const maxBytes = 4 * 1024 * 1024;
      let stdout = "";
      let stderr = "";
      let settled = false;

      function fail(message) {
        if (settled) return;
        settled = true;
        reject(new Error(message));
        try { child.kill(); } catch {}
      }

      const timer = setTimeout(() => fail("knowledge-compound CLI timed out"), timeoutMs);
      child.stdout.on("data", (chunk) => {
        stdout += chunk.toString();
        if (stdout.length > maxBytes) fail("output too large");
      });
      child.stderr.on("data", (chunk) => { stderr += chunk.toString(); });
      child.on("error", (err) => fail(err.message));
      child.on("close", (code) => {
        clearTimeout(timer);
        if (settled) return;
        if (code !== 0 && !stdout) { fail(`CLI exited ${code}: ${stderr.slice(0, 200)}`); return; }
        // Parse stream-json the same way as callClaudeCLI
        let text = "", usage = null, model = null, costUsd = null;
        try {
          for (const line of stdout.split("\n")) {
            if (!line.trim()) continue;
            const evt = JSON.parse(line);
            if (evt.type === "assistant" && Array.isArray(evt.message && evt.message.content)) {
              for (const block of evt.message.content) {
                if (block.type === "text") text += block.text;
              }
              usage = evt.message.usage || usage;
              model = evt.message.model || model;
            } else if (evt.type === "result") {
              if (typeof evt.cost_usd === "number") costUsd = evt.cost_usd;
              if (evt.result) text = evt.result;
            }
          }
        } catch {
          text = stdout;
        }
        if (!text) text = stdout;
        settled = true;
        resolve({ text, usage, model, costUsd });
      });

      if (viaStdin) {
        child.stdin.on("error", (err) => fail(`claude stdin error: ${err.message}`));
        try {
          child.stdin.end(fullPrompt);
        } catch (err) {
          fail(`claude stdin write failed: ${err.message}`);
        }
      }
    });
  }

  // Build the aggregation prompt from per-session brief summaries. Each brief
  // is the result of running analyzeSession(..., "brief") on a single session,
  // so it's already concise (1-line summary + 2-3 topics + 1-2 outcomes).
  // Feeding briefs (not raw conversations) to the AI keeps tokens low and lets
  // the model focus on cross-session synthesis instead of re-reading walls of
  // dialogue.
  function buildMultiSessionPromptFromBriefs(items, rangeKind) {
    let p = "你是用户的编程搭档。以下是用户在这段时间里跨多个 AI 编程会话的**已生成简报**（每个会话独立做过 AI 分析）。\n";
    p += "请基于这些简报，提炼这段时间用户**整体在做什么**，归纳主题、识别重点、概括成果。\n\n";
    for (let i = 0; i < items.length; i++) {
      const { detail, brief } = items[i];
      p += `### 会话 ${i + 1}`;
      if (detail.title) p += ` · ${detail.title}`;
      p += "\n";
      if (detail.cwd) p += `项目：${detail.cwd}\n`;
      if (detail.timestamps && detail.timestamps.length >= 2) {
        const sorted = [...detail.timestamps].sort((a, b) => a - b);
        const start = new Date(sorted[0]);
        const end = new Date(sorted[sorted.length - 1]);
        p += `时间：${start.toLocaleString("zh-CN")} - ${end.toLocaleString("zh-CN")}（约 ${Math.round((end - start) / 60000)} 分钟）\n`;
      }
      if (brief.summary) p += `一句话：${brief.summary}\n`;
      if (Array.isArray(brief.keyTopics) && brief.keyTopics.length) {
        p += `话题：${brief.keyTopics.join("、")}\n`;
      }
      if (Array.isArray(brief.outcomes) && brief.outcomes.length) {
        p += "成果：\n";
        for (const o of brief.outcomes) {
          if (!o) continue;
          const head = o.headline || "";
          const det = o.detail || "";
          p += `- ${head}${det ? "：" + det : ""}\n`;
        }
      }
      p += "\n";
    }
    p += "请用 markdown 直接返回总结（不要 JSON，不要代码块），结构如下：\n\n";
    if (rangeKind === "week") {
      p += "# 这周都做了啥 <emoji>\n\n";
    } else {
      p += "# 这段时间做了什么\n\n";
    }
    p += "**TL;DR：** 一句话概括整段时间的主线（≤ 40 字）\n\n";
    p += "## 主要工作\n";
    p += "按项目或主题归类，3-6 条要点。用「项目/主题名」开头，后跟「做了 X，达成 Y」。\n\n";
    p += "## 关键成果\n";
    p += "2-4 条具体成果（解决了什么问题、上线了什么、想清楚了什么）。\n\n";
    p += "## 时间分布\n";
    p += "粗略估算各项目/主题占的时间比例（百分比即可）。\n\n";
    p += "要求：全程中文，口吻像同事复盘，语言平实，不用感叹号、寒暄语和比喻，不要套话；只用上面提供的简报内容，不要编造未提及的内容。";
    if (rangeKind === "week") {
      p += "标题里的 <emoji> 换成一个贴合本周主线的 emoji；整篇只用这一个 emoji，正文里不要再出现。";
    }
    return p;
  }

  // Compute the cache key the same way maybeCacheAnalysisResult does for a
  // brief-mode analysis. Reuses the persistent disk cache so we don't redo
  // expensive per-session AI work.
  function briefCacheKeyFor(detail, preferredProvider) {
    const id = detail.analysisId || detail.sessionId;
    return analysisCacheKey(id, preferredProvider || "claude-code") + ":brief";
  }

  async function analyzeMultipleSessions(details, preferredProvider, rangeKind) {
    if (!Array.isArray(details) || details.length === 0) return null;

    const tTotalStart = Date.now();
    let cacheHits = 0;
    let cacheMisses = 0;
    let stubs = 0;
    // Aggregated provider-side prompt-cache usage across every AI call this
    // report makes (stage 1 misses + stage 2 aggregation). Purely for the
    // timing log — lets us see whether the warm-up below actually pays off.
    const promptCacheTotals = { fresh: 0, read: 0, write: 0 };
    function addPromptCacheUsage(usage) {
      if (!usage) return;
      const read = usage.cache_read_input_tokens ?? usage.cached_input_tokens ?? 0;
      let fresh = usage.input_tokens || 0;
      // OpenAI-shaped usage (codex) counts cached tokens inside input_tokens;
      // Anthropic reports them disjointly. Subtract so hit-rate math is
      // comparable across providers.
      if (usage.cached_input_tokens != null && usage.cache_read_input_tokens == null) {
        fresh = Math.max(0, fresh - read);
      }
      promptCacheTotals.fresh += fresh;
      promptCacheTotals.read += read;
      promptCacheTotals.write += usage.cache_creation_input_tokens || 0;
    }

    // Stage 1: collect per-session brief summaries. Cache hits return instantly;
    // misses spawn a CLI per session. We split the work into a fast path (all
    // cached) and a slow path (parallel CLI), so a fully-warm run skips spawn
    // entirely. Concurrency capped at MULTI_BRIEF_CONCURRENCY to avoid memory
    // pressure + rate-limit blowups when running many CLI processes at once.
    const MULTI_BRIEF_CONCURRENCY = 4;
    const tStage1Start = Date.now();
    const provider0 = preferredProvider || "claude-code";

    function brieffromAny(b) {
      if (!b) return null;
      // Treat transient single-session failures (short response / non-JSON
      // text / generic AI failures) as a miss so the aggregator falls back
      // to the stub instead of injecting "分析失败:" prose into the prompt.
      if (b._cacheable === false || isTransientAnalysisFailure(b)) return null;
      return (b.summary || (b.keyTopics && b.keyTopics.length) || (b.outcomes && b.outcomes.length))
        ? b : null;
    }
    function stubBrief(detail) {
      return {
        summary: detail.title || (detail.firstUserMsg ? `开了一段会话："${detail.firstUserMsg}"` : "（无可用简报）"),
        keyTopics: [],
        outcomes: [],
      };
    }

    // Pre-pass: classify each detail as cached / miss; the cached ones land
    // in the items array immediately so cache-only runs incur zero await.
    const items = new Array(details.length);
    const missQueue = [];
    for (let i = 0; i < details.length; i++) {
      const detail = details[i];
      if (preferredProvider) detail._preferredProvider = preferredProvider;
      const key = briefCacheKeyFor(detail, provider0);
      const cached = brieffromAny(sessionAnalysisCache.get(key));
      if (cached) {
        items[i] = { detail, brief: cached };
        cacheHits++;
      } else {
        missQueue.push({ index: i, detail });
      }
    }

    // Slow path: parallel CLI for misses.
    //
    // Prompt-cache warm-up: the provider's cache entry only becomes readable
    // once the first response has started streaming. If all workers fire at
    // t=0, the first MULTI_BRIEF_CONCURRENCY requests carry identical system
    // prefixes yet each pays the full cold prefill (and 1.25× cache-write
    // price). Hold every worker except the first until the first call has
    // settled (cache guaranteed written — or the provider is failing and
    // waiting is pointless), with a stagger-timeout fallback of roughly one
    // cold call's spawn + time-to-first-token so a slow first call doesn't
    // serialize the whole batch.
    const WARMUP_STAGGER_MS = 4000;
    let releaseWarmupHold;
    const warmupHold = new Promise(resolve => { releaseWarmupHold = resolve; });
    const warmupTimeout = () => new Promise(resolve => {
      const t = setTimeout(resolve, WARMUP_STAGGER_MS);
      if (t && typeof t.unref === "function") t.unref();
    });
    let queueIdx = 0;
    async function worker(workerIndex) {
      if (workerIndex > 0) {
        await Promise.race([warmupHold, warmupTimeout()]);
      }
      while (queueIdx < missQueue.length) {
        const myIdx = queueIdx++;
        const { index, detail } = missQueue[myIdx];
        let brief = null;
        try { brief = await analyzeSession(detail, "brief"); } catch { brief = null; }
        releaseWarmupHold();
        if (brief && brief._usage) addPromptCacheUsage(brief._usage);
        const good = brieffromAny(brief);
        if (good) {
          items[index] = { detail, brief: good };
          cacheMisses++;
        } else {
          items[index] = { detail, brief: stubBrief(detail) };
          stubs++;
        }
      }
    }
    const workerCount = Math.min(MULTI_BRIEF_CONCURRENCY, missQueue.length);
    if (workerCount > 0) {
      await Promise.all(Array.from({ length: workerCount }, (_, i) => worker(i)));
    }
    const stage1Ms = Date.now() - tStage1Start;

    if (!items.length) return { text: null, error: "未能加载任一会话的简报。", _timing: { stage1Ms, stage2Ms: 0, totalMs: Date.now() - tTotalStart, sessions: 0, cacheHits, cacheMisses, stubs } };

    const prompt = buildMultiSessionPromptFromBriefs(items, rangeKind);

    // Stage 2: cross-session aggregation. Time the AI call separately so we
    // can tell whether the long wall-clock comes from cache misses or the
    // aggregator itself.
    const tStage2Start = Date.now();
    const provider = preferredProvider || "claude-code";

    function makeTimingMeta() {
      return {
        stage1Ms,
        stage2Ms: Date.now() - tStage2Start,
        totalMs: Date.now() - tTotalStart,
        sessions: items.length,
        cacheHits,
        cacheMisses,
        stubs,
        promptCache: { ...promptCacheTotals },
      };
    }
    function logTiming(tag, extra) {
      const m = makeTimingMeta();
      const pc = m.promptCache;
      const pcTotal = pc.fresh + pc.read + pc.write;
      // Hit rate over all input-side tokens: read tokens were served from the
      // provider's prompt cache, fresh + write were prefilled cold. A rate
      // stuck at 0 across warm runs means the prefix is being broken somewhere.
      const pcNote = pcTotal
        ? ` · promptCache ${Math.round((pc.read / pcTotal) * 100)}% hit (${pc.read} read / ${pc.write} write / ${pc.fresh} fresh)`
        : "";
      console.log(`[clawd-insights] report timing (${tag}): ${m.totalMs}ms total, stage1=${m.stage1Ms}ms (briefs: ${m.cacheHits} cached, ${m.cacheMisses} generated, ${m.stubs} stubs), stage2=${m.stage2Ms}ms${pcNote}${extra ? " · " + extra : ""}`);
      return m;
    }

    if (provider === "codex") {
      const codexPath = findCodexBinary();
      if (codexPath) {
        try {
          const result = await callCodexCLI(codexPath, prompt, { outputSchema: null });
          if (result) addPromptCacheUsage(result.usage);
          if (result && result.text) {
            const _timing = logTiming("codex-cli", `${items.length} sessions`);
            return { text: result.text, _provider: "codex", _timing };
          }
        } catch (e) { /* fall through */ }
      }
    } else if (provider === "tclaude") {
      // Same CLI protocol as Claude Code — reuse callClaudeCLIWithSystem.
      const tclaudePath = findTclaudeBinary();
      if (tclaudePath) {
        try {
          const sysPrompt = "你是一个对话分析助手。请按用户的要求直接返回 markdown 文本，不要返回 JSON，不要把回答包在 code block 里。";
          const { text, usage } = await callClaudeCLIWithSystem(tclaudePath, prompt, sysPrompt);
          addPromptCacheUsage(usage);
          if (text) {
            const _timing = logTiming("tclaude-cli", `${items.length} sessions`);
            return { text, _provider: "tclaude", _timing };
          }
        } catch (e) { /* fall through */ }
      }
    } else {
      const claudePath = findClaudeBinary();
      if (claudePath) {
        try {
          const sysPrompt = "你是一个对话分析助手。请按用户的要求直接返回 markdown 文本，不要返回 JSON，不要把回答包在 code block 里。";
          const { text, usage } = await callClaudeCLIWithSystem(claudePath, prompt, sysPrompt);
          addPromptCacheUsage(usage);
          if (text) {
            const _timing = logTiming("claude-cli", `${items.length} sessions`);
            return { text, _provider: "claude-code", _timing };
          }
        } catch (e) { /* fall through */ }
      }
    }

    const registryProvider = getProvider(getDefaultProvider("detail")) || getProvider(getDefaultProvider("brief"));
    if (registryProvider) {
      try {
        let text;
        if (registryProvider.type === "claude") {
          text = await callClaude(registryProvider.apiKey, registryProvider.model, prompt, 4000, registryProvider.baseUrl);
        } else if (registryProvider.type === "ollama") {
          text = await callOllama(registryProvider.model, prompt, registryProvider.baseUrl);
        } else {
          text = await callOpenAICompat(registryProvider.apiKey, registryProvider.model, prompt, registryProvider.baseUrl, 4000);
        }
        if (text) {
          const _timing = logTiming(`registry:${registryProvider.type}`, `${items.length} sessions`);
          return { text, _provider: registryProvider.id || registryProvider.type, _timing };
        }
      } catch (e) { /* fall through */ }
    }

    const cfg = getConfig();
    const legacyProvider = (cfg && cfg.provider) || "claude";
    const apiKey = cfg && cfg.apiKey;
    if (!apiKey && PROVIDERS[legacyProvider] && PROVIDERS[legacyProvider].needsKey) {
      return { text: null, error: "未配置 AI Provider，请到设置中添加。", _timing: makeTimingMeta() };
    }
    try {
      const model = (cfg && cfg.model) || PROVIDERS[legacyProvider].defaultModel;
      const baseUrl = (cfg && cfg.baseUrl) || PROVIDERS[legacyProvider].baseUrl;
      let text;
      if (legacyProvider === "claude") text = await callClaude(apiKey, model, prompt, 4000, baseUrl);
      else if (legacyProvider === "ollama") text = await callOllama(model, prompt, baseUrl);
      else text = await callOpenAICompat(apiKey, model, prompt, baseUrl, 4000);
      if (text) {
        const _timing = logTiming(`legacy:${legacyProvider}`, `${items.length} sessions`);
        return { text, _provider: legacyProvider, _timing };
      }
    } catch (e) {
      return { text: null, error: e && (e.message || String(e)), _timing: makeTimingMeta() };
    }
    return { text: null, error: "AI 调用失败。", _timing: makeTimingMeta() };
  }

  return { getApiKey, setApiKey, getConfig, setConfig, PROVIDERS, analyzeSession, analyzeMultipleSessions, getAnalysisProvider, getAvailableAnalysisProviders, findClaudeBinary, getSessionOneLiner, getSessionOneLiners, getCliDiagnostics, testCliPath, clearAnalysisCaches, loadPersistedAnalyses, analyzeKnowledgeCompound, getProviderRegistry, addProvider, updateProvider, deleteProvider, getProvider, testProvider, getDefaultProvider, setDefaultProvider, generateUUID, validateProvider };
};

module.exports.__test = {
  buildSessionContext,
  getDetailContextEntryCount,
  resolvePreferredAnalysisProvider,
  preferWindowsExecutable,
};
