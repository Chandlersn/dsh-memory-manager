/**
 * dsh-memory-manager — long-term memory for the DeepSeek Harness.
 *
 * Adapted from lantern's `memory-function-org` skill. The memory root holds:
 *   functions/    = per-feature iteration history (date as tag, append-only blocks)
 *   insights/     = transferable principles distilled UP from features (backlinked)
 *   capabilities/ = external tool ledger (what can I call, and how)
 *   skills/       = crystallized procedures (candidate → active → retired)
 *   MEMORY.md     = the index: four one-line-summary tables + consensus + env constants
 *   YYYY-MM-DD.md = the RAW daily layer (free-form, model-maintained)
 *
 * Twelve tools (read / search / capability / write / index / insight / fold /
 * rename / check / usage / federation / skill), an injected discipline section,
 * a budgeted pre-step recall hook (RRF-fused ranking + decision repair), and a
 * read-only HTTP API (`/api/memory-org/*`) consumed by the bundled Web panel.
 *
 * This file is the plugin ENTRY (apply + tool registration + hooks). The pure
 * layers live in ./src — see the import block below for the map.
 *
 * @module dsh-memory-manager
 */
import { readFile, writeFile, rename, unlink, mkdir, readdir, stat, appendFile } from 'node:fs/promises';
import { existsSync } from 'node:fs';
import * as path from 'node:path';
import { homedir } from 'node:os';
import { Buffer } from 'node:buffer';
import { createRequire } from 'node:module';
// ---------------------------------------------------------------------------
// shared layers — the plugin is a folder, not one 3.5k-line file
// ---------------------------------------------------------------------------
//   constants.js — table headings, size caps, lifecycle vocabularies
//   util.js      — dates, atomic write, slugs, block parsing, root resolution
//   usage.js     — the .usage.jsonl usage-signal ledger
//   markdown.js  — file templates + index/section surgery
//   recall.js    — pre-step ranking + full-text search
//   host.js      — DSH install discovery and lazy Host binding
import {
	localDateStr, normDate, oneLine, charLen, readIfExists, writeText, statExists, safeSlug,
	splitIterationBlocks, dshHome, joinDshHome, resolveRoot, appendBlock, countHeadingDate,
} from './src/util.js';
import { usagePath, appendUsage, readUsage, summarizeUsage, insightTrust, trustLineFor, refreshTrustLine } from './src/usage.js';
import {
	memoryIndexTemplate, functionFileTemplate, dailyTemplate, insightTemplate, sepOf,
	upsertIndexRow, appendUnderHeading, resolveOpenItems, refreshSummarySection, replaceSection,
} from './src/markdown.js';
import { tokensOf, matchIndexRows, buildRecallMessage } from './src/recall.js';
import { redactSecrets, scanSecrets } from './src/secrets.js';
import { isSkillName, registerMemorySkillBridge } from './src/host-skill.js';
import { resolveDshRoot, setHostRoot, loadHost, defineTool, createUserMessage } from './src/host.js';
import {
	name, inject, DEFAULTS, FUNC_TABLE_HEADING, INSIGHT_TABLE_HEADING, CAP_TABLE_HEADING,
	CAP_TABLE_HEADER, FUNC_TABLE_HEADER, INSIGHT_TABLE_HEADER, SKILL_DIR, SKILL_STATUSES,
	SKILL_TABLE_HEADING, SKILL_TABLE_HEADER, SKILL_NOMINATE, CAP_DIR, FED_TABLE_HEADING,
	FED_TABLE_HEADER, FED_CONSENSUS_HEADING, DAILY_SECTION, DAILY_OPEN_SECTION, RESULT_LABEL,
	GUARD_MARK, GUARD_LINE, MAX_BLOCK_CHARS, MAX_ROW_SUMMARY_CHARS, MAX_PRINCIPLE_CHARS,
	MAX_CONSENSUS_CHARS, CONSENSUS_HEADING, LEGACY_TABLE_HEADERS,
} from './src/constants.js';

// ---------------------------------------------------------------------------
// locating the Host installation
// ---------------------------------------------------------------------------

/**
 * First-party Host packages (`defineTool`, `createUserMessage`) must come from
 * the DSH installation itself.
 *
 * A profile-installed bundle is a pnpm link whose realpath is this source
 * directory, so bare-import resolution from inside it never sees the Host's
 * node_modules. Requiring the exact Host file works: these are ESM modules
 * (Node >= 22.12 `require(esm)`), their own dependencies resolve from the
 * install's flat node_modules, and require(esm) returns the already-cached
 * namespace the Host loaded — one shared instance.
 *
 * The install root is discovered instead of hardcoded so the bundle stays
 * portable. Candidates, in order:
 *   1. plugin config `dshRoot`
 *   2. env `DSH_INSTALL_DIR` / `DSH_ROOT`
 *   3. walking up from the running CLI entry (`process.argv[1]`)
 *   4. walking up from `process.cwd()`
 *   5. walking up from `DSH_PROFILE_DIR`
 *   6. resolving the Host package from this file's own tree (regular installs)
 * A candidate counts only when it really contains the Host package.
 */
// Host discovery + lazy Host binding now live in src/host.js (imported at the
// top of this file).


// Tool identity + every shared constant (table headings, size caps, lifecycle
// vocabularies, DEFAULTS) live in src/constants.js — imported at the top.

/**
 * Build the passive-capture line for one user turn, or null when it should not
 * be recorded (disabled, empty, or already present in today's log). Pure, so the
 * privacy/truncation rules are testable without touching the filesystem.
 */
function captureLineFor(userText, todayLogText, { enabled = false, maxChars = DEFAULTS.captureMaxChars } = {}) {
	if (!enabled) return null;
	const text = String(userText ?? '').replace(/\s+/g, ' ').trim();
	if (!text) return null;
	const line = text.length > maxChars ? `${text.slice(0, maxChars)}…` : text;
	const stamp = `- ${line}`;
	// Exact-duplicate guard: repeating the same request must not pile up lines.
	if (String(todayLogText ?? '').split('\n').some((l) => l.trim() === stamp)) return null;
	return stamp;
}

// (usage signals now live in src/usage.js — imported above)

// ---------------------------------------------------------------------------
// small helpers
// ---------------------------------------------------------------------------

const pad2 = (n) => String(n).padStart(2, '0');
const byteLen = (s) => Buffer.byteLength(s, 'utf8');

// ---------------------------------------------------------------------------
// canonical file templates — now in src/markdown.js
// ---------------------------------------------------------------------------

// ---------------------------------------------------------------------------
// markdown surgery (index rows / sections)
// ---------------------------------------------------------------------------


// ---------------------------------------------------------------------------
// shared checker pieces (ported from lantern's check_memory.py)
// ---------------------------------------------------------------------------

