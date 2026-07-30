// Shared phrase-boost "compile" pipeline.
//
// Turns a boost-phrase .txt blob into the serialized artifact (token-id
// encoding) that the browser reuses to build the BoostingTrie WITHOUT re-running
// the per-phrase BPE encode (the only expensive part for a 10k-100k clinical
// list). This is the single source of truth for both:
//   - the container-boot prebuild (docker/prebuild-boost.mjs), and
//   - the operator-run compiler (scripts/compile-boost.mjs, which writes .pwc),
// so the on-disk format, the vocab-signature pinning and the augment-default can
// never drift between them. Reuses the exact browser code paths (parseVocabText
// + BpeEncoder + parseBoostPhrases + expandAugmentations + encodePhrases), so
// the ids it emits are byte-for-byte what the UI would have produced.
//
// The artifact (the .pwc the operator ships, and the .json the container serves
// and the browser fetches) is:
//   { version, vocabSig, augmentDefault, encoded, skipped }
// The .pwc is written gzip-compressed (writePwc/readPwc) since it is only read
// back by Node (the boot prebuild + scripts/transcribe.mjs), never fetched by a
// browser; the served .json stays plain JSON (the browser parses it directly,
// and Caddy gzip/zstd-compresses it on the wire anyway).
// `vocabSig` pins it to the exact tokenizer vocab it was built against; on a
// mismatch the boot reuse check (and the browser) re-encode from the .txt, so a
// stale artifact is never wrong, only ignored. `version` lets a future format
// change reject an old artifact rather than misread it.
//
// Node-only: imports node:fs to read the vocab + merges. MUST NOT be imported
// from the browser bundle (App.jsx). Built with Claude Code.

import { readFileSync, writeFileSync } from 'node:fs';
import { gzipSync, gunzipSync } from 'node:zlib';
import { parseVocabText } from './tokenizer.js';
import { BpeEncoder, buildVocabToId, vocabSignature } from './bpeEncoder.js';
import { compileBoostList, formatBoostConflict } from './phraseBoost.js';

/**
 * Thrown by {@link compileBoostText} when the list contains actively
 * incompatible duplicate phrases (see {@link findBoostConflicts}). The compile
 * step is admin-facing and bakes a shipped artifact, so an inconsistency must
 * fail loudly rather than silently resolve to whichever entry happened to win;
 * the web UI, by contrast, only warns. Carries the raw `conflicts` for callers
 * that want to format them differently.
 */
export class BoostConflictError extends Error {
  constructor(conflicts) {
    const lines = conflicts.map((c) => '  - ' + formatBoostConflict(c));
    super(
      `Inconsistent boost list: ${conflicts.length} phrase(s) given conflicting boosts.\n`
      + `${lines.join('\n')}\n`
      + 'Fix the .txt so each phrase has a single weight/min-p, then recompile.',
    );
    this.name = 'BoostConflictError';
    this.conflicts = conflicts;
  }
}

/**
 * Augmentation-default baked into the compiled artifact: the value of the
 * browser's global "Augment" toggle the list was compiled at (OFF / no
 * augmentation by default). Compiling at the same default lets the browser reuse
 * these ids without a re-encode; it falls back to encoding the .txt itself when
 * the user has flipped the toggle ON (augmentDefault mismatch). Per-phrase `:AUG`
 * flags and a list's own `*` defaults line are baked in regardless (they live in
 * the .txt), exactly as in the UI.
 */
export const AUGMENT_DEFAULT = '';

/**
 * On-disk artifact format version. Bump when the shape of `encoded` (or any
 * other field a consumer relies on) changes incompatibly, so an old .pwc / .json
 * is rejected by {@link isReusableArtifact} and re-encoded instead of misread.
 * v2: per-phrase flags switched from casing (`:s`/`:i`) to augmentation
 * (`:f`/`:a`/`:p`), changing the expanded surface forms an `:i` phrase yields.
 * v3: added the `h` (strip-symbols) flag and folded it into the full set, so
 * `:i` now also yields symbol-stripped variants (`fap` -> `faph`).
 * v4: a `*:WEIGHT:TOPK:AUG` line is now a list-level defaults directive (it was
 * parsed as a boost phrase before), and the `#!strength`/`#!augment` directives
 * were removed; a list with a `*` line expands differently than under v3.
 * v5: the per-phrase gate switched from an integer top-k rank to a min-p ratio,
 * so `encoded[].topk` (an integer >= 1) became `encoded[].minp` (a number in
 * (0, 1]); an old v4 artifact's topk would be misread as an out-of-range minp.
 */
export const BOOST_ARTIFACT_VERSION = 5;

/**
 * Build the BPE encoder and its vocab signature from a model's vocab.txt plus
 * the bundled bpe-merges.json. The signature pins any artifact compiled with
 * this encoder to this exact vocab.
 * @param {string} vocabPath Path to the model's vocab.txt.
 * @param {string} mergesPath Path to bpe-merges.json.
 * @returns {{ encoder: BpeEncoder, vocabSig: string, tokenCount: number }}
 */
export function loadBoostEncoder(vocabPath, mergesPath) {
  const id2token = parseVocabText(readFileSync(vocabPath, 'utf-8'));
  if (!id2token.length) throw new Error(`vocab at ${vocabPath} parsed to 0 tokens.`);
  const asset = JSON.parse(readFileSync(mergesPath, 'utf-8'));
  const encoder = new BpeEncoder(asset, buildVocabToId(id2token));
  return { encoder, vocabSig: vocabSignature(id2token), tokenCount: id2token.length };
}

