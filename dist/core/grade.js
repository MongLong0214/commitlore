/**
 * Trust grading (SPEC §7, ADR-0005): the gate between what a commit *says* and
 * what an agent is allowed to *do*.
 *
 * A commit message is an instruction channel. Anyone who can land a commit —
 * including a fork PR author nobody has ever met — can write `Warn:` text that
 * an agent will read as if the repository itself said it. This module is the
 * minimum defence: every record is graded on the two axes of SPEC §7
 * (provenance × lifecycle) plus a configured author-string match, and `Warn:`
 * only survives as a `directive` when all three hold. An author string is
 * selected by the commit author, so this default is useful repository policy,
 * not identity authentication: anyone who can write a commit can forge it.
 * Repositories can opt into Git signature verification as a fourth condition.
 * Everything else degrades to `claim`
 * (surfaced as information, never as an order) or `blocked` (kept out of the
 * injection payload entirely).
 *
 * Every default here fails closed. No `trustedAuthors` means nobody is trusted;
 * an unreadable `Provenance:` value means `unknown`; an injection match outranks
 * every trust signal a record can carry. A false negative — an attacker's line
 * delivered as an instruction — is far more expensive than a false positive,
 * which costs a maintainer one downgraded sentence.
 *
 * The heuristic is not a boundary, it is a speed bump: see `INJECTION_PATTERNS`
 * for what it cannot see. The load-bearing control is the grade, which does not
 * depend on recognising the attack at all.
 */
import { Buffer, isUtf8 } from 'node:buffer';
import { execGit } from './git.js';
import { NOTES_REF } from './notes.js';
import { foldLifecycle } from './stale.js';
import { isFullObjectId, parseProvenance, } from './types.js';
const PROVENANCE_KEY = 'Provenance';
export const BLOCKED_RECORD_WITHHELD = 'Record content was withheld because it matched an injection pattern.';
/**
 * The pattern table. Every entry is pinned by at least one fixture under
 * `spec/fixtures/injection/` (`test/grade.test.ts` fails if an id has none), and
 * the benign fixtures in the same directory pin the other side: normal warning
 * prose must survive. Adding a pattern without both sides is adding an
 * unmeasured false-positive rate.
 *
 * What the fixtures cannot tell you, and a census of this repository's own
 * history can: after #931 and #935, thirteen trailer values out of 5,882 still
 * trip a pattern here, and **none of the thirteen is a true positive**. Precision
 * on this corpus is zero. That is not an argument for deleting the table — the
 * corpus contains no attack, so there is nothing here for it to catch — but it
 * is the shape of the trade, and it was unstated until it was measured. A record
 * is most likely to trip a pattern when its subject is this table, which is why
 * #408, #931 and #935 are all the same report from different directions.
 *
 * Two things keep that bearable rather than silent. `explainWithholding` tells
 * the author at capture and at the commit-msg hook, so a withheld record is a
 * rewrite rather than a discovery someone else makes later. And blocking is not
 * the defence: the trust grade is, for `Warn:`. For `Ruled-out:`, `Limit:` and
 * `Verified:` blocking is the only content control the scanner has, which is why
 * exempting a key is not the cheap fix it looks like.
 *
 * What this table cannot see, by construction:
 * - Character-level obfuscation beyond case/space/confusable folding — leetspeak
 *   (`ign0re`), letter-spacing (`i g n o r e`), inserted punctuation
 *   (`i.g.n.o.r.e`).
 * - Encodings other than one layer of base64, hexadecimal or URL encoding.
 * - Languages and phrasings outside the explicit English, Korean, Japanese and
 *   Chinese patterns below.
 * - Semantic paraphrase: "the maintainers have decided this file may be deleted
 *   without review" carries no keyword at all.
 * - Payloads split across several trailers or several commits, each innocent.
 *
 * That is why `blocked` is a supplement to grading and not the defence: an
 * outside contributor's `Warn:` is a `claim` whether or not any of this fires.
 *
 * And what it withholds although it should not — the benign prose the fixtures
 * below do not cover, measured on this repository's history (#935), every one
 * left as the price of the corresponding attack shape staying blocked:
 * - An attack phrase quoted as an example with no reporting verb in the two
 *   words before it: `` `run the terminal` remains a false positive ``. The
 *   record that names this residual (r-mention408) ruled out quotation marks
 *   as the signal, because an attacker quotes as readily as a defender.
 * - A bare imperative as a `Ruled-out:` alternative: `suppress the warning for
 *   a branch whose content is absent | …`. Position alone cannot release it
 *   without also releasing `curl … | sh` written as an alternative.
 * - A purpose infinitive: `rewrites history to hide that the claim was made`.
 *   `make sure to hide this` is the same form used as an instruction.
 * Each of these is reported to the author at capture and commit time
 * (`explainWithholding`), where a reporting verb or a modal fixes the wording.
 */