function stripCode(text) {
	return text.replace(/```[\s\S]*?```/g, '').replace(/`[^`\n]*`/g, '');
}

async function checkLinks(text, filePath, root, add) {
	const stripped = stripCode(text);
	const base = path.dirname(filePath);
	const rootAbs = path.resolve(root);
	const seen = new Set();
	// Slugs may contain spaces (safeSlug only forbids separators); a [^)\s]
	// pattern silently SKIPPED those links, so a dangling spaced href never
	// tripped R10. Match the same surface the writer produces.
	for (const m of stripped.matchAll(/\[[^\]\n]*\]\(([^)\n]+)\)/g)) {
		const rel = m[1].split('#')[0].trim();
		if (!rel || rel.startsWith('/') || rel.startsWith('http') || rel.includes('attachments')) continue;
		const resolved = path.resolve(base, rel);
		const key = `${filePath}→${resolved}`;
		if (seen.has(key)) continue;
		seen.add(key);
		const exists = await statExists(resolved);
		const label = path.relative(rootAbs, filePath).split(path.sep).join('/') || 'MEMORY.md';
		if (!exists) add('FAIL', 'R10', `dangling link in ${label} -> ${rel}`);
		else if (resolved !== rootAbs && !resolved.startsWith(rootAbs + path.sep)) {
			add('WARN', 'R10e', `link in ${label} escapes memory root -> ${rel}`);
		}
	}
}

/**
 * R21 (memory defence): one file's secrets reported by the health check.
 * Code spans are stripped first — an example token inside a fenced block is
 * documentation, not a leak (Hindsight exempts its own docs the same way).
 * Tier-1 hits mean the write predates the redactor or arrived outside the
 * plugin's write path; tier-2 (ID/phone) is never rewritten anywhere, only
 * reported here.
 */
function scanForSecrets(text, label, add) {
	const findings = scanSecrets(stripCode(text));
	if (!findings.length) return;
	const part1 = findings.filter((f) => f.tier === 1);
	const part2 = findings.filter((f) => f.tier === 2);
	if (part1.length) {
		add('FAIL', 'R21', `${label} 含凭据材料（${part1.map((f) => `${f.kind}×${f.count}`).join('、')}）：写入侧应已 redact——来自插件外的直接写入，请人工清理明文`);
	}
	if (part2.length) {
		add('WARN', 'R21', `${label} 含个人标识（${part2.map((f) => `${f.kind}×${f.count}`).join('、')}）：不自动改写（常属正当事实），确认是否真需要留存`);
	}
}

const REVERSE_DETAIL_FULL = /详见\s*MEMORY\.md[（(][^）)]{2,}[）)]/;
const REVERSE_DETAIL_VAGUE = /详见\s*MEMORY\.md(?!\s*[（(])/;
const DATE_TAG = /^##\s*\[(\d{4})-(\d{2})-(\d{2})/gm;

// ---------------------------------------------------------------------------
// shared health check (memory_check tool + panel API)
// ---------------------------------------------------------------------------

async function runHealthCheck(root, opts) {
	const results = [];
	const add = (level, rule, message) => results.push({ level, rule, message });

	const memPath = path.join(root, 'MEMORY.md');
	const memText = await readIfExists(memPath);
	if (memText === undefined) {
		add('FAIL', 'R0', `MEMORY.md not found under ${root}：先用 memory_write 记录第一次迭代`);
		return { root, results, warnCount: 0, failCount: 1 };
	}
	const memSize = byteLen(memText);
	if (memSize > opts.maxIndexHardBytes) add('FAIL', 'R5', `MEMORY.md ${memSize}B > 硬上限 ${opts.maxIndexHardBytes}B`);
	else if (memSize > opts.maxIndexBytes) add('WARN', 'R5', `MEMORY.md ${memSize}B > 舒适线 ${opts.maxIndexBytes}B`);

	let emptySummary = 0;
	const longRows = [];
	for (const raw of memText.split('\n')) {
		const s = raw.trim();
		if (!s.startsWith('|')) continue;
		const cells = s.replace(/^\|/, '').replace(/\|$/, '').split('|').map((c) => c.trim());
		// The one-line summary is always the SECOND content cell, in every
		// generation (2-column rows: name/summary; legacy 4-column rows:
		// name/summary/link/extra). A 3-column floor would skip 2-column rows
		// entirely — exactly where an over-long summary would hide.
		if (cells.length < 2) continue;
		if (cells.every((c) => /^[-: ]*$/.test(c))) continue;
		// Strip the link syntax so the check measures the words, not the href.
		// BOTH cells need it: the name cell is a whole link since 5.15.0, and an
		// insight row folds its source areas INTO the summary cell — counting
		// `[x.md](functions/x.md)` as words flags a 34-char sentence as 129.
		const name = cells[0].replace(/^\[([^\]]+)\]\([^)]*\)$/, '$1');
		const summary = cells[1].replace(/\[([^\]]*)\]\([^)]*\)/g, '$1');
		if (!summary) emptySummary++;
		else if (charLen(summary) > MAX_ROW_SUMMARY_CHARS) longRows.push(`${name}（${charLen(summary)} 字）`);
	}
	if (emptySummary) add('WARN', 'R5', `${emptySummary} 个索引行缺少一行摘要（摘要列是索引判断相关性的唯一依据）`);
	if (longRows.length) {
		add('WARN', 'R14', `索引行摘要过长（摘要是一句话，细节应留在功能文件）：${longRows.join('、')}`);
	}

	// R5 scaling: past ~40 function rows a single flat table costs too much to
	// scan. The escape hatch is `### 索引·<域>` sub-sections plus memory_index's
	// `group` argument; flag a big ungrouped table so the split happens before
	// the index gets uncomfortable rather than after.
	{
		const at = memText.indexOf(FUNC_TABLE_HEADING);
		if (at !== -1) {
			const rest = memText.slice(at);
			const stop = rest.indexOf('\n## ', 1);
			const section = stop === -1 ? rest : rest.slice(0, stop);
			const rows = section.split(/\r?\n/).filter((l) => l.trim().startsWith('|') && !l.includes('---')).length - 1;
			if (rows > 40 && !section.includes('### 索引·')) {
				add('WARN', 'R5', `功能表已 ${rows} 行（>40）：按「### 索引·<域>」拆分子分区，并在 memory_index 传 group 参数落对表`);
			}
		}
	}

	// R15: duplicated rows / duplicated table sections. The index is a lookup
	// surface; a repeated row (same slug cell) or a repeated table heading makes
	// recall inject the same fact twice and hides which row is authoritative.
	const rowSlugCount = new Map();
	let dupeRows = 0;
	// A grouped index (### 索引·<domain>, see upsertIndexRow's group branch) shares
	// ONE header row across every sub-table by design, so headers are not evidence
	// of a stale duplicate row — skip them before counting slug cells.
	const tableHeaders = new Set([FUNC_TABLE_HEADER, INSIGHT_TABLE_HEADER, CAP_TABLE_HEADER, SKILL_TABLE_HEADER, FED_TABLE_HEADER]);
	for (const raw of memText.split('\n')) {
		const s = raw.trim();
		if (!s.startsWith('|')) continue;
		// The 4-column header generation is still exempt alongside the current
		// 2/3-column one: a root mid-migration carries both, and neither header
		// is evidence of a duplicate row.
		if (tableHeaders.has(s) || LEGACY_TABLE_HEADERS.has(s)) continue;
		const cells = s.replace(/^\|/, '').replace(/\|$/, '').split('|').map((c) => c.trim());
		// 2 as the floor (name + summary): the 3-column floor would silently skip
		// every 2-column row, which is exactly where a duplicate would hide.
		if (cells.length < 2 || cells.every((c) => /^[-: ]*$/.test(c))) continue;
		const slug = cells[0].replace(/^\[([^\]]+)\]\([^)]*\)$/, '$1');
		rowSlugCount.set(slug, (rowSlugCount.get(slug) ?? 0) + 1);
	}
	for (const [slug, n] of rowSlugCount) {
		if (n > 1) {
			dupeRows++;
			add('WARN', 'R15', `索引行「${slug}」出现 ${n} 次（同一事实只在一处为真）：确认哪一行是现状，删掉其余行`);
		}
	}
	const headingCount = new Map();
	for (const raw of memText.split('\n')) {
		const s = raw.trim();
		if (!s.startsWith('## ')) continue;
		headingCount.set(s, (headingCount.get(s) ?? 0) + 1);
	}
	for (const [h, n] of headingCount) {
		if (n > 1) add('WARN', 'R15', `索引小节「${h}」出现 ${n} 次（多为模板换代后锚点失配的兜底产物）：保留第一处，删除其余小节`);
	}

	scanForSecrets(memText, 'MEMORY.md', add);
	await checkLinks(memText, memPath, root, add);

	// R16 (ported from the workbuddy skill's F4): env-constant lines often carry
	// absolute backtick paths (install dirs, DB files, scripts). A moved or
	// renamed path silently poisons every future recall that trusts it — check
	// they still exist. Only the index is scanned: it is the env-constants home.
	const checkedPaths = new Set();
	for (const m of memText.matchAll(/`([^`\n|]+)`/g)) {
		const raw = m[1].trim();
		const pm = /^([A-Za-z]:[\\/].*)$/.exec(raw);
		if (!pm) continue;
		const p = pm[1].replace(/[/\\]+$/, '');
		const key = p.toLowerCase();
		if (checkedPaths.has(key)) continue;
		checkedPaths.add(key);
		if (!(await statExists(p))) {
			add('WARN', 'R16', `环境常量引用的路径已不存在 -> ${p}（索引里的环境常量被未来召回盲信，确认新路径后更新）`);
		}
	}

	// R19: the consensus section is the highest layer (道层) — a binding constraint
	// lives here, so it must point back at its evidence.
	{
		const at = memText.indexOf(CONSENSUS_HEADING);
		if (at !== -1) {
			const rest = memText.slice(at + CONSENSUS_HEADING.length);
			const stop = rest.indexOf('\n## ');
			const section = stop === -1 ? rest : rest.slice(0, stop);
			for (const raw of section.split(/\r?\n/)) {
				const line = raw.trim();
				if (!line.startsWith('- ')) continue;
				const body = line.slice(2).trim();
				if (!body) continue; // the template placeholder
				const n = charLen(body);
				if (n > MAX_CONSENSUS_CHARS) {
					add('WARN', 'R19', `共识条目 ${n} 字 > ${MAX_CONSENSUS_CHARS}：一条共识只约束一件事，论证留在来源功能文件里（条目：${body.slice(0, 24)}…）`);
				}
				const links = [...body.matchAll(/\]\(([^)]+\.md)\)/g)].map((m) => m[1]);
				if (!links.length) {
					add('WARN', 'R19', `共识条目没有依据链接：至少指向一个 functions/ 或 insights/ 文件（条目：${body.slice(0, 24)}…）`);
				} else if (/跨功能|跨项目|所有|全局|一律/.test(body) && new Set(links.map((l) => l.replace(/\/(?:[^/]+)\.md$/, ''))).size < 2) {
					add('WARN', 'R19', `声称跨域的共识只有 1 个来源域：跨域结论要能指向 ≥2 个无关领域（条目：${body.slice(0, 24)}…）`);
				}
			}
		}
	}

	// Collected during the pass below so the temperature analysis can reuse these
	// reads instead of hitting the disk a second time for every file.
	const fnTexts = new Map();
	const fnMtimes = new Map();
	const insightTexts = [];

	for (const zone of ['functions', 'insights', 'capabilities', 'skills']) {
		const dir = path.join(root, zone);
		let files = [];
		try {
			files = (await readdir(dir)).filter((f) => f.endsWith('.md'));
		} catch {
			/* zone absent */
		}
		for (const f of files.sort()) {
			const fp = path.join(dir, f);
			const text = await readFile(fp, 'utf8');
			const stripped = stripCode(text);
			if (zone === 'functions') {
				const slug = f.replace(/\.md$/, '');
				fnTexts.set(slug, text);
				try {
					fnMtimes.set(slug, (await stat(fp)).mtimeMs);
				} catch {
					/* mtime is best-effort */
				}
				const size = byteLen(text);
				if (size > opts.maxFunctionBytes) {
					const fname = f.replace(/\.md$/, '');
					add('WARN', 'R9', `functions/${f} ${size}B > ${opts.maxFunctionBytes}B — 调用 memory_fold(feature="${fname}") 折叠最旧块`);
				}
				if (REVERSE_DETAIL_FULL.test(stripped)) {
					add('FAIL', 'R8', `functions/${f} 反向链接 MEMORY.md 的细节块：细节应移回本文件，MEMORY.md 只留指针`);
				} else if (REVERSE_DETAIL_VAGUE.test(stripped)) {
					add('WARN', 'R8', `functions/${f} “详见 MEMORY.md”目标不明（人工确认）`);
				}
				const dates = [...stripped.matchAll(DATE_TAG)].map((m) => `${m[1]}${m[2]}${m[3]}`);
				for (let i = 1; i < dates.length; i++) {
					if (dates[i] < dates[i - 1]) {
						add('WARN', 'R3', `functions/${f} 迭代日期标签非递增（不是追加写入）`);
						break;
					}
				}
				// R3 head guardrail (from the workbuddy skill variant): the head
				// 「当前状态摘要（截至 date）」 must not be older than the newest
				// iteration block — appending without refreshing the head is exactly
				// the "改头忘尾" drift this check makes visible.
				const mHead = /当前状态摘要（截至\s*(\d{4})-(\d{2})-(\d{2})/.exec(stripped);
				if (mHead && dates.length) {
					const head = `${mHead[1]}${mHead[2]}${mHead[3]}`;
					const newest = dates[dates.length - 1];
					if (head < newest) {
						add('WARN', 'R3', `functions/${f} 头部状态摘要截至 ${mHead.slice(1).join('-')} 早于最新迭代块 ${newest.slice(0, 4)}-${newest.slice(4, 6)}-${newest.slice(6)}：追加迭代须成对刷新头部摘要`);
					}
				} else if (!mHead && dates.length) {
					add('WARN', 'R3', `functions/${f} 缺少「当前状态摘要（截至 YYYY-MM-DD）」头部摘要`);
				}
				// R14: an iteration block is a distilled conclusion, not a process log.
				for (const b of splitIterationBlocks(text)) {
					const n = charLen(b.body);
					if (n > MAX_BLOCK_CHARS) {
						add('WARN', 'R14', `functions/${f} 迭代块「${b.title}」正文 ${n} 字 > ${MAX_BLOCK_CHARS}（未蒸馏）：压成 动因/改动结论/判据/待观察 各一句，过程留在会话与代码里`);
						break; // one report per file is enough
					}
				}
			} else if (zone === 'insights') {
				insightTexts.push(text);
			} else if (zone === 'skills') {
				// R20 (fields mirror lantern skill-creator's quick_validate: a skill is
				// a CALLABLE procedure, so its frontmatter router + the executable
				// sections must be present and its lifecycle legal). status: reads the
				// frontmatter first, tolerating the pre-5.12 `> 状态：` head.
				const sSlug = f.replace(/\.md$/, '');
				const sStatus = (stripped.match(/^status:\s*([a-z]+)/m) ?? stripped.match(/^> 状态：([a-z]+)/m) ?? [])[1];
				if (!sStatus) add('WARN', 'R20', `skills/${f} 缺少 status（frontmatter 或旧「> 状态：」）：召回无法判断可否信任`);
				else if (!SKILL_STATUSES.includes(sStatus)) add('WARN', 'R20', `skills/${f} 状态「${sStatus}」非法（应为 ${SKILL_STATUSES.join('/')}）`);
				// The router: a skill without a description/trigger never fires — same
				// failure quick_validate flags for a missing description field.
				const hasDesc = /^description:\s*"?([^"\n]+)"?/m.test(stripped) || /^>\s*摘要：\s*\S/m.test(stripped);
				if (!hasDesc) add('WARN', 'R20', `skills/${f} 缺 description/摘要：没有路由说明的技能不会被命中`);
				// Scope audit (memory-function-org skill_scope.py, 5.17.0): an owned
				// (agent_created) skill without scope is a cross-project recall risk —
				// a procedure proven in project A silently fires in project B. Only
				// owned skills WARN; hand-managed files get nothing (the script's rule).
				const owned = /agent_created:\s*(?:true|1)/.test(stripped);
				const scopeM = (stripped.match(/^scope:\s*([a-z]+)/m) ?? [])[1];
				if (owned && !scopeM) add('WARN', 'R20s', `skills/${f} 自有技能缺 scope 字段：重结晶补一次（memory_skill 已支持 scope/scopeProject），global=跨项目通用 / project=须带 scope_project`);
				else if (scopeM === 'project' && !/^scope_project:\s*\S/m.test(stripped)) add('WARN', 'R20s', `skills/${f} scope=project 但缺 scope_project：项目归属未知，路由无法判定适用性`);
				// hostName, when present, must satisfy the Host's name grammar or the
				// provider silently ignores the skill at discovery ("ignored: invalid
				// skill name") — a broken promise, cheaper caught here than in logs.
				const hostM = (stripped.match(/^hostName:\s*(\S+)/m) ?? [])[1];
				if (hostM && !isSkillName(hostM)) add('WARN', 'R20h', `skills/${f} hostName「${hostM}」不是 kebab-case：宿主目录会忽略它，改成小写-连字符形式`);
				if (sStatus !== 'retired') {
					const steps = (/## 调用步骤\s*\n([\s\S]*?)(?=\n## |$)/.exec(stripped) ?? [])[1] ?? '';
					const numbered = (steps.match(/^\s*1[.、]/gm) ?? []).length;
					if (!numbered) add('WARN', 'R20', `skills/${f} 「调用步骤」没有编号步骤：技能必须可直接执行，空壳请补全或 retire`);
					const when = (stripped.match(/## 何时使用\s*\n+-\s*(.+)/) ?? [])[1];
					if (!when) add('WARN', 'R20', `skills/${f} 「何时使用」为空：没有触发条件的技能永远不会被命中`);
				}
				// R20e: the index row's 状态 cell must agree with the file status, or the
				// recall filter (which reads the index) trusts the wrong lifecycle.
				const rowM = new RegExp(`^\\|\\s*${sSlug.replace(/[.*+?^${}()|[\]\\]/g, '\\$&')}\\s*\\|[^\\n]*\\|\\s*(candidate|active|retired)\\s*\\|`, 'm').exec(memText);
				if (sStatus && rowM && rowM[1] !== sStatus) {
					add('WARN', 'R20e', `技能「${sSlug}」索引行状态 ${rowM[1]} 与文件 status ${sStatus} 不一致：召回只放行 active，确认哪边是现状`);
				}
			}
			scanForSecrets(text, `${zone}/${f}`, add);
			await checkLinks(text, fp, root, add);
		}
	}

	try {
		for (const f of await readdir(root)) {
			if (!/^\d{4}-\d{2}-\d{2}\.md$/.test(f)) continue;
			const dtext = await readFile(path.join(root, f), 'utf8');
			await checkLinks(dtext, path.join(root, f), root, add);
			// R21 (memory defence, Hindsight-borrowed): the daily RAW layer is
			// where a pasted token most often lands — the write-side redactor
			// never routes it (the model writes daily files itself), so the
			// health check is what catches it, retroactively for pre-defence
			// content too.
			scanForSecrets(dtext, f, add);
		}
	} catch {
		/* root absent */
	}

	try {
		for (const f of await readdir(path.join(root, 'legacy'))) {
			if (!f.endsWith('.md')) continue;
			const text = await readFile(path.join(root, 'legacy', f), 'utf8');
			if (!text.includes('历史原貌')) add('WARN', 'R13', `legacy/${f} 缺少“历史原貌”头部（不得并入当前 functions/）`);
		}
	} catch {
		/* no legacy dir */
	}

	// Memory temperature (cold-area candidates): for every function file count
	// inbound references from OTHER function files (related links) and insight
	// backlinks. The index row and daily threads are excluded — both are
	// auto-generated for every write, so they carry no signal. Zero deep
	// references means nothing ever linked back: brand new or going cold.
	// Files touched within `newFeatureGraceDays` are skipped: a feature written
	// today has had no chance to be backlinked yet, so flagging it is noise.
	try {
		const fnNames = [...fnTexts.keys()];
		const graceMs = Math.max(0, opts.newFeatureGraceDays) * 24 * 60 * 60 * 1000;
		if (fnNames.length > 1) {
			const refText = [...insightTexts, ...fnTexts.values()].join('\n');
			for (const name of fnNames) {
				const mtime = fnMtimes.get(name);
				if (graceMs > 0 && typeof mtime === 'number' && Date.now() - mtime < graceMs) continue;
				const own = fnTexts.get(name) ?? '';
				// Guarded memories opt out: a low-frequency, high-value area (security
				// audit, a兜底 rule) must not be judged cold for being quiet.
				if (own.includes(GUARD_MARK)) continue;
				// Two link spellings exist: index-style `functions/<name>.md` and
				// bare sibling `](<name>.md)` inside functions/ files. Count both,
				// minus the file's own occurrences.
				const idxStyle = refText.split(`functions/${name}.md`).length - 1 - (own.split(`functions/${name}.md`).length - 1);
				const bareStyle = refText.split(`](${name}.md)`).length - 1 - (own.split(`](${name}.md)`).length - 1);
				const inbound = idxStyle + bareStyle;
				if (inbound === 0) {
					add('WARN', 'TEMP', `functions/${name}.md 除索引行外没有任何其他记忆引用（冷记忆）：确认它是仍在活跃维护，还是应并入相关功能域（memory_rename）或折叠（memory_fold）；低频高价值的记忆请用 memory_write guard=true 标为守护型`);
				}
			}
		}
	} catch {
		/* temperature analysis is best-effort */
	}

	// R18 (circuit breaker): a function area that keeps getting corrected is not
	// "another iteration" — the article's rule is that a hot area whose error
	// rate spikes should stop automatic appends and be rebuilt instead. Uses the
	// usage log (correction signals) when it exists; silent without signals.
	try {
		const usage = await readUsage(root, 7);
		if (usage.length) {
			const perHref = new Map();
			for (const e of usage) {
				const href = String(e.href ?? '');
				if (!href.startsWith('functions/')) continue;
				const cur = perHref.get(href) ?? { uses: 0, corrections: 0 };
				if (e.kind === 'recall' || e.kind === 'read') cur.uses++;
				else if (e.kind === 'correction') cur.corrections++;
				perHref.set(href, cur);
			}
			for (const [href, c] of perHref) {
				if (c.corrections >= 3 && c.corrections / Math.max(1, c.uses + c.corrections) > 0.4) {
					add('WARN', 'R18', `${href} 近 7 天被纠正 ${c.corrections} 次、使用 ${c.uses} 次（纠正率 > 40%）：熔断——先重构该域再继续追加迭代，别把问题压进历史`);
				}
			}
		}
	} catch {
		/* usage log is optional */
	}

	// R22 (insight trust): an idea whose corrections reached its confirmations
	// is being overturned by real use — the same circuit-breaker logic as R18,
	// lifted from function areas to the principle layer (Hindsight refines a
	// belief instead of replacing it silently).
	try {
		const usage = await readUsage(root, 30);
		if (usage.length) {
			for (const it of summarizeUsage(usage)) {
				if (!it.href.startsWith('insights/')) continue;
				const trust = insightTrust(it);
				if (trust.level === '动摇') {
					add('WARN', 'R22', `${it.href} 认可 ${trust.positives} 次被纠正追平/反超（${trust.corrections} 次）：该思想正被动摇——精炼原则本体或 memory_insight(supersedes) 取代它`);
				}
			}
		}
	} catch {
		/* usage log is optional */
	}

	const warnCount = results.filter((r) => r.level === 'WARN').length;
	const failCount = results.filter((r) => r.level === 'FAIL').length;
	return { root, results, warnCount, failCount };
}

/**
 * Panel presentation view of a health result: an uninitialized memory root
 * (the only problem is R0) is a neutral "not yet started" state, not a FAIL —
 * the agent-facing memory_check keeps R0 as FAIL to prompt the first write.
 */
function panelizeHealth(health) {
	const uninit = health.results.length === 1 && health.results[0].rule === 'R0';
	return {
		root: health.root,
		initialized: !uninit,
		failCount: uninit ? 0 : health.failCount,
		warnCount: uninit ? 0 : health.warnCount,
		results: uninit ? [] : health.results,
	};
}

// ---------------------------------------------------------------------------
// tools
// ---------------------------------------------------------------------------

function memoryReadTool(opts) {
	return defineTool({
		name: 'memory_read',
		description:
			'Read the function-area project memory. Start with kind=index (MEMORY.md: dual tables whose one-line summaries let you judge relevance without opening files, plus consensus and env constants), then open the exact function/insight file you need. Daily logs are one-line decision threads (kind=daily defaults to the latest day). kind=function/insight WITHOUT a name lists that directory with sizes.',
		parameters: {
			kind: {
				type: 'string',
				required: true,
				enum: ['index', 'function', 'insight', 'capability', 'skill', 'daily'],
				description: 'index=MEMORY.md; function=functions/<name>.md; insight=insights/<name>.md; capability=capabilities/<name>.md (CLI/MCP ledger); skill=skills/<name>.md (crystallized procedure); daily=YYYY-MM-DD.md (latest when date omitted).',
			},
			name: {
				type: 'string',
				description: 'Feature or theme slug (no .md). Required for reading one file; omit to list the directory.',
			},
			date: { type: 'string', description: 'YYYY-MM-DD for kind=daily; defaults to the latest daily log.' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					found: { type: 'boolean', required: true },
					path: { type: 'string', required: true },
					content: { type: 'string', required: true },
					listing: {
						type: 'array',
						required: true,
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								name: { type: 'string', required: true },
								bytes: { type: 'integer', required: true },
								mtime: { type: 'string', required: true },
							},
						},
					},
				},
			},
			render: (_args, v) => {
				if (!v.found && v.listing.length === 0) {
					return [{ type: 'text', text: `未找到：${v.path}。记忆还是空的——先用 memory_write 记录第一次迭代。` }];
				}
				if (v.content) return [{ type: 'text', text: v.content }];
				if (v.listing.length) {
					return [{ type: 'text', text: v.listing.map((e) => `- ${e.name}（${e.bytes}B，更新于 ${e.mtime}）`).join('\n') }];
				}
				return [{ type: 'text', text: `${v.path} 存在但为空。` }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Read memory: ${args.kind}${args.name ? `/${args.name}` : ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			if (args.kind === 'index') {
				const p = path.join(root, 'MEMORY.md');
				const text = await readIfExists(p);
				return { found: text !== undefined, path: p, content: text ?? '', listing: [] };
			}
			if (args.kind === 'function' || args.kind === 'insight' || args.kind === 'capability' || args.kind === 'skill') {
				const dir = path.join(root, args.kind === 'function' ? 'functions' : args.kind === 'insight' ? 'insights' : args.kind === 'skill' ? SKILL_DIR : CAP_DIR);
				if (!args.name) {
					const listing = await listMdDir(dir);
					return { found: listing.length > 0, path: dir, content: '', listing };
				}
				const slug = safeSlug(args.name);
				const p = path.join(dir, `${slug}.md`);
				const text = await readIfExists(p);
				if (text === undefined) {
					const listing = await listMdDir(dir);
					return { found: false, path: p, content: '', listing };
				}
				await appendUsage(root, { href: `${args.kind === 'function' ? 'functions' : 'insights'}/${slug}.md`, kind: 'read' });
				return { found: true, path: p, content: text, listing: [] };
			}
			// daily
			if (typeof args.date === 'string' && /^\d{4}-\d{2}-\d{2}$/.test(args.date.trim())) {
				const p = path.join(root, `${args.date.trim()}.md`);
				const text = await readIfExists(p);
				if (text !== undefined) await appendUsage(root, { href: `${args.date.trim()}.md`, kind: 'read' });
				return { found: text !== undefined, path: p, content: text ?? '', listing: [] };
			}
			let latest;
			try {
				for (const f of await readdir(root)) {
					if (/^\d{4}-\d{2}-\d{2}\.md$/.test(f) && (!latest || f > latest)) latest = f;
				}
			} catch {
				/* root missing */
			}
			const p = latest ? path.join(root, latest) : path.join(root, `${localDateStr()}.md`);
			const text = latest ? await readIfExists(p) : undefined;
			return { found: text !== undefined, path: p, content: text ?? '', listing: [] };
		},
	});
}

// ---------------------------------------------------------------------------
// memory_search — on-demand ranked retrieval over the whole memory root
// ---------------------------------------------------------------------------

function memorySearchTool(opts) {
	return defineTool({
		name: 'memory_search',
		description:
			'Ranked full-text search across the ENTIRE memory root (index, functions/, insights/, daily logs) and return the best matching lines with their zone, file, line number, section heading and a snippet. Use it when you remember something was recorded but cannot tell which function area or which day: memory_read kind=index only scans one-line summaries, while this scans the bodies. Ranking is lexical (query substring, token hits, section heading, file name) with per-file caps, so a broad keyword does not return one file\'s whole history. Read the file afterwards with memory_read before re-deriving anything. Temporal queries (「上个月怎么解决的」) use after/before: every hit carries its attributed date (iteration-block tag → file-head date → filename → mtime) and the bounds filter inclusively.',
		parameters: {
			q: { type: 'string', required: true, description: '检索词：一个词或短句（≥2 字符）。中文子串与英文单词都支持。' },
			zone: { type: 'string', enum: ['all', 'functions', 'insights', 'capabilities', 'skills', 'daily'], description: '限定检索分区，缺省 all（含索引）。能力台账（CLI/MCP/本地工具）在 capabilities，技能程序在 skills。' },
			limit: { type: 'integer', description: '最多返回多少条命中（默认 20，最大 50）。' },
			after: { type: 'string', description: '时间下限 YYYY-MM-DD（含）：只看这天及之后的内容。迭代块按 [日期] 标签归属，文件其余按头部「截至」日期，每日按文件名，无日期文件按 mtime——问“上个月怎么解决的”用它。' },
			before: { type: 'string', description: '时间上限 YYYY-MM-DD（含）。与 after 成对使用框出一个区间。' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					count: { type: 'integer', required: true },
					hits: {
						type: 'array',
						required: true,
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								zone: { type: 'string', required: true },
								name: { type: 'string', required: true },
								line: { type: 'integer', required: true },
								heading: { type: 'string', required: true },
								snippet: { type: 'string', required: true },
								date: { type: 'string', required: true, description: '命中行的归属日期（迭代块标签 / 文件头 / 文件名 / mtime 逐级解析，可能为空串=未知）' },
							},
						},
					},
				},
			},
			render: (_args, v) => {
				if (!v.count) return [{ type: 'text', text: '没有命中：换一个更具体的关键词，或先 memory_read kind=index 看分区摘要。' }];
				const lines = [`命中 ${v.count} 条（按相关度排序）：`];
				for (const h of v.hits) {
					lines.push(`- [${h.zone}] ${h.name}:${h.line}${h.date ? ` · ${h.date}` : ''}${h.heading ? ` · ${h.heading}` : ''} — ${h.snippet}`);
				}
				lines.push('调用 memory_read 打开命中文件确认上下文，再决定是否追加迭代。');
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Search memory: ${args.q ?? ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			const q = oneLine(args.q);
			if (charLen(q) < 2) throw new Error('q must be at least 2 characters');
			const zone = ['functions', 'insights', 'capabilities', 'skills', 'daily'].includes(args.zone) ? args.zone : 'all';
			const limit = Math.min(Math.max(1, Number(args.limit) || 20), 50);
			// Date bounds: accept YYYY-MM-DD (tolerating spaces) or reject loudly —
			// a silently-ignored `after: 上个月` would return everything and be
			// trusted as a filtered answer.
			const normBound = (v, label) => {
				if (v === undefined || v === '') return '';
				const s = String(v).trim();
				// Format AND calendar validity: `2026-13-99` compares as a string but
				// means nothing — a bound that cannot be a real date must fail loud,
				// because a silently-wrong filter is worse than no filter.
				if (!/^\d{4}-\d{2}-\d{2}$/.test(s) || !Number.isFinite(Date.parse(s))) {
					throw new Error(`${label} 必须是有效日期 YYYY-MM-DD（收到：${s.slice(0, 24)}）`);
				}
				return s;
			};
			const after = normBound(args.after, 'after');
			const before = normBound(args.before, 'before');
			if (after && before && after > before) throw new Error(`after ${after} 晚于 before ${before}：区间为空`);
			const hits = await searchMemory(root, q, { zone, limit, after, before });
			return { count: hits.length, hits };
		},
	});
}

// ---------------------------------------------------------------------------
// federation (three-tier mode): project truth sources -> federation layer -> global
// ---------------------------------------------------------------------------
// (FED_* table constants live in src/constants.js)

/** Read + validate the federation config; throws with an explicit fix-it message. */
function federationConfig(opts) {
	const fed = opts.federation;
	if (!fed || typeof fed !== 'object') {
		throw new Error('未配置联邦模式：在插件配置里给出 federation: { root, projects: [{ key, root }] }');
	}
	if (!fed.root || typeof fed.root !== 'string') throw new Error('federation.root 缺失（联邦层记忆根目录）');
	const projects = Array.isArray(fed.projects) ? fed.projects : [];
	if (!projects.length) throw new Error('federation.projects 为空：至少列出 { key, root } 两个字段');
	const seen = new Set();
	const out = projects.map((p) => {
		const key = String(p?.key ?? '').trim();
		if (!key) throw new Error('federation.projects 每一项都需要 key');
		if (!/^[\w\u4e00-\u9fff.-]{1,40}$/.test(key)) throw new Error(`项目 key 不合法（不要带路径分隔符）：${key}`);
		const lower = key.toLowerCase();
		if (seen.has(lower)) throw new Error(`项目 key 重复：${key}`);
		seen.add(lower);
		if (!p?.root || typeof p.root !== 'string') throw new Error(`项目 ${key} 缺 root（该项目记忆根目录）`);
		return { key, root: path.resolve(p.root) };
	});
	return { root: path.resolve(fed.root), projects: out };
}

/** Mechanical federation index: one row per project (no semantic fusion here). */
function federationIndexText(rows) {
	return [
		'# 联邦记忆（跨项目索引）',
		'',
		'> 本层只做**跨项目整合**：项目真相源留在各项目自己的记忆根，这里存它们 `MEMORY.md` 的副本与一张项目索引。',
		'> `memory_federation(action=sync)` 刷新副本与索引行；跨项目共识由模型蒸馏后写在下方小节，不自动生成。',
		'',
		FED_TABLE_HEADING,
		'',
		FED_TABLE_HEADER,
		'|---|---|---|',
		...rows,
		'',
		FED_CONSENSUS_HEADING,
		'',
		'- ',
		'',
	].join('\n');
}

// ---------------------------------------------------------------------------
// memory_usage — usage signals and data-driven layer suggestions
// ---------------------------------------------------------------------------

function memoryUsageTool(opts) {
	return defineTool({
		name: 'memory_usage',
		description:
			'Record and read USAGE signals, the data that lets the memory sort itself. action=record logs one event against a memory file (kind: correction = the user corrected / rejected what was recalled or written; positive = explicit confirmation like "对了/就是这个"; recall/read are logged automatically). action=report aggregates the last N days per file and suggests a layer: 实验 (<3 uses), 专项 (>=3 uses + >=1 confirmation), 通用 (>=10 uses + >=2 confirmations + correction rate <20%). Layers are suggestions for the model to act on — this tool never moves files.',
		parameters: {
			action: { type: 'string', required: true, enum: ['record', 'report'], description: 'record=记一次信号；report=按天聚合出分层建议。' },
			href: { type: 'string', description: 'record 必填：目标记忆文件，如 `functions/批印坊工程加固.md`、`insights/逐帧渲染取帧三闸.md`、`2026-10-18.md`。' },
			kind: { type: 'string', enum: ['correction', 'positive', 'recall', 'read'], description: 'record 必填：correction=用户纠正/否定，positive=用户明确认可，recall/read 一般由插件自动记录。' },
			note: { type: 'string', description: 'record 可选：一句话说明（例如用户原话），便于日后复盘。' },
			days: { type: 'integer', description: 'report 的统计窗口（天，默认 30）。' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					action: { type: 'string', required: true },
					days: { type: 'integer', required: true },
					items: {
						type: 'array',
						required: true,
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								href: { type: 'string', required: true },
								uses: { type: 'integer', required: true },
								recalls: { type: 'integer', required: true },
								reads: { type: 'integer', required: true },
								corrections: { type: 'integer', required: true },
								positives: { type: 'integer', required: true },
								badRate: { type: 'number', required: true },
								flips: { type: 'integer', required: true },
								layer: { type: 'string', required: true },
								lastUsed: { type: 'string', required: true },
							},
						},
					},
					warnings: { type: 'array', required: true, items: { type: 'string' } },
				},
			},
			render: (_args, v) => {
				// action=record carries its confirmation in `warnings` with an empty
				// items list; the generic "no signals yet" branch below swallowed
				// that receipt, so a successful record looked like a no-op.
				if (v.action === 'record') {
					return [{ type: 'text', text: v.warnings.length ? v.warnings.join('\n') : '已记录使用信号。' }];
				}
				if (!v.items.length) return [{ type: 'text', text: '还没有使用信号。信号来自召回注入、memory_read、以及你用 memory_usage(action=record) 记录的纠正/认可。' }];
				const lines = [`近 ${v.days} 天使用信号（按使用次数排序）：`];
				for (const it of v.items) {
					lines.push(`- [${it.layer}] ${it.href} · 用 ${it.uses}（召回 ${it.recalls}/读 ${it.reads}）· 纠正 ${it.corrections} · 认可 ${it.positives} · 纠正率 ${it.badRate}${it.flips ? ` · 翻转 ${it.flips}` : ''}`);
				}
				for (const w of v.warnings) lines.push(`⚠ ${w}`);
				lines.push('层只是建议：通用=可进默认推荐，专项=常规池，实验=仍在小范围验证。');
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Memory usage: ${args.action ?? ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			const days = Math.min(Math.max(1, Number(args.days) || 30), 365);
			const warnings = [];
			if (args.action === 'record') {
				const href = oneLine(args.href);
				if (!/^(functions|insights)\/[^/]+\.md$/.test(href) && !/^\d{4}-\d{2}-\d{2}\.md$/.test(href)) {
					throw new Error('href 必须是 functions/<名>.md、insights/<名>.md 或 YYYY-MM-DD.md');
				}
				const kind = ['correction', 'positive', 'recall', 'read'].includes(args.kind) ? args.kind : null;
				if (!kind) throw new Error('kind 必须是 correction / positive / recall / read');
				await appendUsage(root, { href, kind, note: oneLine(args.note ?? '') || undefined });
				return { action: 'record', days, items: [], warnings: [`已记录：${kind} → ${href}${args.note ? `（${oneLine(args.note)}）` : ''}`] };
			}
			const entries = await readUsage(root, days);
			const items = summarizeUsage(entries).map((it) => ({
				href: it.href,
				uses: it.uses,
				recalls: it.recalls,
				reads: it.reads,
				corrections: it.corrections,
				positives: it.positives,
				badRate: it.badRate,
				flips: it.flips,
				layer: it.layer,
				lastUsed: new Date(it.last).toISOString(),
			}));
			const hot = items.filter((it) => it.layer === '通用').length;
			if (hot) warnings.push(`${hot} 条已达到「通用」建议线：可考虑在索引行里标明它是标配工具，或让它进默认推荐`);
			const bad = items.filter((it) => it.uses >= 3 && it.badRate > 0.4);
			for (const b of bad) warnings.push(`${b.href} 纠正率 ${Math.round(b.badRate * 100)}%（>40%）：先重构这条记忆，别继续往上叠迭代`);
			// Flips: confirmed then overturned (or the reverse). Two or more means the
			// memory keeps changing verdicts — the content is unstable, not unlucky.
			for (const f of items.filter((it) => it.flips >= 2)) {
				warnings.push(`${f.href} 结论被反复推翻（翻转 ${f.flips} 次）：先查清到底哪个判断成立，再决定保留哪一版——反复推翻的记忆不能当依据`);
			}
			return { action: 'report', days, items, warnings };
		},
	});
}

function memoryFederationTool(opts) {
	return defineTool({
		name: 'memory_federation',
		description:
			'Three-tier federation mode (opt-in via plugin config `federation: { root, projects: [{ key, root }] }`). action=sync copies every configured project\'s MEMORY.md into `<federation.root>/sources/<key>.MEMORY.md` and rebuilds the federation index table (one mechanical row per project: size + link). action=check lints the federation layer: missing index, dangling links, missing project roots, missing/orphan copies, and env-constant absolute paths that no longer exist. Project truth sources are never edited by this tool, and cross-project consensus is NOT auto-distilled — the model writes that section itself.',
		parameters: {
			action: { type: 'string', required: true, enum: ['sync', 'check'], description: 'sync=刷新副本与索引行；check=只读体检（F1–F5）。' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					action: { type: 'string', required: true },
					federationRoot: { type: 'string', required: true },
					projects: {
						type: 'array',
						required: true,
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								key: { type: 'string', required: true },
								copied: { type: 'boolean', required: true },
								bytes: { type: 'integer', required: true },
								functions: { type: 'integer', required: true },
								insights: { type: 'integer', required: true },
								daily: { type: 'integer', required: true },
							},
						},
					},
					findings: {
						type: 'array',
						required: true,
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								level: { type: 'string', required: true, enum: ['WARN', 'FAIL'] },
								rule: { type: 'string', required: true },
								message: { type: 'string', required: true },
							},
						},
					},
					failCount: { type: 'integer', required: true },
					warnCount: { type: 'integer', required: true },
				},
			},
			render: (_args, v) => {
				const lines = [
					`联邦层：${v.federationRoot}（${v.action}）`,
					...v.projects.map((p) => `- ${p.key}: ${p.copied ? '已同步' : '未同步'} · ${p.bytes}B · ${p.functions} 功能 / ${p.insights} 思想 / ${p.daily} 日线索`),
				];
				if (!v.findings.length) lines.push('体检：全部通过（F1–F5）');
				else {
					lines.push(`体检：${v.failCount} FAIL，${v.warnCount} WARN`);
					for (const f of v.findings) lines.push(`  [${f.level}] ${f.rule}: ${f.message}`);
				}
				if (v.action === 'sync') lines.push('ℹ 跨项目共识不会自动生成——需要时把蒸馏结论写进「跨项目共识」小节。');
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Memory federation: ${args.action ?? ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const fed = federationConfig(opts);
			const findings = [];
			const add = (level, rule, message) => findings.push({ level, rule, message });
			const sourcesDir = path.join(fed.root, 'sources');
			await mkdir(sourcesDir, { recursive: true });
			const projects = [];
			for (const p of fed.projects) {
				const memPath = path.join(p.root, 'MEMORY.md');
				const text = await readIfExists(memPath);
				const counts = await zoneCounts(p.root);
				if (text === undefined) {
					add('FAIL', 'F3', `项目 ${p.key} 的记忆根里没有 MEMORY.md：${p.root}`);
					projects.push({ key: p.key, copied: false, bytes: 0, ...counts });
					continue;
				}
				const bytes = byteLen(text);
				let copied = false;
				if (args.action === 'sync') {
					await writeText(path.join(sourcesDir, `${p.key}.MEMORY.md`), text);
					copied = true;
				} else {
					copied = await statExists(path.join(sourcesDir, `${p.key}.MEMORY.md`));
					if (!copied) add('FAIL', 'F3', `缺少来源副本 sources/${p.key}.MEMORY.md（先 action=sync）`);
				}
				projects.push({ key: p.key, copied, bytes, ...counts });
			}
			const indexPath = path.join(fed.root, 'MEMORY.md');
			if (args.action === 'sync') {
				const rows = projects.map((p) => `| ${p.key} | ${p.functions} 功能 · ${p.insights} 思想 · ${p.daily} 日线索 · ${p.bytes}B | [sources/${p.key}.MEMORY.md](sources/${p.key}.MEMORY.md) |`);
				const existing = await readIfExists(indexPath);
				let next = federationIndexText(rows);
				if (existing !== undefined) {
					// Keep everything the model distilled (consensus + notes) and only
					// replace this tool's own table block.
					next = existing.replace(/\n## 项目索引（联邦层）[\s\S]*?(?=\n## |$)/, `\n${FED_TABLE_HEADING}\n\n${[FED_TABLE_HEADER, '|---|---|---|', ...rows].join('\n')}\n`);
					if (!next.includes(FED_TABLE_HEADING)) next = federationIndexText(rows);
				}
				await writeText(indexPath, next);
			} else {
				// F1: federation index exists
				const idxText = await readIfExists(indexPath);
				if (idxText === undefined) {
					add('FAIL', 'F1', `联邦层没有 MEMORY.md：${indexPath}（先 action=sync）`);
				} else {
					// F2: in-tree links resolve (the shared link scanner reports R10/R10e;
					// remap it to the federation rule names so findings read coherently).
					await checkLinks(idxText, indexPath, fed.root, (level, rule, message) => add(level, rule.startsWith('R10') ? 'F2' : rule, message));
					for (const m of idxText.matchAll(/`([^`\n|]+)`/g)) {
						const p0 = m[1].trim().replace(/[/\\]+$/, '');
						if (!/^[A-Za-z]:[\\/]/.test(p0) && !p0.startsWith('/')) continue;
						if (!(await statExists(p0))) add('WARN', 'F4', `联邦层引用的绝对路径已不存在 -> ${p0}`);
					}
					// F5: orphan copies
					let copies = [];
					try {
						copies = (await readdir(sourcesDir)).filter((n) => n.endsWith('.MEMORY.md'));
					} catch {
						/* none */
					}
					for (const c of copies) {
						if (!fed.projects.some((p) => `${p.key}.MEMORY.md` === c)) {
							add('WARN', 'F5', `孤儿副本 sources/${c} 不对应任何已配置项目（移走或补配置）`);
						}
					}
					for (const p of fed.projects) {
						if (!idxText.includes(`sources/${p.key}.MEMORY.md`)) add('FAIL', 'F3', `项目索引表缺少 ${p.key} 一行（重新 sync）`);
					}
				}
			}
			const failCount = findings.filter((f) => f.level === 'FAIL').length;
			const warnCount = findings.filter((f) => f.level === 'WARN').length;
			return { action: args.action, federationRoot: fed.root, projects, findings, failCount, warnCount };
		},
	});
}