/**
 * Compile a boost-phrase .txt blob into the serialized artifact. Runs the exact
 * browser parse -> augment-expand -> encode pipeline, so the token ids match
 * what the UI would produce for the same list and tokenizer. The list's own
 * `#!prefixes` directive (if any) drives the `p` augmentation, and its `*`
 * defaults line(s) set per-phrase weight / min-p / augmentation, just like the
 * UI. Only the global "Augment" toggle is an external input (`opts.augmentDefault`).
 * @param {string} raw The .txt contents.
 * @param {BpeEncoder} encoder Built by {@link loadBoostEncoder}.
 * @param {string} vocabSig The encoder's vocab signature (recorded in the artifact).
 * @param {Object} [opts]
 * @param {string} [opts.augmentDefault=AUGMENT_DEFAULT] The global "Augment" toggle value the expansion is baked at (a phrase's `:AUG` field or a `*` defaults line overrides it).
 * @param {(done:number, total:number)=>void} [opts.onProgress] Called once per phrase as it is encoded (the slow step); used by the offline compile script to draw a progress bar.
 * @returns {{ artifact: {version:number, vocabSig:string, augmentDefault:string, encoded:Array, skipped:string[]}, parsedCount:number, expandedCount:number, warnings:Array<{phrase:string, warning:string}> }}
 *   `warnings` are the per-phrase weight/min-p coercions `parseBoostPhrases`
 *   recorded (an out-of-range weight or invalid min-p that was silently reset to
 *   a default). They are non-fatal (the artifact is still valid), but the
 *   admin-facing compile script surfaces them so a clean compile no longer hides
 *   what the web UI would warn about. Conflicts (the other UI warning) are fatal
 *   here and throw above; `skipped` (the third) lives on the artifact.
 */
export function compileBoostText(raw, encoder, vocabSig, opts = {}) {
  const augmentDefault = opts.augmentDefault ?? AUGMENT_DEFAULT;
  // The parse -> expand -> encode chain is shared with the browser (the boost
  // worker runs the exact same function), which is what guarantees the ids here
  // are the ones the UI would have produced. `warnings` come back computed on
  // the pre-expansion phrases, so each typed phrase is reported once rather than
  // once per augmented surface form; conflicts are fatal here (the artifact is
  // shipped) and only warned about in the UI, hence the throwing hook.
  const { phraseCount, warnings, expandedCount, encoded, skipped } = compileBoostList(raw, encoder, {
    augmentDefault,
    onProgress: opts.onProgress,
    onConflicts: (conflicts) => { throw new BoostConflictError(conflicts); },
  });
  return {
    artifact: { version: BOOST_ARTIFACT_VERSION, vocabSig, augmentDefault, encoded, skipped },
    parsedCount: phraseCount,
    expandedCount,
    warnings,
  };
}

/**
 * Serialize a compiled artifact to a .pwc file as gzip-compressed JSON. The
 * .pwc is the operator-shipped cache (scripts/compile-boost.mjs output); the
 * browser never fetches it (the container re-serializes a plain .json from it
 * at boot), so compressing it only shrinks the stored/shipped artifact and can
 * never affect what the UI parses. Token-id arrays compress well, so a clinical
 * list's .pwc drops several-fold.
 * @param {string} path Output path (conventionally .pwc).
 * @param {any} artifact The artifact object from {@link compileBoostText}.
 */
export function writePwc(path, artifact) {
  writeFileSync(path, gzipSync(Buffer.from(JSON.stringify(artifact), 'utf-8')));
}

/**
 * Read and parse a .pwc artifact written by {@link writePwc}. The on-disk form
 * is gzip-compressed JSON, detected by the gzip magic bytes (0x1f 0x8b) rather
 * than the extension, so a plain-JSON .pwc compiled before compression was
 * added is still accepted unchanged.
 * @param {string} path Path to the .pwc file.
 * @returns {any} The parsed artifact object.
 */
export function readPwc(path) {
  const buf = readFileSync(path);
  const text = (buf.length >= 2 && buf[0] === 0x1f && buf[1] === 0x8b)
    ? gunzipSync(buf).toString('utf-8')
    : buf.toString('utf-8');
  return JSON.parse(text);
}

/**
 * Whether a parsed artifact's token ids are valid for the given vocab: the
 * format version is current, the vocab signature matches, and `encoded` is an
 * array. This is the minimum needed before trusting the pre-encoded ids (a
 * mismatch means the ids index a different vocab and would be meaningless).
 * Augmentation is NOT considered here, since a consumer that reuses the ids
 * as-is (e.g. scripts/transcribe.mjs) accepts whatever augmentation expansion
 * the artifact was baked at; the browser-toggle reuse adds that check via
 * {@link isReusableArtifact}.
 * @param {any} artifact Parsed .pwc / .json object.
 * @param {string} vocabSig Signature of the currently loaded vocab.
 * @returns {boolean}
 */
export function artifactMatchesVocab(artifact, vocabSig) {
  return !!artifact
    && artifact.version === BOOST_ARTIFACT_VERSION
    && artifact.vocabSig === vocabSig
    && Array.isArray(artifact.encoded);
}

/**
 * Whether a parsed artifact can be reused as-is for the given vocab +
 * augmentation default, letting the boot prebuild skip the encode. Builds on
 * {@link artifactMatchesVocab} and additionally requires the augmentation
 * default to match, since the browser only reuses the ids when its global
 * "Augment" toggle still agrees with how the artifact was expanded.
 * @param {any} artifact Parsed .pwc / .json object.
 * @param {string} vocabSig Signature of the currently loaded vocab.
 * @param {string} [augmentDefault=AUGMENT_DEFAULT]
 * @returns {boolean}
 */
export function isReusableArtifact(artifact, vocabSig, augmentDefault = AUGMENT_DEFAULT) {
  return artifactMatchesVocab(artifact, vocabSig)
    && (artifact.augmentDefault ?? '') === augmentDefault;
}
