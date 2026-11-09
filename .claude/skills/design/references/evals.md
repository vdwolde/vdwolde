# evals — the maintainer's walk-through (not read at runtime)

After any edit to this skill, walk each request below on paper against SKILL.md and the playbooks. Every
row must still route as written and every "must hold" must still be written down somewhere. `/design`
itself is never run to test this (root `CLAUDE.md` hard rule 11); the helper is tested with
`node tools/design-tools.mjs --self-test`.

| # | Request (project) | Route | Must hold |
|---|---|---|---|
| 1 | "make the accent teal" (any web app) | improve, no picker | `retint` + `ramp` + `contrast` on every pair the accent touches; fingerprint unchanged; old → new list; changelog line |
| 2 | "make it better" (any) | one `AskUserQuestion` with the four modes | no mode is guessed; nothing is edited before the answer |
| 3 | "add a settings page" (Song Snitch) | create, Extend | phases 3, 4, 10 skipped; no existing token or component changed; first screen built and looked at before the rest |
| 4 | "add dark mode" (a light-only app) | create, Extend the system | new token set under the same names; derived not inverted; every pair checked with `contrast`; existing tokens untouched |
| 5 | "make it look like linear.app" (any) | create, Phase 1b | tokens read as data; no markup, copy, image or logo copied; the reference feeds one direction only |
| 6 | "I hate this look" (Computer Cleaner) | overhaul (may ask once if read as vague) | WPF branch asks for a screenshot and never launches; baseline numbers; matrix printed first; three options, each with both costs; nothing changed until chosen |
| 7 | "tidy up the screens I changed" (any) | polish, scope = the diff | `inventory` on the changed files only; no route, screen or feature added; every unfixed finding in `PRODUCT.md` |
| 8 | "review my UI" (any web app) | polish, audit | nothing edited; ranked findings list `path:line — claim — severity — fix`; gates reported in four states |
| 9 | "use a serif for the headings" (improve in progress) | lock crossed | three answers offered: overhaul, stay inside, amend one line; an amendment writes the changelog line |
| 10 | "quieter" where distill would drop the only Export button | improve | the button stays (it is the only path to the function); every removal listed; no file deleted unasked |
| 11 | "show me the directions visually" (during create) | overhaul at `preview` depth | one board per direction; canvas not screenshotted; create resumes after the choice |
| 12 | "polish it" (a WPF app) | polish | static desktop pass runs; measured performance is `unavailable`, never estimated; the app is never launched |
| 13 | `/design polish` on a whole app, a usage limit hits during Phase 3 | polish, cut off | phases 1 and 2 are `done` with notes; the Design Read, fingerprint and discover result are saved; the report says what is done and how to resume; no retry loop |
| 14 | the same request in the next usage window, or `/design resume` | polish, resumed | one line "Resumed: phases 1, 2 done; continuing at 3"; discover is not re-run (`load read`); a phase left `doing` is checked with `git diff` before it is redone; `inventory` shows what is left |
| 15 | `/design overhaul`, a limit hits while two of three option agents are writing boards | overhaul, cut off | the matrix, content brief and work folder are saved; every board written before the cut is kept; no canvas is published with boards missing; the resume spawns agents only for the missing boards, named in their briefs |
| 16 | "build the settings screen in Liquid Glass" (a Tailwind v4 + shadcn app in the Website Builder repo) | create, house style | discover § 2 loads `references/styles/liquid-glass/SPEC.md`; the layer at `playbook/styles/liquid-glass/layer/` is used, not `anywhere.md`; DESIGN.md Style line reads `Liquid Glass (house style, references/styles/liquid-glass/)`; Phase 3 skipped and stated; catalog `liquid-glass` (Apple) is not used; Design Read says "leaning toward Liquid Glass, house style" |
| 17 | "make this tray app Liquid Glass" (a WPF/WinForms tray utility) | overhaul-class apply, house style | asks once to confirm scope; loads SPEC and the WPF section of `anywhere.md` (`wpf.csv` outranks web advice, no backdrop-filter assumed); three-directions step skipped; the app is never launched; frost and blur claims marked unverified where `anywhere.md` says so |
| 18 | "make it glassy" (any app) | vague, not a house style name | the house style is **not** chosen: one `AskUserQuestion` (or the normal create/improve catalog path via `glassmorphism`); only the name or an alias (`liquid-glass-gel` row) triggers the spec |
| 19 | "add a settings screen" in a project under the Development Base (no style named) | create, default house style | discover § 2 loads `references/styles/vdwolde/SPEC.md` and the stack section of `anywhere.md` without being asked; DESIGN.md Style line reads `vdWolde Brand Guide v1.1 (house style, references/styles/vdwolde/)`; Phase 3 skipped and stated; both modes built; `contrast-check.mjs` run; Liquid Glass not used |
| 21 | "audit the design of this app" (a React dashboard with a confirm dialog before every delete and a create button that stays enabled while it runs) | polish, audit | Phase 4 walks `ux-details.md`: reports the confirm-before-reversible-delete (5) and the double-submit (19) as High findings in `path:line — claim — severity — fix`; edits nothing; skips 18 (brand owns corners) and 12 (not Android) with a reason |
| 22 | "add a payments overview page" (a money dashboard) | create, Extend | the `ux-details.md` plan applies: no optimistic update and no stale-while-revalidate on balances or payments (2, 6 skipped with the reason); idempotency key + disabled button on the create request (19); skeleton shown only after ~300 ms (1) |
| 20 | "restyle the client site in `builds/`" | out of scope for the default style | vdwolde is **not** applied (client sites keep their own design); the Design Read says so |
| 23 | "audit this page's spacing" (a web app with a dev server running) | polish, audit | Phase 4 runs `tools/ui-audit.js` at 390, 768 and 1280 and in dark mode; every candidate is checked against a screenshot before it is reported; findings in `selector or path:line — claim — severity — fix`, largest visible fault first; edits nothing; no review subagent (audit); `Not checked:` line present |
| 24 | "this card list looks off" (a card with 4 px of top padding against 24 px at the sides, and rows 60 px apart) | polish | `uneven-padding` and `loose-list` found by the audit and confirmed on the screenshot; fixed once in the shared card/list component, not in each caller; the fix is a spacing token, not a literal |
| 25 | "the dropdown jumps when it opens" | polish (motion) | `motion-probe.js` installed, the menu opened, `report()` shows `anchorDrift` or `jumps`; the fix pins the opening edge and reserves the height; reduced motion keeps a complete result; the motion tier is unchanged |
| 26 | the audit runs on a canvas-only or iframe-only page | polish or create verify | `scanned` near zero or `inconclusive: true`: the gate is `unavailable` with the reason, never `pass`; iframes and shadow roots are named as not entered |
| 27 | "polish the whole app" (React, dev server running) | polish, whole app | after the audit's fixes, one `review.md` subagent gets screenshots plus the Design Read and DESIGN.md only (no plan, no audit report) and returns a ranked `image — claim — fix` list; a diff-scope polish skips the review and says so; it is a subagent of the pass, not `/code` (hard rule 11 holds) |
| 28 | "add dark mode" then the audit finds a stageshow-style shadow rule | create, Extend the system | vdWolde has no drop shadows: depth on the new dark token set comes from surface lightness; no shadow token is added from any reference |