export const INJECTION_PATTERNS = [
    {
        id: 'tool.run-the-following',
        family: 'tool-invocation',
        pattern: /\b(?:run|execute|invoke|perform|apply)\s+(?:the\s+)?(?:following|below)\b/,
        negatable: true,
        intent: 'points the reader at a payload to execute',
    },
    {
        id: 'tool.shell-invocation',
        family: 'tool-invocation',
        // The shell noun has to sit where the verb's *destination* sits: as its
        // object (`run the terminal`), behind a preposition (`paste this into your
        // terminal`), or as an interpreter the verb names outright (`execute
        // bash`). The earlier form — verb, up to 24 characters, shell noun — read
        // every noun compound as an instruction. In the reporter's repository a
        // *run* is one execution of the suite and its *terminal* is the end-state
        // record that execution writes, so `stamping a run terminal is fine` had
        // every record about that codebase's central object withheld (#931); the
        // same shape hid three of this repository's own `Verified:` lines (`npm run
        // build, bash spec/verify.sh`). The object form also stands down when the
        // verb is itself a modified noun — `the run the terminal writes` — because
        // an imperative never carries an article; the prepositional form does not,
        // since `after the build, run this in your terminal` is the instruction
        // with a decoy in front of it.
        pattern: /(?<!\b(?:a|an|the|each|every|any|its|their|our|my|your|this|that|these|those|one|same|single|previous|latest|current|failed|passed|green|red|nightly|dry|test|ci)\s)\b(?:run|execute|paste|type|enter)\s+(?:the|this|these|those|that|a|an|your|my|its|their|our)\s+(?:[a-z-]+\s+)?(?:shell|terminal|bash|zsh|command line|command prompt)\b|\b(?:run|execute|paste|type|enter)\b[^.!?]{0,24}\b(?:in|into|inside|within|at|on|via|through|from|with|under|using)\s+(?:(?:the|this|that|these|those|a|an|your|my|its|their|our|any|every|each|some)\s+)?(?:[a-z-]+\s+){0,2}(?:shell|terminal|bash|zsh|command line|command prompt)\b|\b(?:run|execute)\s+(?:bash|zsh)\b/,
        negatable: true,
        intent: 'asks for the value to be typed into a shell',
    },
    {
        id: 'tool.curl-remote',
        family: 'tool-invocation',
        pattern: /\b(?:curl|wget|iwr|invoke-webrequest)\b[^\n]{0,80}?https?:\/\//,
        negatable: true,
        intent: 'fetches remote content with a command-line HTTP client',
    },
    {
        id: 'tool.pipe-to-shell',
        family: 'tool-invocation',
        // Not negatable: a literal interpreter pipeline inside a warning is the one
        // payload worth excluding even when the sentence around it is a caution.
        pattern: /\|\s*(?:sudo\s+)?(?:sh|bash|zsh|dash|ksh|python3?|node|perl|ruby)\b/,
        negatable: false,
        intent: 'pipes a payload into an interpreter',
    },
    {
        id: 'tool.destructive-command',
        family: 'tool-invocation',
        pattern: /\brm\s+-[a-z]{1,4}\b|\bchmod\s+777\b|\bdd\s+if=|\bmkfs\b|\bgit\s+push\s+--force\b|\bgit\s+reset\s+--hard\b/,
        negatable: true,
        intent: 'names a destructive command verbatim',
    },
    {
        id: 'bypass.ignore-previous',
        family: 'policy-bypass',
        pattern: /\b(?:ignore|disregard|forget|override|discard|bypass)\s+(?:(?:all|any|the|your|these|those|my|other|earlier)\s+){0,3}(?:previous|prior|earlier|above|preceding|foregoing|system)\b/,
        negatable: true,
        intent: 'tells the agent to drop the instructions it already has',
    },
    {
        id: 'bypass.ignore-previous.ko',
        family: 'policy-bypass',
        pattern: /(?:이전|앞선|기존|위의)\s*(?:모든\s*)?(?:지시|지침|명령)(?:을|를)?\s*(?:모두\s*)?(?:무시(?:하고|하라|해라|해|하세요|하십시오|해줘)|잊어(?:버리고|라|주세요)|폐기(?:하고|하라|해라))(?!서는?\s*안|면\s*안|지\s*마)/,
        negatable: false,
        intent: 'tells the agent in Korean to drop earlier instructions',
    },
    {
        id: 'bypass.ignore-previous.ja',
        family: 'policy-bypass',
        pattern: /(?:以前|前|先ほど|上記)(?:の)?(?:すべて|全て|全部)?(?:の)?(?:指示|命令|プロンプト)(?:を)?(?:すべて|全て|全部)?(?:無視|忘れ|破棄)(?:しろ|せよ|して|してください)(?!はいけ(?:ません|ない)|はなら(?:ない|ぬ))/,
        negatable: false,
        intent: 'tells the agent in Japanese to drop earlier instructions',
    },
    {
        id: 'bypass.ignore-previous.zh',
        family: 'policy-bypass',
        pattern: /(?<!不要)(?<!不得)(?<!禁止)(?<!请勿)(?<!請勿)(?<!切勿)(?:忽略|无视|無視|忘记|忘記|丢弃|丟棄|覆盖|覆蓋)(?:此前|之前|以前|先前|上述)(?:的)?(?:所有|全部)?(?:系统|系統)?(?:指令|指示|提示|命令)/,
        negatable: true,
        intent: 'tells the agent in Chinese to drop earlier instructions',
    },
    {
        id: 'bypass.new-instructions',
        family: 'policy-bypass',
        pattern: /\b(?:your|the)\s+(?:new|updated|revised|real|actual|true)\s+(?:system\s+)?(?:instruction|instructions|prompt|directive|directives)\b/,
        negatable: true,
        intent: 'claims to replace the agent’s instructions',
    },
    {
        id: 'bypass.supersede-instructions',
        family: 'policy-bypass',
        // The same demand as `bypass.ignore-previous`, phrased as a replacement
        // rather than a deletion (#408). "Ignore your instructions" was recognised;
        // "follow this instead of your instructions" was not, so an attacker only
        // had to reword.
        //
        // The object carries the precision. A replacement construction is ordinary
        // engineering prose — "this takes precedence over the per-request timeout"
        // — and becomes an attack only when what it replaces is the agent's own
        // instructions. `rules` and `guidelines` are deliberately absent: business
        // rules take precedence over each other all the time.
        pattern: /\b(?:instead of|rather than|in place of|supersedes?|superseding|overrides?|overriding|takes? precedence over|taking precedence over|takes? priority over)\s+(?:(?:all|any|the|your|these|those|my|other|earlier|previous|prior|existing|current|original|system|agent|above)\s+){0,4}(?:instruction|instructions|prompt|prompts|directive|directives)\b/,
        negatable: true,
        intent: 'claims to replace the agent’s instructions rather than delete them',
    },
    {
        id: 'bypass.role-marker',
        family: 'policy-bypass',
        // A chat role marker inside a commit trailer is never prose; it is an
        // attempt to forge a turn boundary in whatever transcript the record lands in.
        pattern: /\b(?:system|assistant|developer)\s*:\s*(?:you\b|do\b|ignore\b|always\b|never\b|new\b|from now\b)/,
        negatable: false,
        intent: 'forges a chat role boundary',
    },
    {
        id: 'bypass.persona-override',
        family: 'policy-bypass',
        pattern: /\byou are (?:now|no longer|actually|really)\b|\b(?:from now on|henceforth)\b[^.!?]{0,20}\byou\b|\b(?:act|behave)\s+as\s+(?:a|an|the|if)\b|\bpretend\s+(?:to\s+be|that|you)\b/,
        negatable: true,
        intent: 'reassigns the agent’s role',
    },
    {
        id: 'privilege.sudo',
        family: 'privilege-escalation',
        // The lookahead keeps "requires sudo access on the build box" — a statement
        // about privilege — out of "sudo <command>", a request for it.
        pattern: /\bsudo\s+(?!access\b|privilege|privileges\b|rights\b|permission|permissions\b|is\b|was\b|required\b|needed\b|user\b)[a-z0-9_./-]+/,
        negatable: true,
        intent: 'invokes a command with sudo',
    },
    {
        id: 'privilege.as-root',
        family: 'privilege-escalation',
        pattern: /\b(?:run|execute|launch|start|install|deploy|apply)\b[^.!?]{0,24}\bas\s+(?:root|admin|administrator|superuser)\b|\bwith\s+(?:root|admin|administrator|superuser|elevated)\s+(?:rights|privileges|access|permission|permissions)\b/,
        negatable: true,
        intent: 'asks for the work to be done with elevated privileges',
    },
    {
        id: 'credential.print-env',
        family: 'credential-exfiltration',
        pattern: /\b(?:print|echo|output|show|display|dump|reveal|cat|send|post|upload|paste|list)\b[^.!?]{0,24}\b(?:env|envs|\.env|dotenv|environment|environment variable|environment variables)\b/,
        negatable: true,
        intent: 'asks for the environment to be printed',
    },
    {
        id: 'credential.exfiltrate-secret',
        family: 'credential-exfiltration',
        pattern: /\b(?:print|echo|output|show|display|dump|reveal|send|share|paste|upload|post|exfiltrate|leak|email)\b[^.!?]{0,32}\b(?:api[ -]?keys?|secrets?|tokens?|credentials?|passwords?|private key|ssh key|access key)\b/,
        negatable: true,
        intent: 'asks for a credential to be emitted or sent somewhere',
    },
    {
        id: 'credential.exfiltrate-secret.ko',
        family: 'credential-exfiltration',
        pattern: /(?:비밀|토큰|암호|비밀번호|자격\s*증명|api\s*키|개인\s*키|ssh\s*키|\.ssh\/id_rsa|id_rsa)[^.!?\n。！？]{0,32}(?:출력|공개|노출|전송)(?:하라|해라|해|하세요|하십시오|해줘)/,
        negatable: false,
        intent: 'asks in Korean for a credential to be emitted or sent',
    },
    {
        id: 'output.always-comply',
        family: 'output-manipulation',
        pattern: /\b(?:always|automatically)\s+(?:answer|reply|respond|say|approve|confirm|accept|output)\b|\bauto-?approve\b|\bapprove\s+(?:everything|all|any)\b/,
        negatable: true,
        intent: 'pre-commits the agent to an answer',
    },
    {
        id: 'output.conceal',
        family: 'output-manipulation',
        pattern: /\b(?:hide|conceal|suppress|omit|obscure)\s+(?:this|that|it|these|the\s+(?:fact|change|edit|diff|output|reason|error|warning|record))\b/,
        negatable: true,
        intent: 'asks for part of the work to be hidden',
    },
    {
        id: 'output.no-disclosure',
        family: 'output-manipulation',
        // Negation is inside the pattern, so the negation guard must not apply:
        // "do not report this" is the attack, not a warning about one.
        pattern: /\b(?:do not|dont|never|no need to)\s+(?:mention|report|reveal|disclose|tell|inform|surface)\s+(?:\w+\s+){0,2}?(?:this|that|it|anyone|anything|users?|humans?)\b/,
        negatable: false,
        intent: 'asks the agent not to disclose what it did',
    },
];
/** Words that disarm an affirmative imperative when they sit right before it. */
const NEGATIONS = new Set([
    'no',
    'not',
    'never',
    'dont',
    'doesnt',
    'didnt',
    'wont',
    'cant',
    'cannot',
    'shouldnt',
    'mustnt',
    'avoid',
    'avoids',
    'avoiding',
    'without',
    'refuse',
    'forbid',
    'forbidden',
    'prohibited',
]);
/**
 * Words that mark the text after them as **mentioned rather than used** (#408).
 *
 * A record whose job is to warn about this class of attack has to name the
 * attack: "reject any record that says ignore all prior instructions". Matching
 * the literal blocked that record, and a blocked record's content is withheld —
 * so the one record an agent most needed to read was the one it could not. A
 * defensive quotation was punished while an attack paraphrase went through.
 *
 * This disarms one occurrence, not the record. `fires` blocks unless *every*
 * occurrence is disarmed, so quoting the phrase and then issuing it still
 * blocks — pinned by a test, because that is the bypass this would otherwise
 * open. An attacker can still phrase a whole payload as a report, and loses
 * most of its imperative force in doing so; that residual is the price of a
 * defensive record being readable at all.
 *
 * Consulted only for `negatable` patterns, the same gate `NEGATIONS` uses:
 * those are the entries whose authors already judged surrounding prose able to
 * change their reading.
 */