async function listMdDir(dir) {
	let entries = [];
	try {
		entries = await readdir(dir);
	} catch {
		return [];
	}
	const out = [];
	for (const f of entries.filter((n) => n.endsWith('.md')).sort()) {
		const st = await stat(path.join(dir, f));
		out.push({ name: f.replace(/\.md$/, ''), bytes: st.size, mtime: st.mtime.toISOString() });
	}
	// Newest-first: every listing consumer (model recall, panel) wants the
	// latest state at the top, not a file-manager's alphabetical order.
	out.sort((a, b) => String(b.mtime).localeCompare(String(a.mtime)));
	return out;
}

// ---------------------------------------------------------------------------
// memory_capability — the tool/MCP ledger ("what can I use to solve this?")
// ---------------------------------------------------------------------------
//
// The other zones answer "how did we do it" (functions/), "what principle holds"
// (insights/), "what happened when" (daily). None of them answers "which CLI,
// MCP server or local tool exists for this job, and how do I call it" — so every
// session rediscovers it. This zone is a ledger of capability: one file per
// tool/server, with the exact invocation, the prerequisites, and what it solved.
// (CAP_DIR lives in src/constants.js)

// ---------------------------------------------------------------------------
// skills — the crystallization layer (borrowed from MemOS's skill tier, adapted)
// ---------------------------------------------------------------------------
//
// The data flow records / distills / promotes / displays, but never CLOSED the
// loop into "use": an operation that keeps being re-run and keeps being confirmed
// should become a directly callable procedure. MemOS does this with an async LLM
// pipeline (L1→L2→L3→Skill with V/α/gain math); we keep the file discipline —
// MECHANICAL NOMINATION (pure aggregation of the usage signals we already
// collect) + A JUDGEMENT CRYSTALLIZES (only the model in context knows whether
// the evidence is coherent enough to write a real procedure).
// (SKILL_* constants live in src/constants.js)

/**
 * Skill file format — the frontmatter idea is borrowed from Anthropic/lantern
 * skill-creator (skills/<name> + YAML frontmatter, description is the ROUTER
 * that decides when the skill fires, imperative writing style, machine-checkable
 * fields), adapted to our one-file-per-skill layout. `status` extends the
 * frontmatter with our lifecycle; `agent_created` marks files this tool owns.
 */
/**
 * Skill-name grammar comes from the bridge module (one source with the host
 * provider); the harness drift-guard compares it against the real package.
 */

function skillTemplate(name, f) {
	return [
		'---',
		`name: ${name}`,
		`description: "${f.description}"`,
		`whenToUse: "${f.when.replace(/"/g, "'")}"`,
		// Host interoperability (5.17.0): the filesystem provider only admits
		// kebab-case names, and a Chinese slug can never be one. hostName is the
		// OPTIONAL address the skill takes in the host catalog; without it the
		// skill still works through our own recall but is never registered to
		// ctx.skills. (isSkillName in src/host-skill.js validates it.)
		...(f.hostName ? [`hostName: ${f.hostName}`] : []),
		'agent_created: true',
		// Scope metadata (memory-function-org §技能作用域元数据): an owned skill
		// MUST carry scope — the audit WARNs without it, and cross-project recall
		// has no way to tell "applies everywhere" from "only valid in project A".
		`scope: ${f.scope}`,
		...(f.scope === 'project' && f.scopeProject ? [`scope_project: ${f.scopeProject}`] : []),
		...(f.scopeNotes ? [`scope_notes: "${f.scopeNotes.replace(/"/g, "'")}"`] : []),
		`status: ${f.status}`,
		`created: ${f.date}`,
		`sources: [${f.srcs.join(', ')}]`,
		'---',
		'',
		`# 技能：${name}`,
		'',
		`> 摘要：${f.summary}`,
		'',
		'## 何时使用',
		'',
		`- ${f.when}`,
		'',
		'## 调用步骤',
		'',
		f.steps.map((s, i) => `${i + 1}. ${s}`).join('\n'),
		'',
		'## 前提与坑',
		'',
		`- ${f.pitfalls || '（待补：跑的过程中把踩到的坑记回这里）'}`,
		'',
		'## 验证方式',
		'',
		`- ${f.verification}`,
		'',
		'## 证据来源',
		'',
		...f.srcLines,
		'',
		'## 使用记录',
		'',
		`- ${f.date} 结晶（${f.status}）`,
		...(f.priorUse ?? []),
		'',
	].join('\n');
}

/**
 * Pure nomination pass over the SAME usage aggregation memory_usage uses: an
 * href is a skill candidate when uses/positives/bad-rate clear the floors and
 * no skill file yet points at it. Returns the rows a `memory_skill(candidates)`
 * call shows the model. `skillSources` = the 来源 lines of existing skill files
 * (so nominated-but-already-crystallized areas drop out).
 */