Also check: `craft-checks.md`, `motion-checks.md` and `review.md` exist, and each is named by the step that reads them (SKILL.md Step 5, polish Phases 4/5/6/7, create Phases 2/7/11, verify § 2 steps 10-11) with every link resolving; `tools/ui-audit.js` against `tools/fixtures/ui-audit-bad.html` at 1280 wide reports every key in the fixture's header comment, and against `ui-audit-good.html` reports none at 1280 and at `390x844x3,mobile,touch`; `tools/motion-probe.js` against `tools/fixtures/motion-bad.html` reports what that file's header lists; no playbook gained a phase number (checkpoint ids unchanged); no rule in the new files contradicts the vdWolde spec (no drop shadows, brand motion tokens, Title Case names, 32 px targets); `ux-details.md` lists all twenty and every link to it resolves (polish, create, verify, SKILL.md); SKILL.md links resolve; every playbook says which shared file it reads; no playbook cites
`app-interface.csv` as a layout source; the performance step uses `performance_start_trace`, not
`lighthouse_audit`; the helper's `--self-test` passes; `node ~/.claude/tools/checkpoint.mjs --self-test` passes; every playbook that fans out to subagents says to write one board or screen at a time and to `done` it from the files on disk.

## Provenance

Verb vocabulary from `impeccable` v4.1.1; taste layer from `design-taste-frontend`; catalog from
`ui-ux-pro-max` v2.13.0 (`catalog-summary.json` verified 2026-08-13). Consolidated 2026-08-16; rebuilt as
four modes on 2026-10-05, then given shared discover / verify references and the helper the same day. `ux-details.md` added
2026-11-07 (twenty interaction details for audit and build; catalog row 35 now prefers Undo to a confirm on reversible actions).
`craft-checks.md`, `motion-checks.md`, `review.md`, `tools/ui-audit.js` and `tools/motion-probe.js` added 2026-11-08, adapted from the
craft rules, detector checks, motion rules and review protocol of `benjitaylor/skills` › `stageshow` v1.1.1 (MIT, © 2026 Benji Taylor):
the checks are re-implemented for real UI, its faux-illustration rules (crop, bleed, placeholder bars, cursor, shadows) are left out.