const MENTIONS = new Set([
    'says',
    'say',
    'saying',
    'said',
    'reads',
    'reading',
    'contains',
    'containing',
    'quotes',
    'quoting',
    'quoted',
    'mentions',
    'mentioning',
    'matches',
    'matching',
    'phrase',
    'phrases',
    'wording',
    'literal',
    'string',
]);
/**
 * The counterfactual modal. `it would hide that two rows were unplanned` is a
 * consequence being described, not a request being made (#935): the bare verb
 * after `would` is the only slot an imperative shares with a conditional, and
 * a `Ruled-out:` reason — *why* an alternative was dropped — is written in
 * exactly that mood. Measured on this repository's history, 6 of the 7
 * `output.conceal` withholdings sat in a reason, 4 of them literally
 * `… would hide that …`; the other two (`to hide that`, `and hide it`) stay
 * withheld, for the reasons the table header gives.
 *
 * Read at the word immediately before the match, not across the window the
 * other sets use: `would you hide this` is a request, and the pronoun between
 * modal and verb is what makes it one. `could`, `might`, `should` and `can`
 * are deliberately absent — `you could paste this into your terminal` is an
 * instruction wearing a modal, and this set exists for the one modal that
 * cannot address the reader.
 */
const IRREALIS = new Set(['would']);
/** How many words before a match the negation guard reads. */
const NEGATION_LOOKBACK = 2;
/** Invisible characters: they change nothing on screen and everything to a regex. */
const INVISIBLE_RE = /[\u00AD\u180E\u200B-\u200F\u202A-\u202E\u2060-\u2064\uFEFF]/g;
/** ANSI CSI sequences, removed whole so stripping cannot join an attack after grading. */
const ANSI_ESCAPE_RE = /\u001B\[[0-?]*[ -/]*[@-~]/g;
/** Combining marks removed from Latin letters — `íg̃nore` must fold to `ignore`. */
const COMBINING_RE = /\p{M}/gu;
const LATIN_CLUSTER_RE = /\p{Script=Latin}\p{M}*/gu;
const stripTransportNoise = (text) => text.replace(ANSI_ESCAPE_RE, '').replace(INVISIBLE_RE, '');
/**
 * Latin lookalikes from other scripts. NFKC does not touch these (they are
 * distinct letters, not compatibility forms), so `іgnоrе` — Cyrillic і and о and
 * е — sails past every ASCII pattern until it is folded here.
 */
const CONFUSABLES = new Map([
    ['а', 'a'], // а CYRILLIC
    ['е', 'e'], // е
    ['к', 'k'], // к
    ['н', 'h'], // н
    ['о', 'o'], // о
    ['р', 'p'], // р
    ['с', 'c'], // с
    ['т', 't'], // т
    ['у', 'y'], // у
    ['х', 'x'], // х
    ['ѕ', 's'], // ѕ
    ['і', 'i'], // і
    ['ј', 'j'], // ј
    ['һ', 'h'], // һ
    ['ӏ', 'l'], // ӏ
    ['ԁ', 'd'], // ԁ
    ['ԛ', 'q'], // ԛ
    ['ԝ', 'w'], // ԝ
    ['α', 'a'], // α GREEK
    ['ε', 'e'], // ε
    ['ι', 'i'], // ι
    ['κ', 'k'], // κ
    ['ν', 'v'], // ν
    ['ο', 'o'], // ο
    ['ρ', 'p'], // ρ
    ['τ', 't'], // τ
    ['υ', 'u'], // υ
    ['χ', 'x'], // χ
    ['ı', 'i'], // ı DOTLESS I
    ['ɡ', 'g'], // ɡ SCRIPT G
    ['‘', ''], // curly quotes: dropped so don’t folds to dont
    ['’', ''],
    ['ʼ', ''],
    ["'", ''],
    ['`', ''],
    ['´', ''],
    ['‐', '-'], // dash family
    ['‑', '-'],
    ['‒', '-'],
    ['–', '-'],
    ['—', '-'],
    ['―', '-'],
]);
/**
 * Folds a value to the form the patterns are written against.
 *
 * The order is load-bearing. NFKC first, which collapses the cheap evasions in
 * one step: fullwidth (`ｉｇｎｏｒｅ`), mathematical alphanumerics (`𝐢𝐠𝐧𝐨𝐫𝐞`),
 * ligatures. Then invisibles, which would otherwise split a word in the middle
 * (`ig​nore`). Then case, then accents, then cross-script lookalikes, and
 * finally whitespace — so `IGNORE  PREVIOUS` and `ignore previous` are the same
 * string by the time any pattern sees them. Accent folding is limited to Latin
 * letters so Hangul and kana retain the characters multilingual patterns use.
 *
 * Match-only: the result is not safe to display.
 */
export const normalizeForMatch = (text) => {
    const folded = stripTransportNoise(text.normalize('NFKC'))
        .toLowerCase()
        .replace(LATIN_CLUSTER_RE, (cluster) => cluster.normalize('NFD').replace(COMBINING_RE, ''));
    let mapped = '';
    for (const char of folded)
        mapped += CONFUSABLES.get(char) ?? char;
    return mapped.replace(/\s+/g, ' ').trim();
};
const URL_ESCAPE_RE = /%[0-9a-f]{2}/i;
const URL_RUN_RE = /(?:%[0-9a-f]{2})+/gi;
const BASE64_TOKEN_RE = /(?<![a-z0-9+/_-])[a-z0-9+/_-]{16,}=*(?![a-z0-9+/_=-])/gi;
const PADDED_BASE64_PREFIX_RE = /(?<![a-z0-9+/_-])[a-z0-9+/_-]{16,}=+/gi;
const WRAPPED_BASE64_TOKEN_RE = /(?<![a-z0-9+/_-])(?:(?:[a-z0-9+/_-]{4})+[ \t\r\n]+)+(?:[a-z0-9+/_-]{4})+(?:[a-z0-9+/_-]{2,3}=*)?(?![a-z0-9+/_=-])/gi;
const HEX_TOKEN_RE = /(?<![0-9a-f])(?:0x)?([0-9a-f]{16,})(?![0-9a-f])/gi;
const CONTROL_RE = /[\u0000-\u001F\u007F-\u009F]/g;
const addDecoded = (decoded, bytes) => {
    if (!isUtf8(bytes))
        return;
    const text = bytes.toString('utf8');
    if (text !== '')
        decoded.add(text);
};
/** One speculative decode layer; failure never replaces the original text. */
const decodedCandidates = (text) => {
    const decoded = new Set();
    if (URL_ESCAPE_RE.test(text)) {
        decoded.add(text.replace(URL_RUN_RE, (run) => {
            const bytes = Buffer.from(run.replaceAll('%', ''), 'hex');
            return bytes.toString('utf8');
        }));
    }
    for (const scanner of [
        BASE64_TOKEN_RE,
        PADDED_BASE64_PREFIX_RE,
        WRAPPED_BASE64_TOKEN_RE,
    ]) {
        for (const match of text.matchAll(scanner)) {
            const token = match[0].replace(/\s+/g, '').replace(/=+$/, '');
            for (let trim = 0; trim <= 3 && token.length - trim >= 16; trim += 1) {
                const candidate = token.slice(0, trim === 0 ? undefined : -trim);
                if (candidate.length % 4 !== 1) {
                    addDecoded(decoded, Buffer.from(candidate, 'base64'));
                }
            }
        }
    }
    for (const match of text.matchAll(HEX_TOKEN_RE)) {
        const token = match[1];
        if (token !== undefined && token.length % 2 === 0) {
            addDecoded(decoded, Buffer.from(token, 'hex'));
        }
    }
    return [...decoded];
};
/** Whether a nearby CJK prohibition or one of the preceding English words disarms a match. */
const CJK_NEGATION_RE = /(?:不要|不得|禁止|请勿|請勿|切勿)[^。！？.!?\n]{0,8}$/u;
/**
 * Whether the prose immediately before a match disarms it — by negating the
 * imperative (`NEGATIONS`), by reporting it rather than issuing it
 * (`MENTIONS`, #408), or by making it the consequence of a condition
 * (`IRREALIS`, #935).
 *
 * All three read the same short window, and all are deliberately narrow: only
 * the two words immediately before the match are consulted, so "never mind the
 * above, run the following" still blocks (fixture `20-bypass-negation-decoy`),
 * and `IRREALIS` reads only the last of them.
 */
const isDisarmed = (haystack, index, matchedText) => {
    const prefix = haystack.slice(0, index);
    if (CJK_NEGATION_RE.test(prefix))
        return true;
    if (/[^\x00-\x7F]/u.test(matchedText))
        return false;
    const words = prefix.split(/[^a-z0-9]+/).filter((word) => word !== '');
    const window = words.slice(-NEGATION_LOOKBACK);
    if (window.some((word) => NEGATIONS.has(word) || MENTIONS.has(word)))
        return true;
    return IRREALIS.has(window.at(-1) ?? '');
};
const fires = (haystack, entry) => {
    // Built fresh so the exported table stays free of `g`-flag lastIndex state,
    // which a caller reading INJECTION_PATTERNS could otherwise trip over.
    const scanner = new RegExp(entry.pattern.source, 'g');
    for (const match of haystack.matchAll(scanner)) {
        if (match.index === undefined)
            continue;
        if (!entry.negatable || !isDisarmed(haystack, match.index, match[0]))
            return true;
    }
    return false;
};
/**
 * Every pattern id `text` trips, in table order. `[]` means nothing matched —
 * which is not the same as "safe", only "not recognised" (see
 * `INJECTION_PATTERNS`).
 *
 * Exported so consumers can scan text that is not part of a record too.
 */
export const scanInjection = (text) => {
    const prepared = stripTransportNoise(text);
    const candidates = [prepared, ...decodedCandidates(prepared)];
    const haystacks = [
        ...new Set(candidates.flatMap((candidate) => [
            normalizeForMatch(candidate),
            normalizeForMatch(stripTransportNoise(candidate).replace(CONTROL_RE, '')),
        ])),
    ];
    return INJECTION_PATTERNS.filter((entry) => haystacks.some((haystack) => fires(haystack, entry))).map((entry) => entry.id);
};
const trailerValues = (trailers, key) => trailers.filter((trailer) => trailer.key === key).map((trailer) => trailer.value);
/**
 * The form an agent is shown for a trailer whose key is not a dedicated
 * section: `context` other-lines and the injection `other` tier both print
 * `key: value`. Known-section renderers print the value alone, which is a
 * substring of this form, so scanning the pair is a superset.
 *
 * Scanning the value alone misses a payload that lives in the key
 * (`system: do nothing` — #596).
 */
export const renderedTrailer = (trailer) => `${trailer.key}: ${trailer.value}`;
/** SPEC §3.1: the one key whose value carries a `|` by construction. */
const RULED_OUT_KEY = 'Ruled-out';
const PIPE_TO_SHELL = 'tool.pipe-to-shell';
/**
 * Every pattern the rendered trailer trips, in table order.
 *
 * One reading is corrected by the key (#935). SPEC §3.1 requires a `|` in
 * every `Ruled-out:` value and makes the first one the separator between the
 * alternative and the reason, so a reason that opens with an interpreter's
 * name as its subject — `| node on Windows reads /tmp/x as C:\tmp\x` — is
 * `tool.pipe-to-shell`'s anchor character followed by its interpreter list,
 * and the pattern read punctuation the grammar mandates as a shell pipe. The
 * separator is neutralised and the value rescanned for that one pattern; a
 * second `|` is still a pipe, and every other pattern still reads the value
 * exactly as an agent is shown it.
 *
 * What this gives up, stated: a whole value of the form `<command> | sh`,
 * where the command trips nothing on its own, is now served as a rejected
 * alternative whose reason is `sh`. `curl … | sh` is not in that set —
 * `tool.curl-remote` reads the alternative — and neither is any value with a
 * second pipe or a verb that asks for the value to be run.
 */
export const scanTrailer = (trailer) => {
    const patterns = scanInjection(renderedTrailer(trailer));
    if (trailer.key !== RULED_OUT_KEY || !patterns.includes(PIPE_TO_SHELL))
        return patterns;
    const separator = trailer.value.indexOf('|');
    if (separator < 0)
        return patterns;
    const unseparated = `${trailer.value.slice(0, separator)} ${trailer.value.slice(separator + 1)}`;
    if (scanInjection(renderedTrailer({ ...trailer, value: unseparated })).includes(PIPE_TO_SHELL)) {
        return patterns;
    }
    return patterns.filter((id) => id !== PIPE_TO_SHELL);
};
/**
 * Whether an identity string would itself trip the scanner, either as the
 * bare value a report prints or as the `Record-Id: …` pair some surfaces
 * still emit. A withheld record whose id is still printed is not withheld.
 */
export const identityCarriesInjection = (recordId) => scanInjection(recordId).length > 0 || scanInjection(`Record-Id: ${recordId}`).length > 0;
/**
 * Why a trailer would be withheld, said to the one person who can still change
 * it (#931). Grading is a read-time judgement: the author of a record that
 * trips a pattern got `staged` from capture and `shape ok` from the commit-msg
 * hook, and learned at query time, from a different reader, that every trailer
 * of the record was gone. Capture verification and `validate` both say this,
 * through one function, so the author hears the same sentence twice rather
 * than two sentences that might disagree.
 */
export const explainWithholding = (key, patterns) => {
    const named = INJECTION_PATTERNS.filter((entry) => patterns.includes(entry.id)).map((entry) => `${entry.id} (${entry.intent})`);
    return (`${key}: reads as an instruction to an agent — it matches ${named.join(', ')} — so every ` +
        'reader would be served this record as [blocked] with all of its trailers withheld (SPEC §7). ' +
        'Reword the value so it describes rather than instructs, or drop the trailer');
};
/*
 * Every trailer is scanned in the form an agent is shown, including the ones
 * whose keys hold enumerated values.
 *
 * Those keys used to be skipped, on the reasoning that a validated `Blast:`
 * cannot carry prose. Validation runs at commit time and grading runs on
 * records read back out of history, where `--no-verify`, missing hooks and
 * rewritten branches all produce trailers that never passed it — so the skip
 * exempted from scanning whatever an attacker chose to put under an exempt key,
 * and `Blast:` is rendered into the projection the agent reads.
 *
 * Asking the validator per trailer would close that, and it pulls the JSON
 * schema stack onto the hot path: `core/schema.ts` imports AJV, so grading
 * would drag a dependency into every hook invocation, and into builds that
 * resolve `dist/` without `node_modules` beside it. Scanning instead costs a
 * few regexes against short strings and needs nothing new. It also cannot
 * drift, which a second hand-written copy of the enums could.
 *
 * The exemption bought nothing: no legal value of any of these keys matches any
 * pattern, which `test/grade.test.ts` pins. Scanning the pair rather than the
 * value does not change that: `Blast: system` is a legal pair and trips
 * nothing.
 */
const scanRecord = (record) => {
    const matchedPatterns = new Set();
    const matchedKeys = new Set();
    for (const trailer of record.trailers) {
        const patterns = scanTrailer(trailer);
        if (patterns.length === 0)
            continue;
        matchedKeys.add(trailer.key);
        patterns.forEach((pattern) => matchedPatterns.add(pattern));
    }
    return {
        patterns: INJECTION_PATTERNS.filter((entry) => matchedPatterns.has(entry.id)).map((entry) => entry.id),
        keys: [...matchedKeys],
    };
};
/**
 * The record's provenance, from its own field when the caller resolved one and
 * from `Provenance:` otherwise. Absent, malformed, or unrecognised all land on
 * `unknown`: a value this module cannot read is a value it cannot trust, and
 * `unknown` is the reading that costs least when it is wrong.
 */
const provenanceOf = (record) => {
    if (record.provenance !== undefined)
        return record.provenance;
    const raw = trailerValues(record.trailers, PROVENANCE_KEY)[0];
    return parseProvenance(raw) ?? { kind: 'unknown' };
};
/**
 * The lifecycle to grade against.
 *
 * A non-`active` state always wins, whichever source it came from. The caller's
 * `record.lifecycle` may have been folded over a longer history than the stream
 * handed to `gradeAll`, and the fold may see a supersession the single record
 * cannot — taking the more restrictive of the two means neither view can quietly
 * promote a retired record back to `active`.
 */
const lifecycleOf = (record, at, folded) => {
    if (record.lifecycle !== undefined && record.lifecycle !== 'active')
        return record.lifecycle;
    if (folded !== undefined)
        return folded;
    if (record.lifecycle !== undefined)
        return record.lifecycle;
    // No stream context: the record can still expire on its own `Expires:` date.
    return foldLifecycle([record], { at })[0]?.lifecycle ?? 'active';
};
/** `Name <email>` splits into the whole string, the name, and the email. */
const AUTHOR_EMAIL_RE = /^(.*?)\s*<([^>]+)>$/;
const identitiesOf = (author) => {
    const trimmed = author.trim();
    const match = AUTHOR_EMAIL_RE.exec(trimmed);
    if (match === null)
        return [trimmed];
    const name = match[1]?.trim() ?? '';
    const email = match[2]?.trim() ?? '';
    return [trimmed, name, email].filter((identity) => identity !== '');
};
/**
 * Whether `author` matches a repository-configured author string.
 *
 * Undefined or empty `trustedAuthors` elects no strings. That default is the
 * feature: a caller that forgets to pass the list gets every record downgraded
 * to `claim`, which is loud and harmless — the opposite default would turn the
 * check off silently. This is not authentication: the commit author chose the
 * string being matched. There is no wildcard entry; `*` in the list matches an
 * author literally called `*`.
 *
 * Comparison is exact after trimming, with `Name <email>` also matching on
 * either half. An identity that differs by case does not match, and degrades to
 * `claim` — the safe direction for a misconfigured list.
 */
export const isTrustedAuthor = (author, trustedAuthors) => {
    if (author === undefined || trustedAuthors === undefined)
        return false;
    const trusted = new Set(trustedAuthors.map((entry) => entry.trim()).filter((entry) => entry !== ''));
    if (trusted.size === 0)
        return false;
    return identitiesOf(author).some((identity) => trusted.has(identity));
};
/**
 * Whether Git's exact signing-key fingerprint is in repository policy.
 *
 * This deliberately has no partial, email, or case-folded matching. `%GF` is
 * Git's signer identifier; accepting a lookalike turns an allowlist into a
 * hint. Missing and empty lists therefore authorize nobody.
 */
export const isTrustedSignerFingerprint = (fingerprint, trustedSignerFingerprints) => {
    if (fingerprint === undefined || trustedSignerFingerprints === undefined)
        return false;
    const trusted = new Set(trustedSignerFingerprints.map((entry) => entry.trim()).filter((entry) => entry !== ''));
    return trusted.has(fingerprint.trim());
};
const quoted = (value) => JSON.stringify(value);
const grade = (input, ctx) => {
    const { record, author, folded } = input;
    const provenance = provenanceOf(record).kind;
    const lifecycle = lifecycleOf(record, ctx.at, folded);
    const matched = scanRecord(record);
    // Checked first and unconditionally: a payload whose author string matches is
    // still a payload, whether they were compromised or careless.
    if (matched.patterns.length > 0) {
        return {
            provenance,
            lifecycle,
            trust: 'blocked',
            reason: `${matched.keys.map((key) => `${key}:`).join(', ')} matched ${matched.patterns.length} injection pattern(s): ${matched.patterns.join(', ')}`,
            matchedPatterns: matched.patterns,
            matchedTrailerKeys: matched.keys,
        };
    }
    const claim = (reason) => ({ provenance, lifecycle, trust: 'claim', reason });
    if (provenance === 'reconstructed') {
        return claim('provenance is reconstructed — rebuilt from history, never directly authored');
    }
    // ADR-0030. Capture may stage a record without anyone reading it, and such a
    // record is real — its quotes were checked against the transcript and the
    // diff it was drafted from. What it lacks is a person who stood behind the
    // wording, and that is exactly what `directive` claims. The cap is here
    // rather than in the pipeline because grading is what consumer routes ask,
    // and a rule the writer could decline to apply is not a rule.
    if (provenance === 'drafted') {
        return claim('provenance is drafted — captured without a person reading it');
    }
    if (provenance !== 'authored') {
        return claim(`provenance is ${provenance}, and only authored records can direct an agent`);
    }
    if (author === undefined) {
        return claim('no commit author is known, so no configured author string can match');
    }
    if (ctx.trustedAuthors === undefined || ctx.trustedAuthors.length === 0) {
        return claim(`no directive author strings are configured, so ${quoted(author)} cannot direct`);
    }
    if (!isTrustedAuthor(author, ctx.trustedAuthors)) {
        return claim(`author ${quoted(author)} does not match a configured author string`);
    }
    const signatureStatus = record.signatureStatus;
    if (ctx.requireSignedDirective === true && signatureStatus !== 'G') {
        return claim(`commit signature status ${quoted(signatureStatus ?? 'unavailable')} is not Git-verified by this verifier`);
    }
    if (ctx.requireSignedDirective === true && (ctx.trustedSignerFingerprints?.length ?? 0) === 0) {
        return claim('no authorized signer fingerprints are configured for signature mode');
    }
    const signerFingerprint = record.signerFingerprint;
    if (ctx.requireSignedDirective === true &&
        !isTrustedSignerFingerprint(signerFingerprint, ctx.trustedSignerFingerprints)) {
        return claim(`verified signer fingerprint ${quoted(signerFingerprint ?? 'unavailable')} is not authorized by repository policy`);
    }
    if (lifecycle !== 'active') {
        return claim(`record is ${lifecycle} and no longer directs anything`);
    }
    return {
        provenance,
        lifecycle,
        trust: 'directive',
        reason: ctx.requireSignedDirective === true
            ? `authored by configured author string ${quoted(author)}, Git signature verified by an authorized signer fingerprint, active, no injection pattern matched`
            : `authored by configured author string ${quoted(author)}, active, no injection pattern matched (author strings are unauthenticated)`,
    };
};
/**
 * Grades one record. `ctx.author` supplies the commit author when the record
 * carries none of its own.
 *
 * With no surrounding stream the lifecycle axis sees only what the record says
 * about itself — an `Expires:` date, nothing more. A supersession lives in
 * *another* commit, so a caller that cares about it must either fold first (and
 * pass `record.lifecycle`) or use `gradeAll`.
 */
export const gradeRecord = (record, ctx) => {
    const author = record.author ?? ctx.author;
    return grade({ record, author, folded: undefined }, ctx);
};
/** blocked outranks claim outranks directive. */
export const TRUST_RANK = { directive: 0, claim: 1, blocked: 2 };
/**
 * Keeps the more restrictive of two grades for the same `Record-Id`.
 *
 * Records fold by identity (SPEC §5), so one `Record-Id` can be declared by
 * several commits — and nothing stops one of them coming from an outside
 * contributor. Latest-commit-wins is right for trailer *values*; for trust it
 * would let an attacker upgrade their own record by appending a commit, so
 * trust takes the floor of every declaration instead.
 */
export const restrictGrade = (a, b) => {
    const kept = TRUST_RANK[b.trust] > TRUST_RANK[a.trust] ? b : a;
    const patterns = [...new Set([...(a.matchedPatterns ?? []), ...(b.matchedPatterns ?? [])])];
    if (patterns.length === 0)
        return kept;
    const keys = [...new Set([...(a.matchedTrailerKeys ?? []), ...(b.matchedTrailerKeys ?? [])])];
    return { ...kept, matchedPatterns: patterns, matchedTrailerKeys: keys };
};
/**
 * Grades a whole stream, keyed by `Record-Id`.
 *
 * The stream is folded once (`foldLifecycle`) so supersessions and expiries are
 * seen, then every record is graded against its own author. Records that
 * declare no `Record-Id` still get an entry — keyed by sha, or by `#<index>`
 * when there is not even that — because dropping a record from the map would
 * hide it from a caller that filters on grade.
 */
export const gradeAll = (records, ctx) => {
    const folded = new Map(foldLifecycle(records, { at: ctx.at }).map((state) => [state.recordId, state.lifecycle]));
    const graded = new Map();
    records.forEach((record, index) => {
        const recordId = record.recordId ?? trailerValues(record.trailers, 'Record-Id')[0];
        const key = recordId ?? record.sha ?? `#${index}`;
        const one = grade({
            record,
            author: record.author ?? ctx.author,
            folded: recordId === undefined ? undefined : folded.get(recordId),
        }, ctx);
        const previous = graded.get(key);
        graded.set(key, previous === undefined ? one : restrictGrade(previous, one));
    });
    return graded;
};
// ---------------------------------------------------------------------------
// Commit authorship — the input grading cannot be honest without
// ---------------------------------------------------------------------------
/** Commits per `git show`. Keeps the argument list well inside any exec limit. */
const AUTHOR_BATCH = 200;
const AUTHOR_RECORD_SEP = '\x01';
const AUTHOR_FIELD_SEP = '\0';
/**
 * `%x01`/`%x00` rather than the literal bytes: `spawnSync` refuses an argument
 * containing a NUL, and these reach git as text and come back as bytes.
 */
const AUTHOR_FORMAT = '--format=%x01%H%x00%an <%ae>%x00%G?%x00%GF';
/**
 * Maps each commit to its **author** identity, `Name <email>`.
 *
 * Author, never committer: a fork PR is committed by whoever merged it, and
 * grading on the committer would hand every outside contributor the merger's
 * trust (`spec/contract-cases/grade-external-contributor.yaml`).
 *
 * A commit git cannot resolve simply has no entry, and a record with no known
 * author grades as a `claim` — the fail-closed direction.
 *
 * This lives here rather than in `inject.ts`, where it was written, because
 * grading is only as good as the authorship it sees: a consumer that cannot get
 * the author cannot call `gradeRecord` and ends up writing its own weaker rule.
 * `query.ts` did exactly that, and graded every record from every author
 * `directive`.
 */
export const authorsOf = (cwd, shas) => {
    const wanted = [...new Set(shas)].filter((sha) => isFullObjectId(sha)).sort();
    const authors = new Map();
    for (let start = 0; start < wanted.length; start += AUTHOR_BATCH) {
        const batch = wanted.slice(start, start + AUTHOR_BATCH);
        const result = execGit(['show', '-s', AUTHOR_FORMAT, ...batch], { cwd });
        if (result.code !== 0)
            continue;
        for (const chunk of result.stdout.split(AUTHOR_RECORD_SEP)) {
            const [sha = '', author = ''] = chunk.split(AUTHOR_FIELD_SEP);
            if (sha === '')
                continue;
            authors.set(sha.trim(), author.trim());
        }
    }
    return authors;
};
/** Maps each commit to Git's exact `%GF` signing-key fingerprint. */
export const signerFingerprintsOf = (cwd, shas) => {
    const wanted = [...new Set(shas)].filter((sha) => isFullObjectId(sha)).sort();
    const fingerprints = new Map();
    for (let start = 0; start < wanted.length; start += AUTHOR_BATCH) {
        const batch = wanted.slice(start, start + AUTHOR_BATCH);
        const result = execGit(['show', '-s', AUTHOR_FORMAT, ...batch], { cwd });
        if (result.code !== 0)
            continue;
        for (const chunk of result.stdout.split(AUTHOR_RECORD_SEP)) {
            const [sha = '', _author = '', _status = '', fingerprint = ''] = chunk.split(AUTHOR_FIELD_SEP);
            if (sha.trim() === '' || fingerprint.trim() === '')
                continue;
            fingerprints.set(sha.trim(), fingerprint.trim());
        }
    }
    return fingerprints;
};
export const noteAuthorsOf = (cwd) => {
    const authors = new Map();
    const result = execGit(['log', AUTHOR_FORMAT, '--name-only', '--no-renames', '--no-color', NOTES_REF], { cwd });
    // No notes ref, an unreadable one, or a repository with no commits: no
    // attributions, so every notes-sourced record falls to `claim`.
    if (result.code !== 0)
        return authors;
    for (const chunk of result.stdout.split(AUTHOR_RECORD_SEP)) {
        if (chunk === '')
            continue;
        const [head = '', authorField = '', status = '', fingerprintAndPaths = ''] = chunk.split(AUTHOR_FIELD_SEP);
        if (head.trim() === '')
            continue;
        const [fingerprint = '', ...pathLines] = fingerprintAndPaths.split('\n');
        const noteAuthor = authorField.trim();
        if (noteAuthor === '')
            continue;
        const writer = {
            author: noteAuthor,
            signatureStatus: status.trim(),
            signerFingerprint: fingerprint.trim(),
        };
        for (const line of pathLines) {
            const annotated = line.trim().replace(/\//g, '');
            if (!isFullObjectId(annotated))
                continue;
            const seen = authors.get(annotated);
            if (seen === undefined)
                authors.set(annotated, [writer]);
            else if (!seen.some((existing) => existing.author === writer.author &&
                existing.signatureStatus === writer.signatureStatus &&
                existing.signerFingerprint === writer.signerFingerprint)) {
                seen.push(writer);
            }
        }
    }
    return authors;
};
/**
 * Who to grade a record's declarations by, per source.
 *
 * A record can be declared by several commits and can arrive from both the
 * commit message and the notes mirror at once. Each declaration is graded by
 * the identity that wrote *that* declaration, and the floor is kept — the same
 * rule `restrictGrade` applies across commits, extended to the axis #409
 * showed was missing.
 *
 * A record whose only source is `notes` is therefore never graded by the
 * annotated commit's author, and a mirrored record cannot be promoted by the
 * friendlier of its two authorships. That downgrades a mirror written by a bot
 * identity to `claim` until the bot's author string is configured, which is the
 * fail-closed direction and is visible in the record's reason.
 *
 * A note carries every identity that has written it, not just the latest, so a
 * blob two writers were merged into is graded against both (`noteAuthorsOf`).
 *
 * Both consumer routes call this rather than looping themselves. `query.ts` and
 * `inject.ts` each had their own copy of the loop, and two implementations of
 * one policy is one implementation and one hole.
 */
export const gradeDeclarations = (record, declarations, ctx) => {
    const { shas, sources, commitAuthors, commitSignatures, commitSignerFingerprints, noteAuthors } = declarations;
    // An empty `sources` predates the field; treat it as a commit declaration so
    // an older caller keeps the behaviour it had.
    const fromNotes = sources.includes('notes');
    const fromCommit = sources.length === 0 || sources.includes('commit');
    // The declaration's author is written onto the record and withheld from the
    // context, because `gradeRecord` reads `record.author` first: leaving either
    // in place would let the record's own field, or a caller's fallback identity,
    // speak for a declaration it did not write. An unattributed declaration keeps
    // `undefined` here and grades `claim`.
    const base = {
        at: ctx.at,
        ...(ctx.trustedAuthors === undefined ? {} : { trustedAuthors: ctx.trustedAuthors }),
        ...(ctx.requireSignedDirective === true ? { requireSignedDirective: true } : {}),
        ...(ctx.trustedSignerFingerprints === undefined
            ? {}
            : { trustedSignerFingerprints: ctx.trustedSignerFingerprints }),
    };
    let worst;
    const consider = (author, signatureStatus, signerFingerprint) => {
        const one = gradeRecord({ ...record, author, signatureStatus, signerFingerprint }, base);
        worst = worst === undefined ? one : restrictGrade(worst, one);
    };
    for (const sha of shas) {
        if (fromCommit) {
            consider(commitAuthors.get(sha), commitSignatures.get(sha), commitSignerFingerprints.get(sha));
        }
        if (!fromNotes)
            continue;
        const writers = noteAuthors.get(sha);
        if (writers === undefined || writers.length === 0)
            consider(undefined, undefined, undefined);
        else
            for (const writer of writers) {
                consider(writer.author, writer.signatureStatus, writer.signerFingerprint);
            }
    }
    return worst ?? gradeRecord(record, ctx);
};
//# sourceMappingURL=grade.js.map