function nominateSkillCandidates(usageItems, skillSources) {
	const out = [];
	for (const it of usageItems) {
		if (!/^(functions|insights)\//.test(it.href)) continue;
		if (it.uses < SKILL_NOMINATE.minUses) continue;
		if (it.positives < SKILL_NOMINATE.minPositives) continue;
		if (it.badRate >= SKILL_NOMINATE.maxBadRate) continue;
		const already = skillSources.some((src) => src === it.href || it.href.startsWith(src.replace(/\.md$/, '')));
		if (already) continue;
		out.push({ href: it.href, uses: it.uses, positives: it.positives, badRate: it.badRate, flips: it.flips });
	}
	// Most-used first; flips included so an unstable conclusion is visible, not
	// silently nominated.
	out.sort((a, b) => b.uses - a.uses);
	return out;
}

function capabilityTemplate(name, kind, date) {
	return [
		`# 能力：${name}`,
		'',
		`> 类型：${kind} · 首次登记：${date}`,
		'> 用途：任务开始前查这张台账，知道「有什么工具能用、怎么调」；不要重复摸索同一个工具。',
		'',
		'## 调用方式',
		'',
		'- ',
		'',
		'## 前提 / 环境',
		'',
		'- ',
		'',
		'## 解决过什么',
		'',
		'- ',
		'',
	].join('\n');
}

function memoryCapabilityTool(opts) {
	return defineTool({
		name: 'memory_capability',
		description:
			'Record or look up an EXTERNAL CAPABILITY: a third-party CLI, MCP server, local binary, or installed software the agent can call. The boundary is what counts as external — do NOT record (a) the harness\'s own built-in tools (shell/file/web/scheduler: the agent already knows them, recording is pure noise), (b) the project\'s own scripts or the plugin\'s own API (that is a functions/ iteration block), (c) anything the system provides natively. Record a tool only when USING it took discovery: the exact invocation, prerequisites, and the traps hit. The other zones answer "how we did it" / "what principle holds" / "what happened"; this one answers "what can I USE for this job, and how exactly do I invoke it". Use action=record after you discover or successfully use such a tool; use action=list before starting a task to see what is already available instead of rediscovering it. This is a CAPABILITY ledger, not an iteration log: per-tool one file, updated in place, never a dated journal.',
		parameters: {
			action: { type: 'string', required: true, enum: ['record', 'list', 'read'], description: 'record=登记/更新一个能力；list=列出全部能力（含一句话摘要）；read=读某个能力的完整台账。' },
			name: { type: 'string', description: 'record/read 必填：能力名（作为文件名），如 `ffmpeg`、`gh-cli`、`playwright-mcp`。' },
			kind: { type: 'string', enum: ['cli', 'mcp', 'binary', 'service', 'skill', 'other'], description: 'record 可选：能力类型，缺省 cli。' },
			invocation: { type: 'string', description: 'record 必填：怎么调用（真实可执行的命令或调用形式，一句话）。' },
			prereq: { type: 'string', description: 'record 可选：前提/环境（路径、token、版本、启动方式）。' },
			solved: { type: 'string', description: 'record 可选：用它解决过什么（一句话；可多次 record 追加）。' },
			summary: { type: 'string', description: 'record 可选：一句话摘要（进索引与列表用），缺省取 invocation 首句。' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					action: { type: 'string', required: true },
					file: { type: 'string' },
					created: { type: 'boolean' },
					items: {
						type: 'array',
						required: true,
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								name: { type: 'string', required: true },
								kind: { type: 'string', required: true },
								summary: { type: 'string', required: true },
								invocation: { type: 'string', required: true },
								updated: { type: 'string', required: true },
							},
						},
					},
					content: { type: 'string' },
					warnings: { type: 'array', required: true, items: { type: 'string' } },
				},
			},
			render: (_args, v) => {
				if (v.action === 'read') return [{ type: 'text', text: v.content || '（空）' }];
				if (v.action === 'record') {
					const lines = [`已登记能力：${v.file}${v.created ? '（新建）' : '（更新）'}`];
					for (const w of v.warnings) lines.push(`⚠ ${w}`);
					lines.push('ℹ 下次做任务前先 memory_capability(action=list) 看有没有现成的。');
					return [{ type: 'text', text: lines.join('\n') }];
				}
				if (!v.items.length) return [{ type: 'text', text: '能力台账还是空的。用到某个 CLI/MCP/本地工具后，用 memory_capability(action=record) 记一笔：调用方式、前提、解决过什么。' }];
				const lines = [`能力台账（${v.items.length} 项）：`];
				for (const it of v.items) lines.push(`- [${it.kind}] ${it.name} — ${it.summary}${it.invocation ? ` ｜ 调用：${it.invocation}` : ''}`);
				for (const w of v.warnings) lines.push(`⚠ ${w}`);
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Memory capability: ${args.action ?? ''}${args.name ? ` ${args.name}` : ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			const dir = path.join(root, CAP_DIR);
			const warnings = [];
			if (args.action === 'list') {
				let names = [];
				try {
					names = (await readdir(dir)).filter((n) => n.endsWith('.md'));
				} catch {
					/* no ledger yet */
				}
				const items = [];
				for (const f of names.sort()) {
					const text = (await readIfExists(path.join(dir, f))) ?? '';
					const kindM = text.match(/^> 类型：([^\s·]+)/m);
					const invM = text.match(/## 调用方式\s*\n+-\s*(.+)/);
					const summaryM = text.match(/^>\s*摘要：(.+)$/m);
					const st = await stat(path.join(dir, f));
					items.push({
						name: f.replace(/\.md$/, ''),
						kind: kindM ? kindM[1] : 'other',
						summary: summaryM ? summaryM[1].trim() : (invM ? invM[1].trim().slice(0, 80) : '（无摘要）'),
						invocation: invM ? invM[1].trim().slice(0, 120) : '',
						updated: st.mtime.toISOString(),
					});
				}
				return { action: 'list', items, warnings };
			}
			const name = safeSlug(args.name);
			const p = path.join(dir, `${name}.md`);
			if (args.action === 'read') {
				const text = await readIfExists(p);
				if (text === undefined) throw new Error(`能力台账里没有 ${name}（先 memory_capability(action=record)）`);
				return { action: 'read', file: p, items: [], content: text, warnings };
			}
			// record / update
			const invocation = oneLine(args.invocation);
			if (!invocation) throw new Error('invocation is required: the exact command or call form, so the next session does not rediscover it');
			const kind = ['cli', 'mcp', 'binary', 'service', 'skill', 'other'].includes(args.kind) ? args.kind : 'cli';
			const date = localDateStr();
			const existing = await readIfExists(p);
			let text;
			const created = existing === undefined;
			if (created) {
				text = capabilityTemplate(name, kind, date);
			} else {
				text = existing;
			}
			// invocation: replace the section body (single source of truth)
			text = replaceSection(text, '## 调用方式', `- ${invocation}`);
			if (args.prereq !== undefined && oneLine(args.prereq)) {
				text = appendUnderHeading(text, '## 前提 / 环境', `- ${oneLine(args.prereq)}`).text;
			}
			if (args.solved !== undefined && oneLine(args.solved)) {
				text = appendUnderHeading(text, '## 解决过什么', `- ${date} ${oneLine(args.solved)}`).text;
			}
			const summary = oneLine(args.summary ?? '') || invocation.slice(0, 80);
			if (!/^>\s*摘要：/m.test(text)) {
				// keep the summary line right under the type line
				text = text.replace(/^(> 类型：.*)$/m, `$1\n> 摘要：${summary}`);
			} else {
				text = text.replace(/^>\s*摘要：.*$/m, `> 摘要：${summary}`);
			}
			const wroteCap = await writeText(p, text);
			if (wroteCap?.hits?.length) {
				warnings.push(`台账内容含凭据材料（${wroteCap.hits.join('、')}），落盘前已 redact——调用方式里留密钥没有意义，留调用形态即可`);
			}
			// Keep the index row in sync: the capability table is the "what can I
			// use" lookup surface, and a ledger nobody indexes is a ledger nobody
			// finds.
			const indexPath = path.join(root, 'MEMORY.md');
			let indexText = (await readIfExists(indexPath)) ?? memoryIndexTemplate();
			const row = `| [${name}](${CAP_DIR}/${name}.md) | ${summary} |`;
			indexText = upsertIndexRow(indexText, CAP_TABLE_HEADING, CAP_TABLE_HEADER, name, row);
			await writeText(indexPath, indexText);
			const st = await stat(p);
			return {
				action: 'record',
				file: p,
				created,
				items: [{ name, kind, summary, invocation, updated: st.mtime.toISOString() }],
				warnings,
			};
		},
	});
}

/**
 * memory_skill — the CRYSTALLIZATION layer (12th tool). Closes the loop the
 * four-layer flow left open: an operation that keeps being RE-RUN (uses) and
 * keeps being CONFIRMED (positives, low correction rate) should become a
 * directly callable procedure under skills/. Nomination is mechanical (usage
 * signals only, no guessing); crystallization is the model's judgement — this
 * tool never auto-writes a skill body. Lifecycle: candidate → active (verified)
 * → retired (environment changed; file kept as history). Borrowed from MemOS's
 * skill tier, adapted to the file discipline.
 */
function memorySkillTool(opts, hooks = {}) {
	// After any write that can change what the HOST catalog should contain
	// (crystallize / activate / retire), nudge the bridge to invalidate. A
	// failure here must never break the tool receipt.
	const publish = () => {
		try {
			hooks.onSkillChange?.();
		} catch {
			/* host refresh is best-effort; the disk is the source of truth */
		}
	};
	return defineTool({
		name: 'memory_skill',
		description:
			'Crystallize a REPEATED, CONFIRMED operation into a callable procedure under skills/ (the missing “use” step of the data flow: record → distill → promote → display → USE). actions: candidates = which areas the usage signals nominate (pure aggregation: >=6 uses, >=1 confirmation, correction rate <20%, not already crystallized) — call it periodically and decide; crystallize = write skills/<name>.md from an area\'s proven steps (YOU write the procedure, the tool files and indexes it, status=candidate); activate/retire = lifecycle transitions (activate only after the procedure was actually followed successfully; retire when the environment changed, the file stays as history); list/read = what skills exist / full text. A skill file answers “do it exactly like THIS” — distinct from capabilities/ (“what tool exists”) and insights/ (“what principle holds”). A crystallized skill carries scope (global/project) and, with a kebab-case hostName, is published to the host skill catalog once active so the `skill` tool can load it directly.',
		parameters: {
			action: { type: 'string', required: true, enum: ['candidates', 'crystallize', 'activate', 'retire', 'list', 'read'], description: 'candidates=看提名；crystallize=结晶一份技能；activate/retire=生命周期；list/read=查。' },
			name: { type: 'string', description: 'crystallize/activate/retire/read 必填：技能名（文件名 slug）。' },
			summary: { type: 'string', description: 'crystallize 必填：一句话用途（索引行与命中提示用）。' },
			when: { type: 'string', description: 'crystallize 必填：什么任务信号出现时该用这条技能（触发条件，一句话）。' },
			procedure: { type: 'array', description: 'crystallize 必填：可直接执行的步骤（每步一句，命令写全），items: { type: string }。', items: { type: 'string' } },
			pitfalls: { type: 'string', description: 'crystallize 可选：前提与踩过的坑（一段话）。' },
			verification: { type: 'string', description: 'crystallize 必填：怎么算执行成功（判据，一句话）。' },
			sources: { type: 'array', description: 'crystallize 必填：证据来源（functions/xxx.md 等，提名/召回据此关联），items: { type: string }。', items: { type: 'string' } },
			scope: { type: 'string', enum: ['global', 'project'], description: '可选：技能作用域（原 memory-function-org 纪律：自有技能必须带 scope）。缺省 global=跨项目通用；project=只适用于某一项目，此时应同时给 scopeProject。' },
			scopeProject: { type: 'string', description: 'scope=project 时必填：项目目录名/key（如 toolbox-login），召回与路由据此判适用性。' },
			scopeNotes: { type: 'string', description: '可选：一句话说明适用条件（何时在哪些项目用）。' },
			hostName: { type: 'string', description: '可选：本技能在宿主 skill 体系里的注册名（kebab-case，如 detached-restart）。给了就随 active 进宿主 ctx.skills 目录、被 skill 工具直接调用；不给则只走本插件召回。' },
			note: { type: 'string', description: 'activate/retire 可选：一句话依据（哪次成功验证 / 环境怎么变了）。' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					action: { type: 'string', required: true },
					file: { type: 'string' },
					created: { type: 'boolean' },
					status: { type: 'string' },
					candidates: {
						type: 'array',
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								href: { type: 'string', required: true },
								uses: { type: 'integer', required: true },
								positives: { type: 'integer', required: true },
								badRate: { type: 'number', required: true },
								flips: { type: 'integer', required: true },
							},
						},
					},
					items: {
						type: 'array',
						required: true,
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								name: { type: 'string', required: true },
								status: { type: 'string', required: true },
								summary: { type: 'string', required: true },
								updated: { type: 'string', required: true },
							},
						},
					},
					content: { type: 'string' },
					warnings: { type: 'array', required: true, items: { type: 'string' } },
				},
			},
			render: (_args, v) => {
				if (v.action === 'read') return [{ type: 'text', text: v.content || '（空）' }];
				if (v.action === 'candidates') {
					if (!v.candidates?.length) return [{ type: 'text', text: `暂无提名（门槛：≥${SKILL_NOMINATE.minUses} 次使用 + ≥${SKILL_NOMINATE.minPositives} 次确认 + 纠正率 <${SKILL_NOMINATE.maxBadRate * 100}%）。使用信号继续累积，隔段时间再查。` }];
					const lines = [`技能提名（机械信号，是否结晶由你判断）：`];
					for (const c of v.candidates) lines.push(`- ${c.href} · 用 ${c.uses} 次 · 确认 ${c.positives} · 纠正率 ${c.badRate}${c.flips ? ` · 翻转 ${c.flips}` : ''}`);
					lines.push('ℹ 反复重跑且被确认的操作 → memory_skill(crystallize) 写成可调用程序；不确定就再等等。');
					return [{ type: 'text', text: lines.join('\n') }];
				}
				if (v.action === 'list') {
					if (!v.items.length) return [{ type: 'text', text: '还没有技能。先 memory_skill(candidates) 看提名，再把反复验证过的操作结晶成程序。' }];
					const lines = [`技能台账（${v.items.length} 项）：`];
					for (const it of v.items) lines.push(`- [${it.status}] ${it.name} — ${it.summary}`);
					for (const w of v.warnings) lines.push(`⚠ ${w}`);
					return [{ type: 'text', text: lines.join('\n') }];
				}
				const verb = v.action === 'crystallize' ? '已结晶技能' : v.action === 'activate' ? '已激活技能' : '已退役技能';
				const lines = [`${verb}：${v.file}（status=${v.status}）`];
				for (const w of v.warnings) lines.push(`⚠ ${w}`);
				if (v.action === 'crystallize') lines.push('ℹ 按真实任务跑通一次后，用 memory_skill(activate) 转正；pre-step 会优先提示命中技能。');
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Memory skill: ${args.action ?? ''}${args.name ? ` ${args.name}` : ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			const dir = path.join(root, SKILL_DIR);
			const warnings = [];
			const listAll = async () => {
				let names = [];
				try {
					names = (await readdir(dir)).filter((n) => n.endsWith('.md'));
				} catch {
					/* no skills yet */
				}
				const items = [];
				for (const f of names.sort()) {
					const text = (await readIfExists(path.join(dir, f))) ?? '';
					// frontmatter `status:` is canonical; tolerate the pre-5.12 head
					// format ("> 状态：x") so hand-written or older files still parse.
					const stM = text.match(/^status:\s*([a-z]+)/m) ?? text.match(/^> 状态：([a-z]+)/m);
					const sumM = text.match(/^>\s*摘要：(.+)$/m) ?? text.match(/^description:\s*"?([^"\n]+)"?/m);
					const st = await stat(path.join(dir, f));
					items.push({ name: f.replace(/\.md$/, ''), status: stM ? stM[1] : 'candidate', summary: sumM ? sumM[1].trim() : '（无摘要）', updated: st.mtime.toISOString() });
				}
				return items;
			};
			const syncIndexRow = async (item) => {
				const indexPath = path.join(root, 'MEMORY.md');
				let indexText = (await readIfExists(indexPath)) ?? memoryIndexTemplate();
				const row = `| [${item.name}](${SKILL_DIR}/${item.name}.md) | ${item.summary} | ${item.status} |`;
				indexText = upsertIndexRow(indexText, SKILL_TABLE_HEADING, SKILL_TABLE_HEADER, item.name, row);
				await writeText(indexPath, indexText);
				// Every write that lands (crystallize/activate/retire all funnel here)
				// refreshes the host catalog — one choke point, no per-action miss.
				publish();
			};
			if (args.action === 'candidates') {
				const items = summarizeUsage(await readUsage(root));
				const all = await listAll();
				const skillSources = [];
				for (const it of all) {
					const text = (await readIfExists(path.join(dir, `${it.name}.md`))) ?? '';
					// evidence links are written as (../functions/x.md); normalize to
					// the usage-href form (functions/x.md) so nomination can compare.
					for (const m of text.matchAll(/\((?:\.\.\/)?((?:functions|insights)\/[^)#]+)\)/g)) skillSources.push(m[1]);
				}
				const candidates = nominateSkillCandidates(items, skillSources);
				return { action: 'candidates', candidates, items: [], warnings };
			}
			if (args.action === 'list') {
				return { action: 'list', items: await listAll(), warnings };
			}
			const name = safeSlug(args.name);
			const p = path.join(dir, `${name}.md`);
			if (args.action === 'read') {
				const text = await readIfExists(p);
				if (text === undefined) throw new Error(`技能台账里没有 ${name}（先 memory_skill(crystallize)，或 candidates 看提名）`);
				return { action: 'read', file: p, items: [], content: text, warnings };
			}
			if (args.action === 'crystallize') {
				const summary = oneLine(args.summary);
				if (!summary) throw new Error('summary is required');
				const when = oneLine(args.when);
				if (!when) throw new Error('when is required: what task signal should trigger this skill');
				const steps = (Array.isArray(args.procedure) ? args.procedure : []).map((s) => oneLine(s)).filter(Boolean);
				if (steps.length < 2) throw new Error('procedure needs at least 2 concrete steps — a skill is a callable procedure, not a hint');
				const verification = oneLine(args.verification);
				if (!verification) throw new Error('verification is required: how success is judged after following the procedure');
				const srcs = (Array.isArray(args.sources) ? args.sources : [])
					.map((s) => oneLine(s))
					.filter(Boolean)
					// Evidence hrefs must resolve: callers hand over anything from a
					// bare slug ("memory-manager") to a full "../functions/x.md".
					// Stripping the zone prefix and re-adding only `../` produced the
					// dangling `../memory-manager` R10 caught on the real root.
					// Normalize to a zone path; the default zone is functions/ — where
					// the iteration history a skill cites lives.
					.map((s) => {
						if (s.includes('](')) return s; // an authored markdown link passes through
						const t = s.trim().replace(/^\.\.?\//, '').replace(/\.md$/i, '');
						return /^(functions|insights|capabilities|skills)\//.test(t) ? `${t}.md` : `functions/${t}.md`;
					});
				if (!srcs.length) throw new Error('sources is required: link the evidence areas (functions/xxx.md) the procedure was distilled from');
				const date = localDateStr();
				const existing = await readIfExists(p);
				const created = existing === undefined;
				// Scope defaults to global; a project-bound skill must SAY so (the
				// origin-skill audit WARNs on owned skills without scope — R20 mirrors
				// it, so defaults must be written down, never left implied).
				const scope = args.scope === 'project' ? 'project' : 'global';
				const scopeProject = oneLine(args.scopeProject ?? '');
				if (scope === 'project' && !scopeProject) {
					warnings.push('scope=project 但没给 scopeProject：项目归属未知，路由/审计会按未知作用域处理（补 scopeProject=<项目目录名>）');
				}
				const scopeNotes = oneLine(args.scopeNotes ?? '');
				const hostName = oneLine(args.hostName ?? '').toLowerCase();
				if (hostName && !isSkillName(hostName)) throw new Error(`hostName 必须是 kebab-case（宿主 isSkillName 语法 ^[a-z0-9]+(-[a-z0-9]+)*$），收到：${hostName}`);
				// Re-crystallization KEEPS the lifecycle: activating then improving a
				// skill must not silently demote it to candidate (the status line and
				// the ⭐ recall gate both read it).
				const priorStatus = created ? 'candidate' : ((existing.match(/^status:\s*([a-z]+)/m) ?? existing.match(/^> 状态：([a-z]+)/m) ?? [])[1] ?? 'candidate');
				if (!created) {
					warnings.push(`技能已存在：本次为整体重结晶（覆盖正文与程序），使用记录已并入新文件头部，生命周期保留为 ${priorStatus}，旧版演进靠 git/人工留存`);
				}
				// Router field (the skill-creator lesson): the frontmatter description
				// decides WHEN the skill fires, so it embeds the trigger, third-person.
				const description = `当${when}时使用本技能：${summary}`.replace(/"/g, "'");
				const srcLines = srcs.map((s) => {
					if (s.includes('](')) return `- ${s}`; // an authored markdown link passes through
					// One place builds the (label, href) pair: the label is the bare
					// filename, the href keeps its zone folder — chained regexes here
					// dropped the .md once too often and made every backlink dangle.
					const rel = s.trim().replace(/^\.\.?\//, '').replace(/\.md$/i, '');
					const label = rel.replace(/^(?:functions|insights|capabilities|skills)\//, '');
					return `- [${label}.md](../${rel}.md)`;
				});
				// Carry the old 使用记录 across a re-crystallization: the lifecycle
				// history belongs to the skill, not to one version of its body.
				let priorUse = [];
				if (existing !== undefined) {
					const rec = (existing.match(/## 使用记录\s*\n([\s\S]*?)(?=\n## |$)/) ?? [])[1];
					priorUse = (rec ?? '').split('\n').map((l) => l.trim()).filter((l) => l.startsWith('- '));
				}
				const body = skillTemplate(name, {
					status: priorStatus,
					date,
					srcs,
					description,
					summary,
					when,
					scope,
					scopeProject,
					scopeNotes,
					hostName,
					steps,
					pitfalls: oneLine(args.pitfalls ?? ''),
					verification,
					srcLines,
					priorUse,
				});
				await mkdir(dir, { recursive: true });
				await writeText(p, body);
				const st = await stat(p);
				const item = { name, status: priorStatus, summary, updated: st.mtime.toISOString() };
				await syncIndexRow(item);
				return { action: 'crystallize', file: p, created, status: priorStatus, items: [item], warnings };
			}
			if (args.action === 'activate' || args.action === 'retire') {
				const text = await readIfExists(p);
				if (text === undefined) throw new Error(`技能台账里没有 ${name}`);
				const to = args.action === 'activate' ? 'active' : 'retired';
				// frontmatter `status:` is canonical; tolerate the pre-5.12 head form.
				const cur = (text.match(/^status:\s*([a-z]+)/m) ?? text.match(/^> 状态：([a-z]+)/m) ?? [])[1] ?? 'candidate';
				const note = oneLine(args.note ?? '');
				if (cur === to) throw new Error(`${name} 已是 ${to}`);
				if (to === 'retired' && cur === 'candidate') warnings.push('candidate 直接 retired：未经使用即放弃，确认是否应保留观察');
				const date = localDateStr();
				// Update whichever status marker the file actually carries so the two
				// formats never both survive on one file.
				let next = text;
				if (/^status:/m.test(next)) next = next.replace(/^status:\s*[a-z]+/m, `status: ${to}`);
				else next = next.replace(/^> 状态：[a-z]+/m, `> 状态：${to}`);
				const entry = `- ${date} ${args.action === 'activate' ? '✅ 激活' : '⛔ 退役'}${note ? `：${note}` : ''}`;
				const appended = appendUnderHeading(next, '## 使用记录', entry);
				next = appended.text;
				await writeText(p, next);
				const st = await stat(p);
				const sumM = next.match(/^>\s*摘要：(.+)$/m) ?? next.match(/^description:\s*"?([^"\n]+)"?/m);
				const item = { name, status: to, summary: sumM ? sumM[1].trim() : name, updated: st.mtime.toISOString() };
				await syncIndexRow(item);
				return { action: args.action, file: p, status: to, items: [item], warnings };
			}
			throw new Error(`unknown action: ${args.action}`);
		},
	});
}

function memoryWriteTool(opts) {
	return defineTool({
		name: 'memory_write',
		description:
			'Append ONE iteration block to functions/<feature>.md (distilled conclusion, not a process log; dates are tags, blocks are append-only) and refresh the file-head stable-state summary via `currentState`. The daily log (YYYY-MM-DD.md) is the RAW layer — the model/harness records whatever it wants there with any means; this tool never touches it. The MEMORY.md index row is written separately (memory_index) once a feature area stabilizes, so distillation flows daily → functions → index, one direction per step. A block is a DISTILLED conclusion (动因 / 改动 / 判据 / 待观察, one line each): per-step changelists, code-level enumerations and debugging process stay in the session, the daily log and the code — writing them into the block is the failure R14 flags.',
		parameters: {
			feature: { type: 'string', required: true, description: '功能域 slug（文件名，不含 .md）：这个迭代属于哪个功能/模块；不确定就先 memory_read kind=index。' },
			title: { type: 'string', required: true, description: '一句话结论式标题，如“修复 config 加载顺序导致的空指针”；不要“优化了一些问题”这类空话。' },
			change: { type: 'string', description: '改动（结论级，1-3 句）：现在是什么行为 / 改了什么。不写过程——逐条实现清单、代码级枚举、调试经过都不进记忆（留在会话与代码/提交里）。' },
			reason: { type: 'string', description: '原因（一句话）：为什么必须改（用户诉求 / 缺陷根因）。' },
			verification: { type: 'string', description: '验证（一句话 + 关键数字）：测试名/命令/实测现象；不要复述全部断言细节。' },
			result: { type: 'string', enum: ['done', 'reverted', 'pending'], description: '结果：done=完成 / reverted=已回滚 / pending=进行中。' },
			open: { type: 'string', description: '待观察（一句话）：遗留风险或下一步要确认什么。' },
			guard: { type: 'boolean', description: '守护型标记：低频高价值、绝不能因为"很久没写"被判冷记忆的记忆（安全审计、关键踩坑、兜底规则）。写入后文件头带 🛡 标记，体检 TEMP 跳过它；传 false 不解除已有标记（删掉文件头那行才真正解除）。' },
			related: { type: 'array', description: '相关功能域 slug 列表，渲染为迭代块内的“相关”链接。', items: { type: 'string' } },
			summary: { type: 'string', required: true, description: '本块的一句话概括（≤60 字）：从每日原始记录蒸馏本迭代时，它回答“这次迭代做了什么/解决了什么”。功能域稳定后由 memory_index 把它收进索引行。' },
			currentState: { type: 'string', description: '刷新文件头部“当前状态摘要”：只写当前稳定行为/关键约束/隐患（3-5 条），不写历史与过程。' },
			date: { type: 'string', description: '迭代日期 YYYY-MM-DD；缺省今天。同日第二个迭代自动加“补”后缀。' },
			replace: {
				type: 'string',
				description: '可选：写完迭代块后在本功能文件内做字面替换（全部出现）。JSON 形式 {"oldString":"...","newString":"..."} 或其数组；找不到目标时报错。用于修正既往迭代块笔误/死链，审计上等价于追加一次修正迭代。',
			},
			resolve: {
				type: 'string',
				description: '可选：功能域 slug，声明本迭代解决了该功能遗留的待观察项。自动把各每日日志“今日待观察”里指向该功能的条目标记 ✅ 已解决（勾掉语义，不重抄）。',
			},
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					featureFile: { type: 'string', required: true },
					appendedHeading: { type: 'string', required: true },
					createdFunctionFile: { type: 'boolean', required: true },
					functionBytes: { type: 'integer', required: true },
					resolvedDailyLogs: { type: 'array', required: true, items: { type: 'string' } },
					warnings: { type: 'array', required: true, items: { type: 'string' } },
				},
			},
			render: (_args, v) => {
				const lines = [
					`已写入：${v.appendedHeading}`,
					`功能文件：${v.featureFile}（${v.functionBytes}B${v.createdFunctionFile ? '，新建' : ''}）`,
				];
				if (v.resolvedDailyLogs.length) lines.push(`✅ 已勾掉待观察项：${v.resolvedDailyLogs.join('、')}`);
				lines.push('ℹ 索引行未自动写入——功能域稳定后用 memory_index 收进索引；每日记录是原始层，由模型自主维护。');
				for (const w of v.warnings) lines.push(`⚠ ${w}`);
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Memory write: ${args.feature ?? ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			const feature = safeSlug(args.feature);
			const date = normDate(args.date);
			const title = oneLine(args.title);
			if (!title) throw new Error('title is required');
			const summary = oneLine(args.summary);
			if (!summary) throw new Error('summary is required: the MEMORY.md index row must carry a one-line summary');
			const warnings = [];

			const indexPath = path.join(root, 'MEMORY.md');
			const indexNow = await readIfExists(indexPath);
			if (indexNow !== undefined && byteLen(indexNow) >= opts.maxIndexHardBytes) {
				throw new Error(
					`MEMORY.md 已 ${byteLen(indexNow)}B ≥ 硬上限 ${opts.maxIndexHardBytes}B：先压缩索引行或按 ### 子分区拆分（拒绝写入以保护索引扫描成本）`,
				);
			}

			// 0) duplicate suspicion (dedupe aid): compare the new summary with
			// every existing index row via token overlap. High overlap on a
			// DIFFERENT feature warns the model to confirm add-vs-update first.
			if (indexNow !== undefined) {
				const sumTokens = tokensOf(summary);
				for (const raw of indexNow.split('\n')) {
					const s = raw.trim();
					if (!s.startsWith('|') || s.includes('---')) continue;
					const cells = s.replace(/^\|/, '').replace(/\|$/, '').split('|').map((c) => c.trim());
					if (cells.length < 2 || !cells[1]) continue;
					const rowName = cells[0].replace(/^\[([^\]]+)\]\([^)]*\)$/, '$1');
					if (rowName === feature) continue; // updating its own row is fine
					const rowTokens = tokensOf(cells.slice(1).join(' '));
					let hit = 0;
					for (const tk of sumTokens) if (rowTokens.has(tk)) hit++;
					if (sumTokens.size > 0 && hit / sumTokens.size >= 0.6) {
						warnings.push(`疑似与已有功能域「${rowName}」重复（摘要重合 ${(hit / sumTokens.size * 100) | 0}%）：先 memory_read kind=index 确认这是新功能还是对既有功能的更新；若为更新，直接对 ${rowName} 追加迭代`);
						break;
					}
				}
			}

			// 1) function file: create / refresh head summary / append iteration block
			const fnPath = path.join(root, 'functions', `${feature}.md`);
			let fnText = await readIfExists(fnPath);
			const created = fnText === undefined;
			if (created) fnText = functionFileTemplate(feature, date, args.guard === true);
			if (args.guard === true && !fnText.includes(GUARD_MARK)) {
				// Marking an existing file as guarded: insert the marker line right
				// after the scope line so the head reads top-down without surprises.
				const lines = fnText.split('\n');
				const scopeAt = lines.findIndex((l) => l.startsWith('> 范围：'));
				lines.splice(scopeAt === -1 ? 2 : scopeAt + 1, 0, GUARD_LINE);
				fnText = lines.join('\n');
			}
			if (args.currentState !== undefined) {
				const cs = String(args.currentState).trim();
				if (cs) fnText = refreshSummarySection(fnText, date, cs);
			}
			const suffixCount = countHeadingDate(fnText, date);
			const suffix = suffixCount === 0 ? '' : suffixCount === 1 ? '补' : `补${suffixCount}`;
			const heading = `## [${date}${suffix}] ${title}`;
			const bullets = [`- **概括**：${summary}`];
			if (args.change !== undefined && oneLine(args.change)) bullets.push(`- **改动**：${oneLine(args.change)}`);
			if (args.reason !== undefined && oneLine(args.reason)) bullets.push(`- **原因**：${oneLine(args.reason)}`);
			if (args.verification !== undefined && oneLine(args.verification)) bullets.push(`- **验证**：${oneLine(args.verification)}`);
			if (args.result !== undefined) bullets.push(`- **结果**：${RESULT_LABEL[args.result] ?? oneLine(args.result)}`);
			if (args.open !== undefined && oneLine(args.open)) bullets.push(`- **待观察**：${oneLine(args.open)}`);
			if (Array.isArray(args.related) && args.related.length) {
				// Sibling links: the host file already lives in functions/, so the
				// href must be bare `<name>.md`. Slugs without an existing file are
				// listed as plain text instead of dangling markdown links.
				const rels = [...new Set(args.related.map((r) => safeSlug(r)))].filter((r) => r !== feature);
				const rendered = [];
				for (const r of rels) {
					rendered.push(
						(await statExists(path.join(root, 'functions', `${r}.md`)))
							? `[${r}.md](${r}.md)`
							: `${r}（未建档）`,
					);
				}
				bullets.push(`- 相关：${rendered.length ? rendered.join('、') : '（无）'}`);
			}
			// Distillation gate: warn at write time instead of letting a process log
			// land silently (the same limits are re-checked by R14 in memory_check).
			const blockBody = bullets.join('\n');
			const blockChars = charLen(blockBody);
			if (blockChars > MAX_BLOCK_CHARS) {
				warnings.push(
					`本块正文 ${blockChars} 字 > ${MAX_BLOCK_CHARS}：迭代块只写结论（动因/改动/判据/待观察 各一句），逐条实现清单与调试过程留在会话/代码里；体检 R14 也会复查`,
				);
			}
			const summaryChars = charLen(args.summary);
			if (summaryChars > MAX_ROW_SUMMARY_CHARS) {
				warnings.push(`索引行摘要 ${summaryChars} 字 > ${MAX_ROW_SUMMARY_CHARS}：摘要是一句话（用来判断相关性），迭代细节留在功能文件`);
			}
			fnText = appendBlock(fnText, `\n${heading}\n\n${blockBody}\n`);
			if (typeof args.replace === 'string' && args.replace.trim()) {
				let pairs;
				try {
					const parsed = JSON.parse(args.replace);
					pairs = Array.isArray(parsed) ? parsed : [parsed];
				} catch {
					pairs = null;
				}
				if (!Array.isArray(pairs) || !pairs.length) {
					throw new Error('replace must be JSON: {"oldString":"...","newString":"..."} or an array of those');
				}
				for (const p of pairs) {
					if (typeof p?.oldString !== 'string' || !p.oldString || typeof p?.newString !== 'string') {
						throw new Error('each replace entry needs non-empty oldString and newString');
					}
					const count = fnText.split(p.oldString).length - 1;
					if (count === 0) throw new Error(`replace target not found in functions/${feature}.md: ${p.oldString.slice(0, 60)}`);
					fnText = fnText.split(p.oldString).join(p.newString);
				}
			}
			const wrote = await writeText(fnPath, fnText);
			if (wrote?.hits?.length) {
				warnings.push(`写入内容含凭据材料（${wrote.hits.join('、')}），落盘前已 redact 为 [REDACTED:kind]——密钥不该进记忆，请改用凭据服务`);
			}
			const fnBytes = byteLen(fnText);
			if (fnBytes > opts.maxFunctionBytes) {
				warnings.push(`functions/${feature}.md ${fnBytes}B > ${opts.maxFunctionBytes}B：调用 memory_fold(feature="${feature}") 折叠最旧块为早期演化段`);
			}

			// 2) index row is NOT auto-written anymore: the MEMORY.md index is the
			// integration layer (memory_index), written once a feature area
			// stabilizes — distillation flows daily → functions → index.

			// 3) the daily log is the RAW layer: the model/harness records there
			// freely with any means; this tool never touches it.

			// 4) resolve open items (R2 勾掉): mark still-open daily entries for
			// the resolved feature across logs from the day it was first raised.
			let resolvedIn = [];
			if (typeof args.resolve === 'string' && args.resolve.trim()) {
				const target = safeSlug(args.resolve);
				resolvedIn = await resolveOpenItems(root, target, '0000-01-01', date);
				if (!resolvedIn.length) warnings.push(`resolve: ${target} 在每日日志的待观察区没有未解决条目（可能已勾掉或不存在）`);
			}

			return {
				featureFile: fnPath,
				appendedHeading: heading,
				createdFunctionFile: created,
				functionBytes: fnBytes,
				resolvedDailyLogs: resolvedIn,
				warnings,
			};
		},
	});
}

function memoryInsightTool(opts) {
	return defineTool({
		name: 'memory_insight',
		description:
			'Distill a TRANSFERABLE PRINCIPLE (something you would RE-APPLY, not an operation you would re-run) into insights/<theme>.md with backlinks to its source feature files, and sync the MEMORY.md insights table. Consensus/rules and env constants belong in MEMORY.md instead; how-to steps belong in functions/. Writing the same idea into both zones is a rule violation.',
		parameters: {
			theme: { type: 'string', required: true, description: '思想主题 slug（文件名，不含 .md），如“等待策略”。' },
			principle: { type: 'string', required: true, description: '原则本体，具体地一句话说清（不要“注意性能”这类空话）。' },
			summary: { type: 'string', required: true, description: '索引行的一行内涵：这个原则解决什么权衡。' },
			sources: { type: 'array', required: true, description: '来源功能域 slug 列表（必须已存在于 functions/，用于回链）。', items: { type: 'string' } },
			evolution: { type: 'string', description: '思想演进：取代了什么旧做法 / 为什么。' },
			applicability: { type: 'string', description: '适用面：超出来源功能还适用于哪里。' },
			open: { type: 'string', description: '待观察：下一步要验证什么。' },
			supersedes: {
				type: 'string',
				description: '可选：被本思想取代的旧主题 slug（须已存在于 insights/）。自动给旧文件加“已取代”头部并链接到本主题（不删除，保留历史）。',
			},
			date: { type: 'string', description: 'YYYY-MM-DD；缺省今天。' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					insightFile: { type: 'string', required: true },
					linkedSources: { type: 'array', required: true, items: { type: 'string' } },
					skippedSources: { type: 'array', required: true, items: { type: 'string' } },
					supersededFile: { type: 'string' },
					// The schema is additionalProperties:false — every field execute
					// returns must be declared here or the Host rejects the receipt
					// (the 5.11.3 lesson, in reverse).
					trust: { type: 'object', required: true, additionalProperties: false, properties: { level: { type: 'string', required: true }, positives: { type: 'number', required: true }, corrections: { type: 'number', required: true } } },
					warnings: { type: 'array', required: true, items: { type: 'string' } },
				},
			},
			render: (_args, v) => {
				const lines = [`思想已沉淀：${v.insightFile}`];
				if (v.linkedSources.length) lines.push(`回链来源：${v.linkedSources.join('、')}`);
				if (v.skippedSources.length) lines.push(`⚠ 来源不存在，未回链：${v.skippedSources.join('、')}`);
				if (v.supersededFile) lines.push(`⚠️ 旧思想已标记取代：${v.supersededFile}`);
				for (const w of v.warnings) lines.push(`⚠ ${w}`);
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Memory insight: ${args.theme ?? ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			await mkdir(path.join(root, 'insights'), { recursive: true });
			const theme = safeSlug(args.theme);
			const principle = oneLine(args.principle);
			if (!principle) throw new Error('principle is required');
			const summary = oneLine(args.summary);
			if (!summary) throw new Error('summary is required: the insights index row must carry a one-line 内涵');
			const date = normDate(args.date);
			const warnings = [];

			const sources = (Array.isArray(args.sources) ? args.sources : []).map((s) => safeSlug(s));
			if (!sources.length) throw new Error('sources is required: at least one existing functions/ file to backlink');
			const linked = [];
			const skipped = [];
			for (const s of sources) {
				if (await statExists(path.join(root, 'functions', `${s}.md`))) linked.push(s);
				else skipped.push(s);
			}
			if (skipped.length) warnings.push(`来源不存在，未回链：${skipped.join('、')}（先用 memory_write 建立功能文件）`);
			// Verification gate (the 法层's promotion test, reduced to what is
			// mechanically checkable): a principle that claims to be
			// transferable must show up in >=2 unrelated areas, and must not be an
			// operation manual in disguise. Both are WARN, not FAIL — this is a
			// judgement the model should make with the warning in front of it.
			if (linked.length < 2) {
				warnings.push(
					`跨域闸门未过：只有 ${linked.length} 个来源功能域（法层「跨域迁移」要求 ≥2 个无关领域）。本条仍属专项经验：可以留在 insights/，但不要当普适原则用，也不要升级为共识`,
				);
			}
			const stepLike = /(^|\s)(\d+[.、)]|步骤|第[一二三四五]步|命令行|执行命令|运行 `|点击|打开菜单|安装依赖)/;
			if (stepLike.test(principle)) {
				warnings.push(
					`可降级警告：原则里出现操作步骤句式（法层「不可降级」闸门：能改写成操作手册的就不是原则）。把步骤留在 functions/，这里只留判断`,
				);
			}
			if (charLen(principle) > MAX_PRINCIPLE_CHARS) {
				warnings.push(`原则 ${charLen(principle)} 字 > ${MAX_PRINCIPLE_CHARS}：原则是判断，不是论述；推导留在来源功能文件里`);
			}
			const srcLine = linked.length ? linked.map((s) => `[functions/${s}.md](../functions/${s}.md)`).join('、') : '（来源缺失）';

			// 1) insight file
			const p = path.join(root, 'insights', `${theme}.md`);
			const existing = await readIfExists(p);
			let text;
			if (existing === undefined) {
				text = insightTemplate(theme, principle, srcLine, args.evolution, args.applicability, args.open, date);
			} else {
				text = replaceSection(existing, '## 核心原则', `- ${principle}`);
				const evo = `- ${date} 调整为：${principle}${args.evolution ? `（${oneLine(args.evolution)}）` : ''}`;
				text = appendUnderHeading(text, '## 思想演进', evo).text;
				text = text.replace(/^> 来源：.*$/m, `> 来源：${srcLine}`);
				// applicability is refreshed too: an evolved principle usually widens,
				// narrows, or replaces the scope it applies to.
				if (args.applicability !== undefined && oneLine(args.applicability)) {
					text = replaceSection(text, '## 适用面', `- ${oneLine(args.applicability)}`);
				}
				if (args.open !== undefined && oneLine(args.open)) text = appendUnderHeading(text, '## 待观察', `- ${oneLine(args.open)}`).text;
			}
			// Trust refresh (Hindsight-borrowed: beliefs carry proof counts and are
			// REFINED, never silently replaced): recompute from .usage.jsonl on every
			// insight write, so the head line is always the current evidence — and a
			// theme that keeps being corrected shows it right on its first line.
			const trustItems = summarizeUsage(await readUsage(root));
			const trust = insightTrust(trustItems.find((x) => x.href === `insights/${theme}.md`) ?? {});
			text = refreshTrustLine(text, trustLineFor(trust));
			if (trust.level === '动摇') {
				warnings.push(`该思想正处于「动摇」（认可 ${trust.positives} · 纠正 ${trust.corrections}）：继续追加前先精炼原则本体或传 supersedes 取代它`);
			}
			await writeText(p, text);

			// 1b) supersede (R12): stamp the old insight without deleting it.
			let supersededFile;
			if (typeof args.supersedes === 'string' && args.supersedes.trim()) {
				const oldTheme = safeSlug(args.supersedes);
				if (oldTheme === theme) throw new Error('supersedes must reference a DIFFERENT theme');
				const oldPath = path.join(root, 'insights', `${oldTheme}.md`);
				const oldText = await readIfExists(oldPath);
				if (oldText === undefined) {
					warnings.push(`supersedes: insights/${oldTheme}.md 不存在，未打标`);
				} else if (oldText.includes('> ⚠️ 已被取代')) {
					warnings.push(`supersedes: insights/${oldTheme}.md 已带有取代标记（检查链是否正确）`);
				} else {
					// The old file lives in insights/, so the successor href is a bare
					// sibling link (insights/-prefixed hrefs resolve to insights/insights/).
					const stamp =
						`> ⚠️ 已被取代 → [${theme}.md](${theme}.md)（${date}）。以下内容保留作为决策历史。`;
					const stamped = oldText.replace(/^/, `${stamp}\n\n`);
					await writeText(oldPath, appendUnderHeading(stamped, '## 思想演进', `- ${date} 被 [${theme}.md](${theme}.md) 取代`).text);
					supersededFile = oldPath;
				}
			}

			// 2) index row is NOT auto-written: insights land in the index via
			// memory_index when the theme stabilizes (same integration layer as
			// function areas).

			// 3) the daily log is the raw layer; this tool never touches it.

			// Omit `supersededFile` entirely when nothing was superseded: an
			// `undefined` property makes the tool result non-lossless JSON, which
			// the Host rejects even though the write already succeeded.
			const out = {
				insightFile: p,
				linkedSources: linked.map((s) => `functions/${s}.md`),
				skippedSources: skipped.map((s) => `functions/${s}.md`),
				trust,
				warnings,
			};
			if (supersededFile) out.supersededFile = supersededFile;
			return out;
		},
	});
}

function memoryFoldTool(opts) {
	return defineTool({
		name: 'memory_fold',
		description:
			'Compress a function file (R9): fold the OLDEST iteration blocks into a single "早期演化" paragraph (keeps 结论 only — title, result, key lesson — drops step-by-step detail), keeping the head state summary and the most recent blocks verbatim. Use it when memory_check reports R9 or a write warns about size. The folded history stays recoverable: the paragraph names every folded date tag.',
		parameters: {
			feature: { type: 'string', required: true, description: '功能域 slug（functions/ 下的既有文件）。' },
			keep: { type: 'integer', description: '从最新块往回保留的块数（默认 3，最小 1）。' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					file: { type: 'string', required: true },
					foldedBlocks: { type: 'integer', required: true },
					keptBlocks: { type: 'integer', required: true },
					bytesBefore: { type: 'integer', required: true },
					bytesAfter: { type: 'integer', required: true },
					warnings: { type: 'array', required: true, items: { type: 'string' } },
				},
			},
			render: (_args, v) => {
				const lines = [
					`已折叠：${v.file}`,
					`折叠 ${v.foldedBlocks} 块为早期演化段，保留最近 ${v.keptBlocks} 块完整`,
					`体积 ${v.bytesBefore}B → ${v.bytesAfter}B`,
				];
				for (const w of v.warnings) lines.push(`⚠ ${w}`);
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Fold memory: ${args.feature ?? ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			const feature = safeSlug(args.feature);
			const warnings = [];
			const p = path.join(root, 'functions', `${feature}.md`);
			const text = await readIfExists(p);
			if (text === undefined) throw new Error(`functions/${feature}.md 不存在`);
			const bytesBefore = byteLen(text);

			// Collect iteration blocks (## [date...] up to the next ## heading).
			const lines = text.split('\n');
			const headEnd = (() => {
				// The body starts after the first `---` separator (template) or at the
				// first iteration heading, whichever comes first.
				const sep = lines.findIndex((l) => l.trim() === '---');
				return sep === -1 ? lines.findIndex((l) => /^## \[/.test(l)) : sep + 1;
			})();
			const blockStarts = [];
			for (let i = Math.max(0, headEnd); i < lines.length; i++) {
				if (/^##\s*\[\d{4}-\d{2}-\d{2}/.test(lines[i])) blockStarts.push(i);
			}
			if (blockStarts.length === 0) throw new Error('没有可折叠的迭代块（文件里没有 [YYYY-MM-DD] 块）');
			const keep = Math.max(1, Math.min(Number.isFinite(args.keep) ? args.keep : 3, blockStarts.length - 1));
			if (blockStarts.length <= keep) throw new Error(`只有 ${blockStarts.length} 个迭代块，keep=${keep} 无需折叠`);

			const foldCount = blockStarts.length - keep;
			const foldFrom = blockStarts[0];
			const foldTo = blockStarts[foldCount]; // first kept block start
			const foldedLines = lines.slice(foldFrom, foldTo);
			const keptLines = lines.slice(foldTo);

			// Extract per-block: heading (date + title) and its bullets' key info.
			const summaries = [];
			let cur = null;
			for (const l of foldedLines) {
				const hm = l.match(/^##\s*\[([^\]]+)\]\s*(.+)$/);
				if (hm) {
					if (cur) summaries.push(cur);
					cur = { tag: hm[1], title: hm[2].trim(), results: [], lessons: [] };
				} else if (cur) {
					const rm = l.match(/^-\s*\*\*结果\*\*[:：]\s*(.+)$/);
					const om = l.match(/^-\s*\*\*待观察\*\*[:：]\s*(.+)$/);
					if (rm) cur.results.push(rm[1].trim());
					else if (om) cur.lessons.push(om[1].trim());
					else if (l.startsWith('- 相关：')) cur.lessons.push(l.trim());
				}
			}
			if (cur) summaries.push(cur);

			const evoLines = summaries.map((s) => {
				// One short line per folded block: tag + title, plus the result only
				// when it is informative (reverted/pending), never a bare "完成".
				const res = s.results.find((r) => r !== '完成');
				return `- [${s.tag}] ${s.title}${res ? `（${res}）` : ''}`;
			});
			const evoBlock = [
				`## 早期演化（${foldCount} 块已折叠：${summaries.map((s) => s.tag).join('→')}）`,
				'',
				...evoLines,
				'',
			];

			const newText = [...lines.slice(0, foldFrom), ...evoBlock, ...keptLines].join('\n');
			await writeText(p, newText);
			const bytesAfter = byteLen(newText);
			if (bytesAfter > opts.maxFunctionBytes) {
				warnings.push(`折叠后仍 ${bytesAfter}B > ${opts.maxFunctionBytes}B：再降低 keep 或压缩状态摘要`);
			}
			return {
				file: p,
				foldedBlocks: foldCount,
				keptBlocks: keep,
				bytesBefore,
				bytesAfter,
				warnings,
			};
		},
	});
}

function memoryRenameTool(opts) {
	return defineTool({
		name: 'memory_rename',
		description:
			'Rename or merge a function area (R10): moves functions/<from>.md to functions/<to>.md (merge = fold the old file\'s blocks under the target\'s head, when <to> already exists), rewrites EVERY in-memory-root reference (index row, related links in other function files, insight backlinks, daily logs), and verifies zero dangling links afterwards. The target file is canonical; a merged file is deleted after its content moves.',
		parameters: {
			from: { type: 'string', required: true, description: '现有功能域 slug。' },
			to: { type: 'string', required: true, description: '目标 slug：不存在 = 重命名；已存在 = 合并（旧块追加到目标文件末尾）。' },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					mode: { type: 'string', required: true, enum: ['renamed', 'merged'] },
					fromFile: { type: 'string', required: true },
					toFile: { type: 'string', required: true },
					rewrittenFiles: { type: 'array', required: true, items: { type: 'string' } },
					danglingAfter: { type: 'integer', required: true },
					warnings: { type: 'array', required: true, items: { type: 'string' } },
				},
			},
			render: (_args, v) => {
				const lines = [
					v.mode === 'renamed' ? `已重命名：${v.fromFile} → ${v.toFile}` : `已合并：${v.fromFile} 并入 ${v.toFile}`,
					`改写引用的文件：${v.rewrittenFiles.length ? v.rewrittenFiles.join('、') : '（无）'}`,
					`改写后死链数：${v.danglingAfter}`,
				];
				for (const w of v.warnings) lines.push(`⚠ ${w}`);
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Rename memory: ${args.from ?? ''} → ${args.to ?? ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			const from = safeSlug(args.from);
			const to = safeSlug(args.to);
			if (from === to) throw new Error('from 与 to 相同');
			const warnings = [];
			const fromPath = path.join(root, 'functions', `${from}.md`);
			const toPath = path.join(root, 'functions', `${to}.md`);
			const fromText = await readIfExists(fromPath);
			if (fromText === undefined) throw new Error(`functions/${from}.md 不存在`);
			const toText = await readIfExists(toPath);
			const merging = toText !== undefined;

			// 1) move / merge content
			let finalToText;
			if (!merging) {
				finalToText = fromText;
				await writeText(toPath, finalToText);
				await (await import('node:fs/promises')).unlink(fromPath);
			} else {
				// Append the old file's iteration blocks under the target's head,
				// then rewrite intra-file links from `from` to `to` inside the moved
				// blocks; the source file is deleted (R10: no absorbed leftovers).
				const fromLines = fromText.split('\n');
				const firstBlock = fromLines.findIndex((l) => /^##\s*\[\d{4}-\d{2}-\d{2}/.test(l));
				const blockPart = firstBlock === -1 ? '' : fromText.slice(fromText.indexOf(fromLines[firstBlock]));
				const relinked = blockPart.split(`](${from}.md)`).join(`](${to}.md)`);
				finalToText = toText.replace(/\n*$/, '\n') + relinked;
				await writeText(toPath, finalToText);
				await (await import('node:fs/promises')).unlink(fromPath);
			}

			// 2) rewrite every reference across the memory root. Four spellings
			// exist: index link `functions/<from>.md`, bare sibling links
			// `](<from>.md)` inside functions/, `functions/<from>.md` prose, and
			// the index row's first cell `| <from> |`.
			const rewritten = [];
			const rewriteIn = async (fp) => {
				const before = await readIfExists(fp);
				if (before === undefined) return;
				let after = before
					// Label + href pairs first (both spellings), then bare prose.
					.split(`[${from}.md](${from}.md)`).join(`[${to}.md](${to}.md)`)
					.split(`[${from}.md](functions/${from}.md)`).join(`[${to}.md](functions/${to}.md)`)
					.split(`](${from}.md)`).join(`](${to}.md)`)
					.split(`](functions/${from}.md)`).join(`](functions/${to}.md)`)
					.split(`functions/${from}.md`).join(`functions/${to}.md`)
					.split(`| ${from} |`).join(`| ${to} |`);
				if (merging) {
					// A merged source's index row must go; the target row remains.
					// Order matters: the replace above already renamed the source row's
					// first cell to `to` (the replacement `| ${from} |` runs before this
					// filter), so match by the pre-rename spelling is impossible here.
					// Identify the stale row instead by its href: it still points at the
					// now-deleted `functions/${from}.md`… which the replace ALSO renamed.
					// The only stable trait left is the row's position: it sits in the
					// SAME table as the target's row and carries a different summary.
					// Simplest correct move: drop rows whose first cell is `to` beyond
					// the first occurrence — the kept one is whichever appears first.
					const lines = after.split('\n');
					let seenTarget = false;
					const cleaned = lines.filter((l) => {
						if (!l.startsWith('|')) return true;
						const cell0 = l.split('|')[1]?.trim();
						if (cell0 === to) {
							if (seenTarget) return false; // extra row created by the rename
							seenTarget = true;
						}
						return true;
					});
					after = cleaned.join('\n');
				}
				if (after !== before) {
					await writeText(fp, after);
					rewritten.push(path.relative(root, fp).split(path.sep).join('/'));
				}
			};
			await rewriteIn(path.join(root, 'MEMORY.md'));
			for (const zone of ['functions', 'insights']) {
				let names = [];
				try {
					names = (await readdir(path.join(root, zone))).filter((n) => n.endsWith('.md'));
				} catch {
					/* zone absent */
				}
				for (const n of names) await rewriteIn(path.join(root, zone, n));
			}
			try {
				for (const n of await readdir(root)) {
					if (/^\d{4}-\d{2}-\d{2}\.md$/.test(n)) await rewriteIn(path.join(root, n));
				}
			} catch {
				/* root absent */
			}

			// 3) verify: run the real checker and count dangling links
			const health = await runHealthCheck(root, opts);
			const danglingAfter = health.results.filter((r) => r.rule === 'R10' && r.level === 'FAIL').length;
			if (danglingAfter > 0) warnings.push(`改写后仍有 ${danglingAfter} 条死链（见 memory_check 输出，可再用 replace 修正残余字面量）`);
			if (merging) warnings.push(`合并完成：${from} 的块已追加到 ${to} 末尾，来源文件已删除；请确认 target 的状态摘要仍准确`);

			return {
				mode: merging ? 'merged' : 'renamed',
				fromFile: fromPath,
				toFile: toPath,
				rewrittenFiles: rewritten,
				danglingAfter,
				warnings,
			};
		},
	});
}

// ---------------------------------------------------------------------------
// proactive recall: pre-step index matching (agent/pre-step waterfall)
// ---------------------------------------------------------------------------

function indexRowsOf(indexText) {
	const out = [];
	for (const raw of indexText.split('\n')) {
		const s = raw.trim();
		if (!s.startsWith('|') || s.includes('---')) continue;
		const cells = s.replace(/^\|/, '').replace(/\|$/, '').split('|').map((c) => c.trim());
		if (cells.length < 2 || !cells[1]) continue;
		// Column-agnostic, like matchIndexRows: the 4-column generation kept the
		// link in cell 3, the current one bakes it into cell 1. Both must resolve
		// so a mixed-shape root keeps working.
		const href = cells.map((c) => /\(([^)\s]+\.md)\)/.exec(c)?.[1]).find((h) => /^(functions|insights|skills|capabilities)\//.test(h ?? ''));
		if (!href) continue;
		const zone = href.startsWith('skills/') ? 'skill' : href.startsWith('insights/') ? 'insight' : href.startsWith('functions/') ? 'function' : null;
		if (!zone) continue;
		out.push({ name: href.split('/').pop().replace(/\.md$/, ''), summary: cells[1], href, zone });
	}
	return out;
}

/**
 * Decision-repair (MemOS borrow ④, simplified to our signals).
 *
 * MemOS: N tool failures within M steps → build a repair packet (prefer the
 * high-value approach, avoid the low-value one) and inject it BEFORE THE NEXT
 * step — never interrupting the in-flight one. We have no V-values, but the
 * equivalent signal exists: an area corrected repeatedly in the recent window
 * (the same raw material as the R18 circuit breaker) is exactly where the model
 * is about to repeat a mistake.
 *
 * Returns the hrefs to force-recall on the NEXT pre-step, most-corrected first.
 */
function decisionRepairTargets(usageItems, { minCorrections = 2, minBadRate = 0.3, limit = 2 } = {}) {
	return usageItems
		.filter((it) => it.corrections >= minCorrections && it.badRate >= minBadRate)
		.sort((a, b) => b.corrections - a.corrections || b.badRate - a.badRate)
		.slice(0, limit)
		.map((it) => ({ href: it.href, corrections: it.corrections, badRate: it.badRate, uses: it.uses }));
}

/**
 * Ranked full-text search over the whole memory root. Shared by the
 * `memory_search` tool and the panel's /search route so both rank identically
 * (the panel used to do a naive indexOf, whose order was file order).
 *
 * `after` / `before` (YYYY-MM-DD, inclusive) filter each hit by a LINE-level
 * date (Hindsight's temporal retrieval, lifted from a DB column to plain
 * markdown): an iteration block attributes to its `[YYYY-MM-DD…]` heading
 * tag, everything else in a file attributes to the head 「截至」 date, a daily
 * log to its filename, and a file with no date at all falls back to mtime.
 */
async function searchMemory(root, rawQuery, { zone = 'all', limit = 20, after = '', before = '' } = {}) {
	const q = String(rawQuery ?? '').trim().toLowerCase();
	if (q.length < 2) return [];
	const tokens = tokensOf(q);
	const zones = zone === 'all' ? ['index', 'functions', 'insights', 'capabilities', 'skills', 'daily'] : [zone];
	const files = [];
	if (zones.includes('index')) files.push({ zone: 'index', name: 'MEMORY.md', file: path.join(root, 'MEMORY.md') });
	for (const z of ['functions', 'insights', 'capabilities', 'skills']) {
		if (!zones.includes(z)) continue;
		let names = [];
		try {
			names = (await readdir(path.join(root, z))).filter((n) => n.endsWith('.md')).sort();
		} catch {
			/* zone absent */
		}
		for (const n of names) files.push({ zone: z, name: n, file: path.join(root, z, n) });
	}
	if (zones.includes('daily')) {
		let names = [];
		try {
			names = (await readdir(root)).filter((n) => /^\d{4}-\d{2}-\d{2}\.md$/.test(n)).sort().reverse();
		} catch {
			/* root absent */
		}
		for (const n of names) files.push({ zone: 'daily', name: n, file: path.join(root, n) });
	}
	const hits = [];
	for (const f of files) {
		const text = await readIfExists(f.file);
		if (text === undefined) continue;
		// Split on CRLF too: files written by other tools (or on Windows) carry
		// \r, and `.` never matches \r — a `^#{1,3}\s+(.+)$` test on a raw CRLF
		// line silently fails, which left every daily hit without its heading.
		const lines = text.split(/\r?\n/);
		const nameHit = f.name.toLowerCase().includes(q) || tokensOf(f.name).size && [...tokens].some((t) => tokensOf(f.name).has(t));
		// Date attribution, cheapest source first; mtime is stat'd lazily and
		// only when a hit actually needs the fallback.
		const headDate = /当前状态摘要（截至\s*(\d{4}-\d{2}-\d{2})/.exec(text)?.[1] ?? '';
		const nameDate = /^(\d{4}-\d{2}-\d{2})\.md$/.exec(f.name)?.[1] ?? '';
		let fileDate = headDate || nameDate;
		let mtimeDate = null;
		const dateOf = async (blockDate) => {
			if (blockDate || fileDate) return blockDate || fileDate;
			if (mtimeDate === null) {
				try {
					mtimeDate = localDateStr(new Date((await stat(f.file)).mtime));
				} catch {
					mtimeDate = '';
				}
			}
			return mtimeDate;
		};
		let heading = '';
		let blockDate = '';
		const fileHits = [];
		for (let i = 0; i < lines.length; i++) {
			const line = lines[i];
			const lower = line.toLowerCase();
			const hm = lower.match(/^#{1,3}\s+(.+)$/);
			if (hm) heading = hm[1].trim();
			const dm = /^##\s*\[(\d{4}-\d{2}-\d{2})/.exec(line.trim());
			if (dm) blockDate = dm[1];
			let score = 0;
			if (lower.includes(q)) score += 3;
			if (heading && heading.toLowerCase().includes(q)) score += 2;
			let tokenHits = 0;
			for (const tk of tokens) if (lower.includes(tk)) tokenHits++;
			score += tokenHits;
			if (score === 0) continue;
			const hitDate = await dateOf(blockDate);
			// A line whose date cannot be resolved at all passes both bounds —
			// never hide a hit whose age is unknown; the date field shows why.
			if (after && hitDate && hitDate < after) continue;
			if (before && hitDate && hitDate > before) continue;
			fileHits.push({
				zone: f.zone,
				name: f.name,
				line: i + 1,
				heading: heading.slice(0, 60),
				snippet: line.trim().slice(0, 160),
				date: hitDate,
				score: score + (nameHit ? 2 : 0),
			});
		}
		// At most 3 lines per file: one file should not monopolise the ranking.
		fileHits.sort((a, b) => b.score - a.score);
		hits.push(...fileHits.slice(0, 3));
	}
	hits.sort((a, b) => b.score - a.score);
	return hits.slice(0, limit).map(({ zone: z, name, line, heading, snippet, date }) => ({ zone: z, name, line, heading, snippet, date }));
}


// ---------------------------------------------------------------------------
// tools
// ---------------------------------------------------------------------------

function memoryCheckTool(opts) {	return defineTool({
		name: 'memory_check',
		description:
			'Lint the memory root (read-only): MEMORY.md size caps + rows missing one-line summaries (R5), dangling / root-escaping links (R10), function files reverse-linking to MEMORY.md detail (R8), function-file size (R9), over-detailed iteration blocks and index rows that were not distilled (R14), duplicated index rows or table sections (R15), head stable-state summary older than the newest iteration block or missing (R3), env-constant absolute paths that no longer exist (R16), a function area corrected over 40% of the time in the last 7 days (R18 circuit breaker), iteration date tags not append-ordered (R3), legacy/ files missing the 历史原貌 header (R13), credential material or personal identifiers in memory files (R21 memory defence). Guarded files (🛡 守护型) are exempt from the cold-memory rule. Run it after batch memory edits or when memory_check has never run on this root.',
		parameters: {},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					root: { type: 'string', required: true },
					results: {
						type: 'array',
						required: true,
						items: {
							type: 'object',
							additionalProperties: false,
							properties: {
								level: { type: 'string', required: true, enum: ['WARN', 'FAIL'] },
								rule: { type: 'string', required: true },
								message: { type: 'string', required: true },
							},
						},
					},
					warnCount: { type: 'integer', required: true },
					failCount: { type: 'integer', required: true },
				},
			},
			render: (_args, v) => {
				const lines = [`memory_check — ${v.root}：${v.failCount} FAIL，${v.warnCount} WARN`];
				for (const r of v.results) lines.push(`  [${r.level}] ${r.rule}: ${r.message}`);
				if (!v.results.length) lines.push('  全部通过');
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: 'Lint memory structure', kind: 'other', rawInput: args }),
		async execute(_args, exec) {
			return runHealthCheck(resolveRoot(opts), opts);
		},
	});
}

/**
 * memory_index — the INTEGRATION layer (data-flow layer 3). Function areas and
 * insights are written by memory_write / memory_insight; this tool is the ONLY
 * writer of the MEMORY.md dual tables, invoked once a feature/theme has
 * stabilized. Keeps the index a derived, curated surface instead of a
 * write-time side effect.
 */
function memoryIndexTool(opts) {
	return defineTool({
		name: 'memory_index',
		description:
			'Upsert ONE row into the MEMORY.md index (the integration layer). Call it when a feature area or insight theme has STABILIZED (>=2 iteration blocks, or clearly a standalone topic) — not per write. The row summary is distilled from the area\'s iteration-block summaries: one sentence saying what this feature IS. Zones: zone=functions or zone=insights. Unindexed-but-existing files are surfaced by memory_check (R5 orphan) so nothing silently falls out of the index.',
		parameters: {
			zone: { type: 'string', required: true, enum: ['functions', 'insights'], description: '收进哪张索引表。' },
			name: { type: 'string', required: true, description: '功能域或思想主题 slug（functions/ 或 insights/ 下的既有文件名，不含 .md）。' },
			summary: { type: 'string', required: true, description: '索引行摘要：一句话（≤60 字）说清"这是什么/解决什么"，供检索时判断相关性；从各迭代块的概括中提炼，不复制细节。' },
			group: { type: 'string', description: '可选：功能表已按 `### 索引·<域>` 分组时，指定这一行落到哪个子分区（如「基础设施」「业务功能」）；缺省写入无标题的总表。' },
			sources: { type: 'array', description: 'zone=insights 必填：来源功能域 slug 列表（渲染进"相关（来源功能）"列）。', items: { type: 'string' } },
		},
		output: {
			schema: {
				type: 'object',
				additionalProperties: false,
				properties: {
					indexFile: { type: 'string', required: true },
					zone: { type: 'string', required: true },
					name: { type: 'string', required: true },
					created: { type: 'boolean', required: true },
					indexBytes: { type: 'integer', required: true },
					warnings: { type: 'array', required: true, items: { type: 'string' } },
				},
			},
			render: (_args, v) => {
				const lines = [
					`索引已更新：${v.zone}/${v.name}${v.created ? '（新行）' : '（更新）'}`,
					`索引文件：${v.indexFile}（${v.indexBytes}B）`,
				];
				for (const w of v.warnings) lines.push(`⚠ ${w}`);
				return [{ type: 'text', text: lines.join('\n') }];
			},
		},
		presentCall: (args) => ({ card: 'generic', title: `Memory index: ${args.zone ?? ''}/${args.name ?? ''}`, kind: 'other', rawInput: args }),
		async execute(args, exec) {
			const root = resolveRoot(opts);
			const zone = args.zone === 'insights' ? 'insights' : 'functions';
			const name = safeSlug(args.name);
			const summary = oneLine(args.summary);
			if (!summary) throw new Error('summary is required: the index row must carry a one-line summary');
			const warnings = [];
			if (charLen(summary) > MAX_ROW_SUMMARY_CHARS) {
				warnings.push(`索引行摘要 ${charLen(summary)} 字 > ${MAX_ROW_SUMMARY_CHARS}：摘要是一句话，细节留在功能文件`);
			}
			const indexPath = path.join(root, 'MEMORY.md');
			let indexText = (await readIfExists(indexPath)) ?? memoryIndexTemplate();
			// Row presence check is shape-agnostic: the name cell may be plain
			// text (legacy 4-column rows) or a link (current rows).
			const rowExists = indexText.split('\n').some((l) => {
				if (!l.trim().startsWith('|')) return false;
				const first = l.trim().replace(/^\|/, '').split('|')[0].trim();
				return first === name || first === `[${name}](${zone === 'insights' ? 'insights' : 'functions'}/${name}.md)`;
			});
			const created = !rowExists;

			let row;
			if (zone === 'insights') {
				const srcs = (Array.isArray(args.sources) ? args.sources : []).map((s) => safeSlug(s)).filter((s) => s !== name);
				if (!srcs.length) throw new Error('zone=insights requires sources: the theme must name the areas it was distilled from');
				row = `| [${name}](insights/${name}.md) | ${summary}（来源：${srcs.map((s) => `[${s}.md](functions/${s}.md)`).join('、')}） |`;
				if (!(await statExists(path.join(root, 'insights', `${name}.md`)))) {
					warnings.push(`insights/${name}.md 尚不存在——索引行先建了，记得用 memory_insight 沉淀文件本体`);
				}
			} else {
				row = `| [${name}](functions/${name}.md) | ${summary} |`;
				if (!(await statExists(path.join(root, 'functions', `${name}.md`)))) {
					warnings.push(`functions/${name}.md 尚不存在——索引行先建了，记得用 memory_write 落第一个迭代块`);
				}
			}
			indexText = upsertIndexRow(
				indexText,
				zone === 'insights' ? INSIGHT_TABLE_HEADING : FUNC_TABLE_HEADING,
				zone === 'insights' ? INSIGHT_TABLE_HEADER : FUNC_TABLE_HEADER,
				name,
				row,
				zone === 'functions' && typeof args.group === 'string' && args.group.trim() ? oneLine(args.group).slice(0, 20) : undefined,
			);
			await writeText(indexPath, indexText);
			const indexBytes = byteLen(indexText);
			if (indexBytes > opts.maxIndexBytes) {
				warnings.push(`MEMORY.md ${indexBytes}B > ${opts.maxIndexBytes}B 舒适线：压缩各行摘要，或把功能表拆成 ### 子分区`);
			}
			return {
				indexFile: indexPath,
				zone,
				name,
				created,
				indexBytes,
				warnings,
			};
		},
	});
}

// ---------------------------------------------------------------------------
// system-prompt discipline section
// ---------------------------------------------------------------------------

const DISCIPLINE_TEXT = [
	'## 持久记忆纪律（memory-manager）',
	'',
	'本 Harness 维护**全局**跨会话记忆（`~/.dsh/memory/`，即 dshHome 的 memory/ 目录；十二个工具：memory_read / memory_search / memory_capability / memory_write / memory_index / memory_insight / memory_fold / memory_rename / memory_check / memory_usage / memory_federation / memory_skill；结构见 memory/MEMORY.md）。记忆对全部项目、全部会话通用，按功能域组织而非按项目隔离。**数据流单向五层，每层只吃上一层的产出**：',
	'',
	'- **第 0 层 · 每日记录（原始层）**：`YYYY-MM-DD.md` 是任务与对话过程的第一手数据，**本插件不约束其内容与格式**——用任何工具、任何方式自由记录（决策、对话、试错、片段都行）。它是一切蒸馏的原料；同一事实只在这里是"过程"，其余层只见结论。',
	'- **第 1 层 · 功能域（memory_write）**：从每日原始记录中**归纳汲取**功能划分——一次实质工作 = 一个 functions/<功能域>.md 迭代块（蒸馏结论：动因/改动/判据/待观察 各一句）。`summary` 是本块的一句话概括；功能域该新建还是并入既有的，判断依据就是每日记录里反复出现的主题。',
	'- **第 2 层 · 创新思想（memory_insight）**：从功能划分中**再提取**可迁移原则（会重套的、不绑定单一功能机制的），回链来源功能域；取代旧思想传 `supersedes`。',
	'- **第 3 层 · 索引与总览（memory_index）**：**整合层**——功能域稳定后（有 ≥2 个迭代块，或用户可感知为独立主题时）用 memory_index 把它收进 MEMORY.md 索引；索引行摘要 = 从各迭代块的概括中提炼的"这个功能是什么"。索引是展示与检索的派生物，不与单次写入强绑。',
	'- **第 4 层 · 技能（memory_skill）**：**使用环收口**——一个被反复重跑且被确认的操作，应结晶为 skills/<技能>.md 的可调用程序（何时使用/步骤/坑/验证），下次命中直接照做，不再现场推导。何时结晶：`memory_skill(candidates)` 给出机械提名（≥6 次使用 + ≥1 次确认 + 纠正率<20%，来自 .usage.jsonl），**提名≠结晶**——是否成文由你判断证据是否连贯；生命周期 candidate→active（真实任务照做成功过才转正）→retired（环境变了留档）。召回只放行 active 技能并标注 ⭐；技能=怎么做（程序），capability=有什么工具，insight=什么原则——三者别混。结晶时标 `scope`（global=跨项目通用 / project=须带 scopeProject=<项目名>），跨项目复用前先核对作用域；想让宿主 `skill` 工具直接调用，给一个 kebab-case 的 `hostName`（active 后自动发布进宿主目录，中文 slug 宿主不认）。',
	'- **层级定义（道/法/术/器，按普适程度分）**：**器**=指向内容的指针与检索面（MEMORY.md 双表+面板）；**术**=一个功能域"怎么做"的完整迭代史（functions/，判据"我会不会再跑一次这个操作"）；**法**=从具体操作提炼的可套原则（insights/，判据"换个项目/领域还成立吗"）；**道**=跨域都必须遵守的约束（MEMORY.md 共识区，判据"违反了会不会出事故"）。**放错层的三个信号**：① 在功能域里翻到普适断言 → 该升到 insights；② 同一句话想写进两个功能域 → 该升到 insights；③ 一条"原则"每次都要附带操作步骤才能用 → 该降回 functions。**反例**：索引行里写推导过程；迭代块里写"以后所有项目都应该……"；原则写成"1. 先运行 X；2. 再执行 Y"；把某次技术选型记成共识。',
	'- **先查后写**：涉及"项目里怎么做 / 为什么这么做 / 环境常量"时，先 `memory_read kind=index`（行内摘要判断相关性，再打开对应文件）；只记得片段、说不清在哪个域或哪天时用 `memory_search`（全库排序检索，返回命中的分区/文件/行号/小节/片段）。**动手前先查 `memory_capability`**：外部 CLI / MCP / 已装软件都在 `capabilities/` 台账里，能省下一整轮摸索。不要凭空重推已有结论。',
	'- **用到的外部工具要登记**：只有**项目外部**的工具才进台账——第三方 CLI / MCP / 已装软件，且调用它需要摸索（确切命令、前提、踩过的坑）。不登记：harness 自带工具（shell/文件/网络等，模型本来就会）、本项目自己的脚本与 API（那是 functions/ 迭代块）。台账按工具一文件、就地更新——**不是流水账，是索引**。下次同类任务先 `action=list`，不要重新摸索同一个工具。',
	'- **蒸馏不搬过程**：迭代块只写结论；逐条实现清单、调试经过属于每日原始层与会话/代码。块 >900 字或概括 >110 字写入告警，体检 R14 复查。',
	'- **经验三分**：会**重跑**的操作进 functions/；会**重套**的原则用 memory_insight 进 insights/；**反复重跑且被验证**的操作程序用 memory_skill 结晶进 skills/；跨功能共识与环境常量只在 MEMORY.md。',
	'- **使用信号让记忆自己排序**：召回命中与 memory_read 会自动记信号；用户纠正/明确认可时用 `memory_usage(action=record, kind=correction|positive)` 记一笔（这是分层判断里唯一不能自动获得的信号）。`memory_usage(action=report)` 给出 实验/专项/通用 建议；某域近 7 天纠正率 >40% 时体检 R18 报熔断——先重构再追加。',
	'- **守护型**：低频但高价值的记忆（安全审计、关键踩坑、兜底规则）用 `memory_write(guard=true)` 标记，体检的冷记忆规则会跳过它——不要因为"很久没写"就删掉兜底经验。',
	'- **项目归属**：涉及特定项目的记忆，在功能域 slug 或正文里注明项目名（如 `toolbox-login`）。功能域多到单根过大时，可启用**联邦模式**（`federation: { root, projects }`）：项目真相源留在各项目记忆根，`memory_federation` 负责刷副本与跨项目索引，项目细节不上升。',
	'- **收缩机制**：功能文件超 30KB 用 `memory_fold` 折叠最旧块；MEMORY.md 超线按 ### 子分区拆分；重命名/合并用 `memory_rename`（自动改写引用并验证死链清零）。',
	'- **密钥防线**：凭据（API key / token / 私钥 / JWT）绝不进记忆——插件写入口在落盘前把凭据形态替换成 `[REDACTED:kind]` 并在回执点名；每日原始层不经插件，直接写文件时请自律（体检 R21 兜底报告，身份证/手机号只告警不改写）。留「调用形态 + 前提从哪里领」，不留密钥本体。',
	'- 批量改动记忆后跑 `memory_check` 体检。',
	'- 归属口诀：会**重跑**的操作（术·functions/）、会**重套**的原则（法·insights/）、**反复跑通且验证**的程序（技能·skills/）、违反即出事故的约束（道·共识区）、指向内容的指针（器·索引与面板）；原始过程永远只留在每日记录。',
].join('\n');

// ---------------------------------------------------------------------------
// plugin entry
// ---------------------------------------------------------------------------

const MIME_PLAIN = { 'Content-Type': 'text/plain; charset=utf-8' };
const MIME_HTML = { 'Content-Type': 'text/html; charset=utf-8' };

function json(res, status, body) {
	res.writeHead(status, { 'Content-Type': 'application/json; charset=utf-8' });
	res.end(JSON.stringify(body));
}

function htmlPage(res, status, title, body) {
	res.writeHead(status, MIME_HTML);
	res.end(
		`<!doctype html><html lang="zh"><head><meta charset="utf-8"><title>${title}</title></head>` +
			`<body style="font-family:system-ui;margin:2rem;line-height:1.7"><h1>${title}</h1>${body}` +
			`<p style="color:#888;font-size:.9em">memory-manager 面板 API</p></body></html>`,
	);
}

/** Zone file counts for the rail badges (directory listing only, no reads). */
async function zoneCounts(root) {
	const count = async (dir, test) => {
		try {
			return (await readdir(dir)).filter(test).length;
		} catch {
			return 0;
		}
	};
	return {
		functions: await count(path.join(root, 'functions'), (n) => n.endsWith('.md')),
		insights: await count(path.join(root, 'insights'), (n) => n.endsWith('.md')),
		capabilities: await count(path.join(root, 'capabilities'), (n) => n.endsWith('.md')),
		skills: await count(path.join(root, 'skills'), (n) => n.endsWith('.md')),
		daily: await count(root, (n) => /^\d{4}-\d{2}-\d{2}\.md$/.test(n)),
	};
}

/**
 * Build the panel API handler. The memory root is global and always resolved
 * server-side, so a request can never widen it: there is deliberately no
 * client-supplied `?path=`.
 */
function memoryPanelApi(opts) {
	return async (req, res) => {
		const url = new URL(req.url, 'http://localhost');
		const seg = url.pathname.slice('/api/memory-org'.length).replace(/^\//, '');
		const root = resolveRoot(opts);
		try {
			if (seg === 'overview') {
				const health = panelizeHealth(await runHealthCheck(root, opts));
				// Panel-side usage snapshot: layer histogram + flip/correction hot
				// spots, so the overview answers "how is the memory being used"
				// alongside "how big is it". Optional data — absent when the log is
				// empty (a fresh root starts with no signals).
				const usage = summarizeUsage(await readUsage(root, 30));
				const layerCounts = { 实验: 0, 专项: 0, 通用: 0 };
				const hotspots = [];
				for (const it of usage) {
					if (layerCounts[it.layer] !== undefined) layerCounts[it.layer]++;
					if (it.flips >= 2 || (it.uses >= 3 && it.badRate > 0.4)) {
						hotspots.push({ href: it.href, flips: it.flips, badRate: it.badRate, uses: it.uses });
					}
				}
				const signalCount = (await readIfExists(usagePath(root)))?.split('\n').filter((l) => l.trim()).length ?? 0;
				return json(res, 200, [{ ...health, title: '全局记忆', path: joinDshHome(), counts: await zoneCounts(root), usage: { signalCount, layers: layerCounts, hotspots: hotspots.slice(0, 5) } }]);
			}
			if (seg === 'file') {
				const name = url.searchParams.get('name');
				if (!name || /[\\/]|\.\./.test(name) || !name.endsWith('.md')) {
					return json(res, 400, { error: 'invalid file name' });
				}
				const zone = url.searchParams.get('zone') ?? '';
				if (!['', 'functions', 'insights', 'capabilities', 'skills', 'daily'].includes(zone)) {
					return json(res, 400, { error: 'invalid zone' });
				}
				if (zone === 'daily' && !/^\d{4}-\d{2}-\d{2}\.md$/.test(name)) {
					return json(res, 400, { error: 'daily zone accepts only YYYY-MM-DD.md' });
				}
				// zone is whitelisted and name rejects separators, so the join can
				// only land inside the memory root.
				const full = zone === 'daily' ? path.join(root, name) : path.join(root, zone, name);
				const text = await readIfExists(full);
				if (text === undefined) return json(res, 404, { error: 'file not found' });
				return json(res, 200, { name, text });
			}
			// Recall preview (MemOS borrow ②): run the REAL pre-step pipeline
			// against an arbitrary query and return what would be injected, with
			// why. Recall quality was previously only observable after the fact;
			// this makes "this input recalls these rows, for these reasons" a
			// first-class, debuggable answer (same code path, same RRF fusion).
			if (seg === 'recall-preview') {
				const q = (url.searchParams.get('q') ?? '').trim();
				if (q.length < 2) return json(res, 200, { query: q, rows: [], message: '（查询至少 2 个字符）' });
				const indexText = (await readIfExists(path.join(root, 'MEMORY.md'))) ?? '';
				if (!indexText) return json(res, 200, { query: q, rows: [], message: '（记忆根尚未建档）' });
				const usageItems = summarizeUsage(await readUsage(root, 30));
				const usage = new Map(usageItems.map((it) => [it.href, it]));
				const tokens = tokensOf(q);
				const rows = matchIndexRows(indexText, tokens, 3, usage)
					.filter((l) => !q.includes(l.href))
					.map((r) => {
						const u = usage.get(r.href);
						const reasons = [];
						const nameTokens = tokensOf(r.name);
						const hits = [...tokens].filter((t) => nameTokens.has(t));
						if (hits.length) reasons.push(`名称命中：${hits.join('、')}`);
						if (r.lexical !== undefined) reasons.push(`词法分 ${Number(r.lexical).toFixed(2)}`);
						if (u) reasons.push(`使用 ${u.uses} 次 · 认可 ${u.positives} · 纠正率 ${u.badRate}`);
						return {
							href: r.href,
							zone: r.zone,
							summary: r.summary,
							fusedScore: Number(r.score.toFixed(4)),
							lexicalScore: r.lexical === undefined ? undefined : Number(r.lexical.toFixed(2)),
							usage: u ? { uses: u.uses, positives: u.positives, corrections: u.corrections, badRate: u.badRate, layer: u.layer } : null,
							reasons,
							// Would the user's own text have suppressed this row?
							suppressedByPointerDedupe: false,
						};
					});
				return json(res, 200, {
					query: q,
					tokens: [...tokens],
					usageSignals: usageItems.length,
					rows,
					message: rows.length ? '' : '（无命中：该输入不会注入任何召回）',
				});
			}
			if (seg === 'list') {
				const zone = url.searchParams.get('zone');
				if (!['functions', 'insights', 'capabilities', 'skills', 'daily'].includes(zone)) return json(res, 400, { error: 'invalid zone' });
				const dir = zone === 'daily' ? root : path.join(root, zone);
				let names = [];
				try {
					names = (await readdir(dir)).filter((n) => n.endsWith('.md'));
				} catch {
					/* zone absent */
				}
				// Daily zone lists ONLY decision threads (YYYY-MM-DD.md). The index
				// (MEMORY.md) has its own zone and must never appear under 每日,
				// and neither may stray non-dated files at the root. Newest first.
				if (zone === 'daily') names = names.filter((n) => /^\d{4}-\d{2}-\d{2}\.md$/.test(n));
				names.sort(zone === 'daily' ? (a, b) => b.localeCompare(a) : undefined);
				const files = [];
				for (const n of names) {
					const st = await stat(path.join(dir, n));
					files.push({ name: n, bytes: st.size, mtime: st.mtime.toISOString() });
				}
				// Newest-first for every zone (the panel and any other consumer
				// display the top row first). Names were pre-sorted per zone, so
				// this single mtime pass makes the order uniform.
				files.sort((a, b) => String(b.mtime).localeCompare(String(a.mtime)));
				return json(res, 200, { files });
			}
			if (seg === 'check') {
				return json(res, 200, panelizeHealth(await runHealthCheck(root, opts)));
			}
			if (seg === 'search') {
				const q = (url.searchParams.get('q') ?? '').trim();
				if (q.length < 2) return json(res, 200, { hits: [] });
				// Same ranker as the memory_search tool: the panel used to scan in
				// file order, so a hit in the first file always outranked a better
				// one further down.
				const zoneParam = url.searchParams.get('zone');
				const zone = ['functions', 'insights', 'capabilities', 'skills', 'daily'].includes(zoneParam) ? zoneParam : 'all';
				const hits = await searchMemory(root, q, { zone, limit: 60 });
				return json(res, 200, { hits });
			}
			htmlPage(
				res,
				200,
				'memory-manager',
				'<p>该插件的可视面板在 Harness Web UI 的侧栏（记忆图标）。此只读 API 供面板取数；记忆根由服务端解析，请求不能指定路径：</p>' +
					'<ul><li><code>GET /api/memory-org/overview</code> — 全局记忆体检 + 各分区计数</li>' +
					'<li><code>GET /api/memory-org/check</code> — 体检</li>' +
					'<li><code>GET /api/memory-org/list?zone=functions|insights|daily</code> — 分区文件列表</li>' +
					'<li><code>GET /api/memory-org/file?zone=functions&amp;name=&lt;file&gt;.md</code> — 读记忆文件（省略 zone 即索引）</li>' +
					'<li><code>GET /api/memory-org/search?q=&lt;关键词&gt;</code> — 全库搜索</li></ul>',
			);
		} catch (err) {
			json(res, 500, { error: String(err?.message ?? err) });
		}
	};
}

export function apply(ctx, config) {
	// The Host install may be pointed at explicitly; otherwise it is discovered
	// (env / CLI entry / cwd / profile). Loading eagerly fails fast with an
	// actionable message instead of breaking the first tool call.
	setHostRoot(typeof config?.dshRoot === 'string' && config.dshRoot.trim() ? config.dshRoot.trim() : undefined);
	loadHost();

	const opts = {
		memoryRoot: typeof config?.memoryRoot === 'string' && config.memoryRoot.trim() ? config.memoryRoot.trim() : undefined,
		maxIndexBytes: Number.isFinite(config?.maxIndexBytes) ? config.maxIndexBytes : DEFAULTS.maxIndexBytes,
		maxIndexHardBytes: Number.isFinite(config?.maxIndexHardBytes) ? config.maxIndexHardBytes : DEFAULTS.maxIndexHardBytes,
		maxFunctionBytes: Number.isFinite(config?.maxFunctionBytes) ? config.maxFunctionBytes : DEFAULTS.maxFunctionBytes,
		newFeatureGraceDays: Number.isFinite(config?.newFeatureGraceDays) ? config.newFeatureGraceDays : DEFAULTS.newFeatureGraceDays,
		// Foreground recall budget (ms). Config may SHORTEN it but never extend
		// past the default — recall must stay bounded no matter the config.
		recallTimeoutMs: resolveRecallBudget(config?.recallTimeoutMs),
		// Passive capture into the raw daily layer (off unless opted in).
		captureUserTurns: config?.captureUserTurns === true,
		// Opt-in three-tier federation: { root, projects: [{ key, root }] }.
		federation: config?.federation && typeof config.federation === 'object' ? config.federation : undefined,
	};

	const disposers = [
		ctx.tools.register(memoryReadTool(opts)),
		ctx.tools.register(memorySearchTool(opts)),
		ctx.tools.register(memoryCapabilityTool(opts)),
		ctx.tools.register(memoryWriteTool(opts)),
		ctx.tools.register(memoryIndexTool(opts)),
		ctx.tools.register(memoryInsightTool(opts)),
		ctx.tools.register(memoryFoldTool(opts)),
		ctx.tools.register(memoryRenameTool(opts)),
		ctx.tools.register(memoryCheckTool(opts)),
		ctx.tools.register(memoryUsageTool(opts)),
		ctx.tools.register(memoryFederationTool(opts)),
	];
	// Host skill bridge (5.17.0): publish active+hostName skills into ctx.skills
	// so the host `skill` tool can load them. OPTIONAL — a host without the
	// skill registry (ctx.get returns nothing usable) skips the bridge entirely
	// and our own pre-step recall keeps serving all skills. inject deliberately
	// does NOT list 'skills': waiting on it would break hosts that never mount
	// dsh-skill, and the bridge needs no startup guarantee (it reads disk on
	// every list()).
	const skillBridge = registerMemorySkillBridge(ctx, { skillsDir: path.join(resolveRoot(opts), SKILL_DIR) });
	disposers.push(ctx.tools.register(memorySkillTool(opts, skillBridge ? { onSkillChange: skillBridge.invalidate } : {})));

	// Proactive recall: on every proposed step, match the batch's user text
	// against the memory index and prepend one recall message when the overlap
	// clears the threshold. Waterfall listener returning next() unchanged when
	// nothing matches or the batch was already served a recall (per-agent
	// signature dedupe). Registration is global; dispatch is agent-scoped.
	const recallServed = new Map(); // agentId -> signature of last served batch
	const indexCache = { text: undefined, at: 0 };
	const usageCache = { map: undefined, at: 0 };
	const readUsageCached = async () => {
		const now = Date.now();
		if (usageCache.map === undefined || now - usageCache.at > 60_000) {
			// Fusion input: which rows are actually USED (recall/read) and how they
			// were judged (positives / correction rate). Cheap: one dot-file read
			// per minute, and a failure just means "rank lexically only".
			try {
				const items = summarizeUsage(await readUsage(resolveRoot(opts)));
				usageCache.map = new Map(items.map((it) => [it.href, it]));
			} catch {
				usageCache.map = new Map();
			}
			usageCache.at = now;
		}
		return usageCache.map;
	};
	const readIndexCached = async () => {
		const now = Date.now();
		if (indexCache.text === undefined || now - indexCache.at > 10_000) {
			indexCache.text = (await readIfExists(path.join(resolveRoot(opts), 'MEMORY.md'))) ?? '';
			indexCache.at = now;
		}
		return indexCache.text;
	};
	disposers.push(
		ctx.on('agent/pre-step', async (payload, next) => {
			// Build the recall candidate first; a recall failure must never break a
			// step, so ONLY this block is guarded. `next()` runs exactly once,
			// outside the guard, so a downstream error propagates (instead of the
			// waterfall being re-entered by a catch that calls next() again).
			let recall = null;
			try {
				const batch = payload.messages ?? [];
				const userText = batch
					.flatMap((m) => (m?.role === 'user' ? m.content : []))
					.filter((b) => b?.type === 'text')
					.map((b) => b.text)
					.join('\n');
				const signature = `${payload.agent.id}:${userText.slice(0, 400)}`;
				// MemOS borrow ⑤: every non-empty user turn gets a recall attempt,
				// but the whole attempt is bounded by an absolute budget. On timeout
				// we inject NOTHING (rather than a slow or half-built recall), so the
				// step proceeds normally — the failure mode is silence, not latency.
				const budgetMs = Math.min(Number(opts.recallTimeoutMs) || DEFAULTS.recallTimeoutMs, DEFAULTS.recallTimeoutMs);
				const buildRecall = async () => {
					if (!userText.trim()) return null;
					if (recallServed.get(payload.agent.id) === signature) return null;
					const indexText = await readIndexCached();
					if (!indexText) return null;
					// RRF fusion: lexical IDF rank + usage-heat rank (see
					// matchIndexRows). Signals already exist in .usage.jsonl;
					// without this they were collected but never used to rank.
					const usage = await readUsageCached();
					const base = matchIndexRows(indexText, tokensOf(userText), 3, usage)
						// Pointer dedupe: when the user's own text already cites a memory
						// file (they quoted an earlier recall or wrote the link), re-
						// injecting the same row just echoes what is already on screen.
						.filter((l) => !userText.includes(l.href));
					const rows = [...base];
					// Decision-repair (④): an area corrected repeatedly is where a
					// mistake is about to be repeated — force it into the NEXT step's
					// context even when the current wording doesn't match it. The
					// current step is never interrupted or modified.
					if (usage && usage.size) {
						const repairs = decisionRepairTargets([...usage.values()]).filter(
							(r) => !rows.some((l) => l.href === r.href) && !userText.includes(r.href),
						);
						if (repairs.length) {
							const indexRows = indexRowsOf(indexText);
							for (const r of repairs) {
								const row = indexRows.find((x) => x.href === r.href);
								if (!row) continue;
								rows.push({ ...row, repair: { corrections: r.corrections, badRate: r.badRate } });
							}
						}
					}
					recallServed.set(payload.agent.id, signature);
					if (!rows.length) return null;
					// Usage signal: what recall actually put in front of the model is
					// the demand side of the memory's popularity. Fire and forget —
					// logging must never delay or break the step.
					for (const r of rows) void appendUsage(resolveRoot(opts), { href: r.href, kind: 'recall' });
					return createUserMessage(buildRecallMessage(rows));
				};
				// Absolute budget: whichever settles first wins. A timeout injects
				// nothing (silence), never a slow or partial recall.
				recall = await Promise.race([
					buildRecall(),
					new Promise((resolve) => setTimeout(() => resolve(null), budgetMs)),
				]);
				// Passive capture (⑥): append the user's own words to today's RAW layer.
				// Opt-in, best-effort and SIDE-STEPPED: it never blocks, never breaks
				// the step, and never changes what was injected above.
				if (opts.captureUserTurns && userText.trim()) {
					void (async () => {
						try {
							const root = resolveRoot(opts);
							const today = localDateStr();
							const p = path.join(root, `${today}.md`);
							const before = (await readIfExists(p)) ?? dailyTemplate(today);
							const line = captureLineFor(userText, before, opts);
							// The capture writes via appendFile (bypassing writeText's
							// choke point), so the credential scan must run here too —
							// the user's raw words are the MOST likely place for a pasted
							// token.
							if (line) await appendFile(p, `${before.endsWith('\n') || before === '' ? '' : '\n'}${redactSecrets(line).text}\n`, 'utf8');
						} catch {
							/* capture is a best-effort breadcrumb, never a failure */
						}
					})();
				}
			} catch {
				recall = null; // degrade to plain admission
			}
			const decision = await next();
			if (!recall || decision.kind !== 'enter') return decision;
			return { ...decision, messages: [recall, ...decision.messages] };
		}, { prepend: true }),
	);
	const sp = ctx.systemPrompt;
	disposers.push(
		sp.section({
			name: 'memory-manager:discipline',
			order: sp.getSectionOrder('TOOL_REPORT') + 5,
			interpolate: false,
			text: DISCIPLINE_TEXT,
		}),
	);

	// Panel API: optional — without a web server the tools keep working and the
	// panel page shows its fallback text. Resolved lazily via ctx.inject because
	// webServer may not be provided yet at apply time. The memory root is global
	// (~/.dsh/memory), so workspaceRegistry is no longer needed here.
	ctx.inject(['webServer'], (scoped) => {
		const server = scoped.webServer;
		if (server) {
			scoped.effect(() =>
				server.register({ kind: 'prefix', path: '/api/memory-org', handler: memoryPanelApi(opts) }),
			);
		}
	});

	return () => {
		for (const d of disposers.reverse()) d();
	};
}

/**
 * Recall budget (MemOS borrow ⑤): config may SHORTEN the budget but never
 * extend it past the default ceiling — recall must stay bounded no matter how
 * it is configured. Pure so the clamping rule is testable.
 */
export function resolveRecallBudget(configured) {
	const ceiling = DEFAULTS.recallTimeoutMs;
	if (!Number.isFinite(configured)) return ceiling;
	return Math.min(Math.max(0, configured), ceiling);
}

export { name, inject, dshHome, joinDshHome, resolveRoot, resolveDshRoot, runHealthCheck, panelizeHealth, zoneCounts, tokensOf, matchIndexRows, buildRecallMessage, decisionRepairTargets, indexRowsOf, captureLineFor, insightTrust, DEFAULTS, DISCIPLINE_TEXT };
