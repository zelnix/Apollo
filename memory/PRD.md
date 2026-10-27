## Evidence received: email finished (Check Results), then websites and links (2026-10-27)
**Owner's choices:** go ahead with the Check Results work; then "Start websites and links right away". No testing agent.
- **Email Check Results (`app/email.tsx`):** the result shows the Evidence received card (`check-result-evidence-profile` /
  `investigation-check-evidence-profile`) with "Add the original email (.eml)" below L3 → `checkEmail({via: "eml_file",
  original, upgradeEventId})`, a "Checking the original email" modal, and a notice on the card (`…-notice`): the upgrade
  sentence, or "That original doesn't match the email you checked…". New input card "Open the original email (.eml)"
  (`email-open-original`); pasted original source ("Show original") is detected (`looksLikeRawEmail`) and read as
  `raw_source` (L3); inbox picks are `connected_mailbox`, shares `shared`, preview samples `simulated`. A shared .eml file
  now routes to /email (`isOriginalEmailFile` in classifyShare) and is read on the phone. Upgrades don't count as a new check.
- **Bug fixed:** an L1 pasted email could never be upgraded — its From/Subject lived inside the text, so `sameEmail` saw no
  subject/sender. ApolloContext now reads the earlier capture with `parseEmail` before comparing.
- **Backend (was missing):** `MessageAnalyseIn.email_evidence` (strict `services/email_evidence.EmailEvidenceFindings`, extra
  fields → 422) adds a plain summary to the investigation's initial findings; new `POST /investigations/{id}/evidence-profile`
  `{findings}` attaches better evidence to a running email case (idempotent per level+fingerprint; 404/410 for gone cases —
  the phone then says "This case's investigation had already finished, so the new evidence is kept with the case on this phone").
- **Links and websites (`src/domain/triage/linkEvidence.ts`):** levels Link as given (no lookup answered) · Link checked
  (destination not followed) · Destination followed · Connection seen by Site Gate (Site Gate biting / desktop flow drops).
  Capabilities: original URL, redirect chain, final destination, domain registration (recorded by the registry), reputation
  ("Listed as … by N of M lists" / "No match on N lists that answered"), TLS + hosting (not inspected). Signals: on-device URL
  structure signals (plain words from risk.ts), redirect to another site, newly registered, destination not followed.
  `checkLink(input, scent, {via, upgradeEventId})`: case re-check (`RecheckCase`) re-triages the SAME link in place (history,
  triage_history, first detection time kept); a weaker re-check never replaces a stronger result (`recheckWeaker`). Shown on
  the link Check Result (`linkCheckResultAdapter.evidenceProfile`) and the Threat case (CaseEvidenceProfile, now generic).
  QR scans `via: "qr"`; links from email/messages `via: "message"`. `PatrolEvent.evidence_profile` is now `EvidenceProfile`.
- Catalogue: link words (levels, via, notes, upgrade/recheck/recheckWeaker, signals); `catalogue.ts` regenerated with
  `/tmp/regen_catalogue.mjs` (JSON.stringify of the backend file). Rule book: Email Gate "Email evidence levels", Site Gate
  "Evidence received", Link Gate "Link evidence levels", privacy (originals never leave the phone), Your data (.eml); WATCHED +
  evidence files; re-stamped. Also fixed a committed tsc error (`urlIntel.ts` missing `quota_exhausted` message).
- Tests: frontend 1051/1051 (`emailEvidence` +1, `share` +1, new `linkEvidence` 7); backend `tests/test_email_evidence.py` (5),
  full suite 1310 passed. Preview verified by screenshots: L1→L3 upgrade, direct .eml (L3 + recorded auth), pasted source,
  mismatch, link check "Link checked" with signals.
- **Next (not started):** messages, calls, files, images, QR, apps — catalogue words for these types already exist.


## Triage Limited check by cause (2026-10-26, report only — nothing changed)
- Full report: `/app/memory/triage_limited_report.md` (simulation script /tmp/sim_limited.ts, real engine + real
  /intel/check answers for the 120-link benchmark corpus).
- Healthy providers → 0/60 clean links Limited; any failed reputation lookup → 60/60 clean links Limited. Benign texts
  with "call me on <number>" go Limited when the number lookup fails (CB-03 gap that can't change the outcome). Number
  "review" always Limited by design. No real-phone telemetry in preview; production needs the owner's admin login.
- Measurement gap: number checks with "allow" never report telemetry. Risk: `/call/risk-check` skips the cache, so
  IPQS credits (89/1,020 used) drain per call. Recommended: no threshold change; four fixes listed in the report.


## Case Briefing UI check (Stoko + other cases) and fixes found while checking (2026-10-26)
- Checked in the web preview with three real briefings from `explain.explain_case` (injected as device-committed
  investigations): Stoko email (No scam indicators, no "Needs you"), a lookalike link (Concerning, "Needs you" with
  its reason), an Unable-to-determine text (Keeping watch, no "Needs you"). Home, Threats, Overview and Alerts all show
  the briefing's subjects, findings and the "Still unresolved" reason.
- Fixed: Overview/Ask Higgins dropped the plain English "What it is" subject line (`plainReport` now shows it); Threats
  card titles for investigated cases were generic ("Higgins found no remaining concern") → briefing headline/summary
  (`caseCardText` in `patrolOutcomes`); Home hero wrapped full briefing sentences in "Apollo flagged … There's also a
  concern about …" (double periods, broken capitals) → `briefedLine()` (headline: first finding, "It needs your
  decision." only when `needsYou`).
- Fixed: a lookalike's subject line said "the Stoko website st0ko-login.co". Findings now carry `organisationClaimed`
  (impersonation check or "not X's"); subject line "What it is: the website st0ko-login.co, which isn't Stoko's.",
  headline "Link using Stoko's name checked" (`words.SUBJECT_LINE_CLAIMED`, `HEADLINE_CLAIMED_ORG`;
  `BriefingSubject/BriefingFinding.organisation_claimed`).
- Rule book: the 8 new Fidelity Check codes (SUBJECT_DROPPED … CAUSAL_DROPPED) were missing from `{#fidelity-check}`
  (test_rulebook failed) → added, re-stamped.
- Tests: `frontend/tests/caseBriefingSurfaces.test.ts` (3), tabBadges updated to the strict "Needs you" rule,
  plainEnglish +1; backend test_case_briefing updated (lookalike). Frontend all pass, backend 1250 passed.
  No testing agent (owner's rule).


## Rule book: Plain-English Renderer + Fidelity Check sections (2026-10-26)
- New `###` sections under Investigation process: `{#plain-english-renderer}` (facts → draft order, identifiers kept,
  contradiction words, severity lines, basis/confidence labels, what may change, ALL 52 plain swaps, ALL 19 jargon
  explanations) and `{#fidelity-check}` (all 25 failure codes word for word, the "same point" test 85%/25%/negations/
  numbers/quotes, the 4 tone-word lists, attempts/modes plain·repaired·literal with PASS/FAIL, RENDERER_ERROR, staff view).
  The old `####` summary in higgins-explanation is now a pointer. Fixed "From what you told ApolloSG" → code's wording.
- Tests (`test_rulebook.py`): new word-for-word tests for both sections (every swap/glossary/code/tone list/threshold/
  MAX_ATTEMPTS), placement list updated. 25/25 rule-book tests pass; frontend rule-book tests 12/12.


## Notification text: entities decoded once, short specific summaries (2026-10-26)
- Frontend `src/push/notificationText.ts`: `decodeHtmlEntities` (one pass; named + numeric; unknown/invalid left
  as-is; `&amp;quot;` → `&quot;`), `presentAlertText` (decode once + tidy + clip title 65 / body 178) applied ONLY in
  `scheduleLocalAlert` (the OS boundary) and for the held-alert log row; `notificationSummary` / `completedSummary`
  build the short body ("Higgins: The Instagram link you sent has signs that need checking. Open ApolloSG to see what
  I found."; barking/biting/Limited variants, Limited never "safe"). `eventLocalAlert` + `completedCheckAlert` use them
  instead of `event.headline`.
- Backend `services/notification_text.py`: `present_push` (html.unescape once + tidy + clip) applied at the top of
  `send_push` — every push; `owner_alert_summary` replaces "Higgins: {headline}" + the what_to_do subtext in
  `push_owner_alert`. Events, investigations and evidence are never modified.
- Tests: `frontend/tests/notificationText.test.ts` (5), `backend/tests/test_notification_text.py` (11). Frontend
  1013/1013; backend 1275 passed (1 live-API test flaky under full-suite load, passes alone). Rule book Alerts
  section updated + stamped.


## Failed lookups, phone-only rules, one Threat Case per input, Limited by cause (2026-10-26)
- **Reputation lookups** (`src/domain/reputationLookup.ts`): controlled retry per the catalogue policy (3 attempts,
  800 ms doubling backoff, 45 s budget; number lookups 30 s), in-flight dedup per (check, key). Transient = timeout,
  offline, 5xx, 429, malformed, coverage "none" (provider_unavailable). Never retried: 401/403/4xx, not_configured.
  All attempts failing → reputation `unavailable` with `failure` (gap evidence "reputation lookup did not complete
  (timeout)"), RetryRecord on the Triage record (DI shows it). Coverage "none" is now unavailable, never a pass.
  Used by checkLink (`lookupUrlIntel`, 30 s/attempt via new `apiPost(..., {timeoutMs})`), message/email links
  (`fetchMessageUrlIntel`, dedupes repeated URLs; malformed answers no longer dropped), numbers (`lookupNumberRisk`;
  server already retries IPQS so "unknown" answers are final).
- **BITM-01..04**: NOT APPLICABLE with reason `BROWSER_OBSERVATION_NA` when browser/WebSocket observation is absent
  (both engines). Catalogue v2: those rules carry `notApplicableWithout: "browser_observation"` instead of a gapCode.
  DI lists every not-applicable rule with its reason.
- **One input → one Threat Case**: root cause was `patrol_records._issue_key` anchoring on investigation_case_id — an
  event filed before its case was bound got a second logical issue (two cards). `_stable_issue_key` pins the key the
  source event was first filed under (and joins an existing case's key, same category); `current()`/`timeline()`
  merge legacy split keys by source event (`_canonical_issue_keys`). Verified in preview: one check → 1 key, 1 card.
- **Limited by cause**: device posts `POST /api/triage/telemetry` (egress `triage_telemetry`: codes only) after every
  device Triage; server Triage (`store.record_triage_history`, first save only) records too. Collection
  `triage_outcome_telemetry` (platform/adapter_mode from the device doc). Admin → Triage "Limited by cause": outcome
  totals, Limited by cause × source type, lookup retry outcomes; real phones only by default (`?scope=all`, `?days=7`).
  Causes: reputation_{timeout,offline,server_error,rate_limited,malformed,provider_unavailable,auth_failure,forbidden,
  rejected,not_configured,no_data,unavailable}, insufficient_evidence, number_risk_moderate, rule_execution_error, gap_<code>.
- Tests: frontend `tests/reputationLookup.test.ts` (10), triage BITM test updated — 1008/1008; backend
  `tests/test_case_identity_and_limited_causes.py` (5), contract test updated — 1265 passed. Rule book updated + stamped.


## DI tab decision trace; Limited wording; Triage Limited investigation (report only) (2026-10-26)
- **DI tab** (`src/components/DiReport.tsx`, both Threat Case and Investigation Report): "Decision path" card
  (Deterministic triage → TC FlyBy → Magnum DI → Higgins, pure builder `src/domain/diTrace.ts`, each step from
  recorded data only) + three sections closed by default: "Apollo deterministic rules" (every rule with result/evidence,
  coverage gaps with codes, retries, TC FlyBy checks/pattern/searches), "Sent to Magnum DI" (why it was escalated +
  request), "Response from Magnum DI" (response, processing). DI keeps internal codes; never provider/model.
  `DiReport` takes `triage` (event's record) so Triage-only cases show the trace with no case.
- **Backend:** `GET /investigations/{id}/di` adds `trace` (`di_record.decision_trace`: triage record by
  investigation_case_id, routing.teddy without searchModel/tokens, routing.magnum as webSearch/itemsSent, settled reason,
  fidelity). `wire()` no longer sends `modelRequested`; tool/route `google_search` → `web_search`; simulated notice
  "SIMULATED — the preview simulator answered; Magnum DI was not engaged". PDF simulated note reworded.
- **Wording:** "No AI calls" → "Magnum DI was not engaged" / "Escalated to Magnum DI" / "TC FlyBy settled it — Magnum DI
  was not engaged" (caseSources); copy texts name Magnum DI only ("Magnum DI calls").
- **Limited language:** `LIMITED_CAUTION` (owner's choice "Treat this with caution") in contract.ts + catalogue.py;
  TriageSummary, Overview (meaning, "Not determined" risk, `LIMITED_TODO` instead of "Nothing to do"), server briefing
  (record_classification) and triage store `what_to_do`. Coverage-gap codes → plain English (`plainTriageText` /
  `plain_codes`) in Overview, Home, Higgins briefing, Evidence sources; both engines' Limited reason now plain English.
  Overview no longer shows rule IDs.
- Tests: frontend `tests/diTrace.test.ts` (7) + caseSources updated (998/998); backend `tests/test_di_trace.py` (5),
  full suite 1260 passed. Rule book Limited row updated + re-stamped. No testing agent (owner's rule).
- **Triage Limited investigation (no thresholds changed):** preview server Triage has 0 Limited (251: 153 possible,
  98 no threat). Phone-side simulation: with reputation answering, 1/23 links Limited; when `/intel/check` fails, every
  non-threat link is Limited (LINK-01, LINK-10, BITM-05 all gap on one failure). Number checks "review"/"unknown" are
  always Limited by design. Preview logs: `/intel/check` 131/1708 = 422; `/call/risk-check` 128/261 = 401 (mixed with
  test traffic). BITM-01..04 can never run on a phone (browser visibility off). Production data not readable from here.
- Found, not fixed: one link check filed two Threat cards in the web preview ("two children with the same key").

## Australian carriers' scam blocking row (2026-10-26)
- Owner's choice: "Show all three, no picking" (carriers block inside their networks; no app/carrier read).
- New catalogue row `au_carrier_scam_blocking` (src/domain/deviceSecurityCatalogue.ts): Android + iOS, only when
  `DeviceFacts.country` (region setting via `regionCountry`, set in `deviceCapabilityState.deviceFacts()`) is AU;
  `optional` (never "Needs checking"), state not_verifiable, no settings action (`action` now optional on
  SecurityDef/ProtectionGuidance). Steps: Telstra Scam Protect labels (incl. Boost/Belong), Optus Call Stop
  warning, Vodafone background blocking, report at scamwatch.gov.au. Reviewed explanation in DEVICE_SEEDS.
- Facts checked against telstra.com.au (Scam Protect, Mar 2025) and optus.com.au (Call Stop).
- Test: frontend `tests/auCarrierProtection.test.ts` (4).

## Gemini Map 4-week trend; pre-written explanations for the phone's own call/message protection (2026-10-26)
- **Last four weeks** table on `/api/admin/gemini-map`: Magnum DI, TC FlyBy, Ask Higgins, removed/retired, all calls;
  cost + calls per Monday–Sunday week (admin's zone), oldest first; finished weeks show ▲/▼ % vs the week before
  (red up, green down, "new" from zero); this week has no comparison. `gemini_usage_by_feature(start, end)`.
- **Explanations:** every catalogue protection (39) already had one; the gap was provider rows `call:<pkg>` /
  `message:<pkg>`. Added `PROVIDER_SEEDS` (iOS Phone, iOS Messages, Google Phone, Samsung Phone, Samsung Smart Call,
  Hiya, T-Mobile Scam Shield, AT&T ActiveArmor, Verizon Call Filter, Google Messages, Samsung Messages) and
  `PROVIDER_KIND_SEEDS` (true of any call / message protection app) in services/protection_knowledge.py; the
  `GET /protections/device/{id}` lookup uses them. Tests check every catalogue id and every Android
  NATIVE_PROTECTION package has reviewed text.

## Gemini Map admin page; page readers and protection explanations removed (2026-10-26)
- **Gemini Map** (`/api/admin/gemini-map`, nav item): the 3 features that call Gemini (Magnum DI, TC FlyBy web search,
  Ask Higgins) with code location, model, when it calls, and this week's calls / failed / searches / est. cost / last
  call. Week = Monday 00:00 in the admin's zone (`?tz=` added by a one-line script). `gemini_usage_by_feature()` buckets
  records by purpose + correlation id prefix (case-/chat-/protection-/page-crawl/msg-check); anything else shows
  under "Other calls this week" so totals reconcile. Tests: `tests/test_admin_gemini_map.py`.
- **Removed:** `/api/page/extract` + `/api/page/crawl` (routers/analysis.py), `Purpose.PAGE_SIGNAL_EXTRACTION`,
  egress `page_extract`/`page_crawl`; Device Protection AI explanations (`POST /protections/device/explanation`,
  scope/caching/Gemini in services/protection_explanations.py, preview-simulator branch, egress
  `protection_explanation`, `explanationScope` on catalogue rows). Device protections now show only the reviewed
  explanation (`GET /protections/device/{id}`); no explanation → "ApolloSG doesn't have an explanation of this
  protection yet." Old phone-cached Higgins copies are ignored. Apollo Protection explanations unchanged.
- Remaining Gemini callers: coordinator.run_turn (Magnum DI), teddy/search.run (TC FlyBy), chat.reply (Ask Higgins).

## Family sharing: code-only pairing; Threats → Family alerts link (2026-10-26)
- **Email invitations removed end to end:** `/family/guardians` (POST/GET/DELETE) and `/family/confirm/{token}` are
  gone (core/auth.py has no public prefix any more); `notify_guardians` only fans out to paired devices (in-app + push),
  no email. Legacy `guardians` docs are still purged by Delete My Data. Admin stats no longer count guardians.
- **Pairing code** (`POST /family/pair`, body `{device_id, owner_name}`; an old app's `phone` is ignored, never stored):
  `secrets.randbelow` 6 digits, unique among working codes, 15-minute expiry, returns `expires_at` +
  `expires_in_minutes`; a new code retires the device's earlier unused ones. `POST /family/link` takes `^\d{6}$` only;
  5 wrong codes in 15 minutes per device → 429 (`pair_link_misses`, in the family deletion group).
- **Family screen** (`app/family.tsx`): intro line, Email alerts card and optional phone field removed; code shows
  "Works once. Expires in 15 minutes, at h:mm" and disappears at expiry ("That code has expired…"); link field is a
  digits-only number pad. Family members can still save a call-back number from an alert.
- **Threats tab:** "Family alerts" link next to "Patrol history" → `/family?focus=alerts`, which scrolls to
  "Alerts from people you watch" until the person scrolls.
- Docs: privacyInventory family entry, privacy policy (no family email), Play declarations, rule book (Family links).
- Tests: backend `tests/test_family_pair_code.py` (7) + updated test_family/test_family_weekly/test_device_auth;
  frontend `tests/familyPairing.test.ts` (3); frontend 973/973, tsc clean.

## Admin: Devices list, Reset Stats, Family Help Test page; device telemetry (2026-10-25)
**Owner's choices:** checklist + connection status first; country from the phone's region setting; Learn/scam reads
count *different* ones opened; Reset Stats = "everything, delete the old records" = usage and cost data (incl. admin panel).
- **Family Help Test** (`/api/admin/family-help-test`, nav item): `content/family_help_two_phone_test.md` in closed
  sections with tick boxes, a "Server ready / Server not ready" banner (from `services/family_assist/config.load_config`:
  FAMILY_ASSIST_ENABLED + Cloudflare relay keys; preview currently NOT ready — relay keys missing/invalid), and a
  "Recent Family Help sessions" table (phones' make/model/system, scope, state, end reason, sharing time, paused).
  PDF at `/api/admin/reports/family-help-test/pdf` (REPORTS entry).
- **Connection status** (`src/family-help/ConnectionStatus.tsx`) is wired into `app/family/help/active.tsx` and `view.tsx`.
- **Device telemetry:** `src/telemetry/deviceInfo.ts` (expo-device make/model/os/version, region-setting country
  `^[A-Z]{2}$` only, `Application.getInstallationTimeAsync` on native) merged into `deviceMeta()` (now async) for
  `/devices/register` and `/devices/heartbeat`. Backend `DeviceRegister` optional fields + `telemetry()`; heartbeat only
  sets the ones sent (older apps leave them alone). Egress allow-list `device_register` extended; new `device_activity`.
- **Usage counts** on `devices.stats` (`services/device_stats.py`): `tc_flyby`/`magnum_di` bumped on an investigation's
  first answer (`coordinator._commit`, by `answeredBy`), `ask_higgins` on each new chat receipt (`context.add_chat_exchange`),
  `device_checks` + `learn_read`/`scam_alerts_read` (sets of 16-char sha256 digests) via `POST /api/devices/activity`
  (`src/telemetry/activity.ts`, called from recheck, first-check, Learn article, scam alert detail).
- **Devices page** (`/api/admin/device-list`, nav item): totals, filter All/Android/iOS/Web, 50 per page, newest first;
  columns ID, Manufacturer, Model, OS, OS version, Country, Date installed (* = first registration when not reported),
  App version, the six counts, Last seen. (`/api/admin/devices` is the older X-Admin-Key JSON API — different route.)
- **Reset Stats** (on the Devices page, type RESET + confirm → `POST /api/admin/reset-stats`, `services/stats_reset.py`):
  deletes gemini_usage, triage_results, trusted_search_usage, intel_reuse_metrics, investigation_cases past expires_at;
  zeroes higgins_knowledge/reusable_intelligence hits; unsets devices.stats. Keeps devices, family links/sessions, saved
  reports, Higgins history, KB entries, blocklists, admin_audit (the reset is logged there; page shows "Stats last reset").
- Privacy: privacy policy "About your phone" bullet, privacyInventory detail, iOS privacy manifest + ProductInteraction,
  rule book (What may leave the phone; Usage counts) — re-stamped.
- Tests: backend `tests/test_admin_devices.py` (10; the real reset is tested on a throwaway DB), frontend
  `tests/deviceTelemetry.test.ts` (5); frontend 970/970, tsc clean. Testing agent not run (needs owner's approval).

## Family Help — step 6 (Android switched on) + step 10 (iPhone/iPad ReplayKit restored) (2026-10-25)
**Step 6:** `apollo-family-assist` removed from `package.json` `expo.autolinking.android.exclude` (still in the doctor
`reactNativeDirectoryCheck.exclude`, like apollo-security). Stage-gate test replaced by an activation test.
`expo-modules-autolinking resolve --platform android` lists the module; temp-copy `expo prebuild --clean` passes and
`scripts/verify-generated-projects.mjs` passes when run with two unrelated, older mismatches patched (it expects
`versionCode 2` but app.config sets none → 1; it expects `ios/Apollo.xcodeproj`, which the rename made `ApolloSG.xcodeproj`).
Two Android session defects fixed before activation (`FamilyAssistRtcPeer.kt`): relay `expiresAt` now parsed with
`OffsetDateTime.parse` (the server sends Python isoformat "+00:00"; `Instant.parse` rejects that before Android 14, so
every session would have ended at "ready"); `sequence` is now assigned inside `send` under `sendLock` (sends from the
WebRTC thread and the executor could go out of order, and the server drops the socket on any out-of-order sequence).
**Step 10 (iOS, `modules/apollo-family-assist/ios/`):** the earlier Swift could not compile (`extension AnyObject`/`.also`,
optional passed to `command(for:)`, `await` in sync Expo closures) and would have failed at runtime (ISO8601DateFormatter
rejected the server's fractional seconds, so `startCapture` always threw `invalid_input`; NSNull written to UserDefaults
crashes the extension; stop/pause only noticed on the next frame; no stale-session fencing; races on sequence/peer state).
Rewritten to mirror the Android repairs:
- `FamilyAssistState.swift`: `FamilyAssistState` + `FamilyAssistStateStore` (session/generation fenced, terminal states
  only give way to `begin`), `FamilyAssistDates.parse` (drops fractional seconds), `FamilyAssistWire.failureReasons`.
- `FamilyAssistWebRtc.swift`: the one set-up path (RTCInitializeSSL once, RTCAudioSession manual + disabled, factory),
  relay configuration and signaling URL.
- `FamilyAssistViewerPeer.swift`: one serial queue (URLSession delegate queue runs on it), owns factory/peer/socket,
  generation check, chained `add(_:completionHandler:)`, pings every 20s, `onEnded` once, `invalidateAndCancel` on close.
- `FamilyAssistViewerView.swift`: `FamilyAssistRenderer` (RTCVideoRenderer proxy; attach/detach in `didMoveToWindow`;
  pause hides the view on main).
- `ApolloFamilyAssistModule.swift`: `FamilyAssistRuntime` (store + viewer + Darwin observer
  `app.apollo.familyassist.state` → takes in extension state once per revision → events to JS); `startCapture` on main,
  clears old state/command, iOS may replace a session still in `requesting_consent` (picker cancel is never reported);
  `stopCapture` removes the handoff; error codes match Android.
- `Broadcast/SampleHandler.swift`: serial queue; `FrameGate` (lock; closed before teardown; one capturer; 15 fps; keeps
  screen aspect, long side ≤1280; rotation from `RPVideoSampleOrientationKey`; invalid timestamps skipped); commands via
  Darwin notification `app.apollo.familyassist.command` + 1s check, each `issuedAt` applied once; state published without
  nulls + Darwin notification; `finish` order gate → publish → terminate (sharer reasons only) → teardown → end broadcast;
  `broadcastFinished` waits ≤1.5s for the helper message.
- Plugin: Broadcast target now gets MARKETING_VERSION/CURRENT_PROJECT_VERSION (app's), PRODUCT_BUNDLE_IDENTIFIER,
  GENERATE_INFOPLIST_FILE NO, Frameworks phase. Picker name "ApolloSG Family Help". Podspec `swift_version 5.9`.
- Tests: `tests/familyHelpIosRepair.test.ts` (11 source checks); frontend 964/964, tsc clean, security preflight PASS.
  No Apple/Android toolchain here: first Swift/Kotlin compile happens in the next EAS builds (step 7 APK proof).
- **Found, not fixed (step 9 territory, owner did not pick it this round):** `backend/services/family_assist/signaling.py`
  `serve()` waits at most 120s for a data message (`asyncio.wait_for(websocket.receive_text(), timeout=120)`). WebSocket
  pings don't count, and after connecting neither phone sends data until the relay refresh (~55 min), so the server
  closes the signaling socket ~2 min into every session and the sharer ends it as a failure.

## Family Help Android repairs — stage 1 (steps 1–5 of owner's 10-step plan) (2026-10-25)
Owner's rule: "Code can enter main immediately. Family Help becomes active in the Android build only after its native
startup defects have been corrected." Repairs committed on their own (git commit after f53eaf7, message starts
"Family Help Android repairs (stage 1 of 10)"); `apollo-family-assist` STILL in `expo.autolinking.android.exclude`.
- Crash cause: `FamilyAssistRuntime.state` was `ConcurrentHashMap` seeded with `null` → NPE at object init, triggered
  by module `OnCreate` at app start. Now `FamilyAssistState` (data class) + `FamilyAssistStateStore` (synchronized,
  session/generation-fenced, terminal states only give way to `begin`). Files in
  `modules/apollo-family-assist/android/src/main/java/app/apollo/familyassist/`: `FamilyAssistState.kt`,
  `FamilyAssistWebRtc.kt` (only initialize/createPeerConnectionFactory), `FamilyAssistRtcPeer.kt` (owns factory/pc/
  track/source; `createScreenSource()`; `onEnded` → owner tears down; executor-guarded; WIRE_REASONS = backend
  signaling.py accepted set), `FamilyAssistProjectionService.kt` (main-thread teardown: capturer → texture helper →
  peer.terminate), `FamilyAssistViewerView.kt` (`FamilyAssistRenderer` VideoSink proxy; init on attach, release on
  detach), `ApolloFamilyAssistModule.kt` (runtime object + module).
- Dependency: `implementation 'org.jitsi:webrtc:124.0.0'` in the module's build.gradle (iOS podspec JitsiWebRTC ~> 124.0.0).
- Checks: JVM `android/src/test/.../FamilyAssistStateTest.kt` (run `./gradlew :apollo-family-assist:testDebugUnitTest`
  once linked); node `tests/familyHelpAndroidRepair.test.ts` (9 source guards + stage gate — REMOVE the stage-gate
  test together with the exclusion in the activation commit). `scripts/verify-generated-projects.mjs` expects 0
  links while excluded, 1 after.
- No Kotlin/Android toolchain in this workspace: the Kotlin was not compiled here. First compile happens in step 7.
- NEXT (only on owner's go): step 6 activation commit (remove exclusion + stage-gate test) → step 7 APK cold-start/
  reopen/background proof → 8 enable Family Help capability + two-device test → 9 TURN/relay + FF10 physical tests →
  10 iOS/iPadOS from ReplayKit. No redesign, no new Gate, no remote control, FF10 security model unchanged.

## Tab badges + splash until ready (2026-10-25)
- `src/domain/tabBadges.ts` (pure, tested in `tests/tabBadges.test.ts`): `countNeedingYou(events)` = cases whose
  latest event is status "attention" ("Needs you"); `countNewSevereAlerts` = HIGH/EXTREME alerts applying here
  (everywhere or home region) not yet seen; `badgeText` (none at 0, "9+" cap).
- `src/higgins/scamAlertBadge.ts`: seen list `apollo.scamAlerts.seen.v1` (500 URLs); first run seeds it with all
  current alerts (no backlog count); refresh on app open/foreground ≤ every 10 min once `deviceId` exists (the API
  needs the device credential); `markScamAlertsSeen` from `app/higgins/scams.tsx` on load, plus reload on focus when
  the count > 0. Owner's choices: Threats = "threats that still need you"; Alerts = "only new High and Extreme".
- `app/(tabs)/_layout.tsx`: `tabBarBadge` (barking red, white text) + accessibility labels; iOS 26 NativeTabs Badge.
- `LaunchSplash`: stays until `useApollo().ready`, min 1s, max 8s, +300ms settle, 0.4s fade.
- `tests/iosSourceReadiness.test.ts` tab-parity test updated for the tablet title variables (was failing since that change).

## Tablet launch artwork (2026-10-25)
- Owner's landscape artwork saved as `assets/images/splash-full-tablet.webp` (1672×941). `LaunchSplash` now runs on
  every device: tablets (shortest side ≥ 600) show the landscape artwork, phones the portrait one
  (`launch-splash-tablet` / `launch-splash-phone` testIDs). Same 1.8s + 0.4s fade, white background.

## Longer tab names on tablets (2026-10-25)
- `app/(tabs)/_layout.tsx`: when the shortest window side is ≥ 600 (tablet/iPad), the Alerts tab reads
  "Scam Alerts" and Learn reads "Learn with Higgins" (both the JS tab bar and iOS 26 native tabs). Phones keep
  "Alerts" / "Learn". Verified in preview at 390×844 (phone) and 820×1180 (tablet).

## Bottom tab labels on one line on every phone (2026-10-25)
- `app/(tabs)/_layout.tsx`: tab label `numberOfLines={1}`, `adjustsFontSizeToFit` (minimumFontScale 0.75),
  `maxFontSizeMultiplier 1.2`; size = clamp(9, (screenW/5 − 10)/6.1, 11) so "Ask Higgins" fits its column
  (11pt from ~390 wide, 10.2pt at 360, 9pt at 320). Was wrapping to two lines at 360 and below, making that
  tab taller/offset. Five equal columns, evenly spaced. iOS 26 native tabs unchanged (system layout).

## Full-screen launch artwork on phones (2026-10-25)
- Owner's portrait artwork (shield dog + ApolloSG Scam Guard + tagline) saved as `assets/images/splash-full.webp`.
- Android 12+/iOS native splash can only show a small centred icon, so `src/components/LaunchSplash.tsx` (mounted
  last in `app/_layout.tsx`) shows the artwork full-screen (contain, white) for 1.8s after the native splash on phones
  (shortest window side < 600), then fades out over 0.4s; never blocks touches after it fades. Tablets: native splash only.
- Native splash background changed to `#FFFFFF` (was `#F5F7FA`) to match the artwork; native icon unchanged
  (`splash-logo.png`). Background change needs a new build; the full-screen artwork also shows in Expo Go/preview.

## Home header wordmark 25% smaller on phones (2026-10-25)
- `app/(tabs)/home.tsx` `home-brand-title`: width `min(screenW*0.58, 280) * (screenW < 600 ? 0.75 : 1)`.
  On a 390-wide phone it is now ~170px (was ~226px). Tablets/iPad (≥600) unchanged.

## CI fix: "Native dependency singleton guard" (run 40196879565) (2026-10-25)
- **Cause 1 (the failing step, "Install without changing the lockfile"):** the committed `frontend/yarn.lock`
  was last committed in 2f99e32 and lacked `expo-background-task` / `expo-task-manager` (added to package.json in
  5f88451), so `yarn install --frozen-lockfile` failed. The workspace lockfile was already correct but the automatic
  saves never include `frontend/yarn.lock`. **Fix:** committed it explicitly (commit f53eaf7).
  ⚠️ Whenever a package is added/removed, commit `frontend/yarn.lock` by hand (`git add frontend/yarn.lock && git commit`).
- **Cause 2 (next step, masked by cause 1):** `tests/previewIsolation.test.ts` read the uncommitted sandbox `.env`
  (ENOENT in CI). Those two assertions now run only where `.env` exists.
- Verified by rebuilding the exact CI checkout (`git archive HEAD` + new lockfile) in /tmp/ci and running every
  workflow step: clean-CNG check, frozen install (with scripts), native-dependency audit, 51 guard/security tests,
  security preflight, no-simulation (production) and simulation-present (preview) exports, GuardDog sha256 — all pass.
- **Pending (not started):** Family Help Android restoration, steps 1–5 (null-safe ConcurrentHashMap state,
  WebRTC lifecycle repair, `org.jitsi:webrtc:124.0.0` inside the module, regression checks, keep Android exclusion);
  plan sent for confirmation, the user has not answered yet.

## Apple compliance: privacy wording, permissions, web privacy policy, no Android wording on iPhone (2026-10-25)
**Owner's choices:** hide Android wording on iPhone; fix the permission details; privacy policy on a web page (no
existing URL, so ApolloSG's server hosts it); keep iPad support. "We redact all personal information going to Google AI"
→ never name Google AI / Gemini in the app; say "AI tools", and that personal information is removed first.
- **Privacy policy web page:** `GET /api/privacy-policy` (public, no device credential) serves
  `backend/content/privacy_policy.html` (`routers/legal.py`). App opens it with `src/config/privacyPolicy.ts`
  (`openPrivacyPolicy`, in-app browser) from Settings › Policies › "Privacy policy" (`settings-privacy-policy`),
  the Privacy screen (`privacy-open-policy`) and the Privacy statement (`disclosure-full-policy`).
  App Store Connect / Play Console privacy URL = `<published domain>/api/privacy-policy`.
- **AI wording:** every user-facing "Gemini"/"Google AI" (privacy statement, register, About, Privacy, DI record,
  simulator notes, saved-answer note, KB label "Written by AI", PDF export, rule book, too-long-document message)
  now says "AI tools"/"AI call". The DI record no longer shows "Model requested". Admin portal (owner-only) unchanged.
  Internal names (`geminiCalls`, `GEMINI_PUBLISHER`, `MAX_GEMINI_CALLS`) unchanged.
- **Permissions (app.config.js):** one camera string for both expo-camera and expo-image-picker ("Scan QR codes and
  photograph suspicious items for checking"); photos "Choose screenshots of suspicious messages to check for scams";
  removed the non-existent `NSUserNotificationsUsageDescription` key; privacy manifest now lists collected data types
  (Device ID, Email, Phone, Name, Other user content, Other diagnostics — linked, not tracking, app functionality).
- **Android wording on iPhone:** Platform-gated in text-guard, call-guard, network, family help, privacy-data (screened
  calls row hidden), rule book (`forPlatform()` in `src/domain/ruleBook.ts` drops "(Android)" labels+lists, "Android:"
  items, "(Android)" table rows on iOS); neutral wording in shared domain text (recovery steps, app removal advice, APK
  finding, gate limitations, phone/messaging spam-label rows, VPN toast). Rule book §13 has a separate "Call Guard (iPhone)".
- Tests: frontend 954/954 (ruleBook iOS filter + no AI provider named; privacyDisclosure updated); backend
  `test_privacy_policy_page.py` (3) + updated rulebook/simulator/DI/too-long tests; rule book re-stamped; tsc clean.

## App name vs the dog: "ApolloSG" where it means the app (2026-10-25)
**Owner's rule:** ApolloSG = the app/product; Apollo = the guard-dog detector/protector (detects, blocks, checks, patrols,
barks…, its findings and protections); Higgins explains. **Owner's choice for unclear lines: ApolloSG.**
- Applied by a context classifier (`/tmp/naming/apply2.py`, not shipped) over user-facing strings only (TS/TSX strings + JSX
  text, Python string literals, rulebook.md, play_console_declarations.md, triage_catalogue.json, native Kotlin/Swift strings);
  comments, docstrings, identifiers, routes, storage keys, test IDs untouched. ~1,030 renamed, ~1,070 kept as Apollo.
- Kept Apollo: dog states and actions ("Apollo is Patrolling", "Apollo blocked…", "What Apollo found", "Ask Apollo to
  investigate", "Calls Apollo screened", "Meet Apollo", "Show Apollo"), "Apollo's protection/checks/findings/wording",
  "Apollo Protections", "Apollo alerts" notification channel, persona lists (Apollo, Higgins, TC FlyBy, Magnum DI),
  How Apollo checks role name "Apollo", `attributedTo: "Apollo"` data values, console tags.
- Renamed: app name/screens/settings/support/privacy/server/data/permissions/install/share-to, KB ("ApolloSG's knowledge
  base", "ApolloSG KB"), cost/admin labels, notification fallbacks, iOS Settings path (`iosPath: "ApolloSG"`), email footer.
- Compatibility: Higgins intent regexes accept "apollo", "apollosg" and "apollo sg"; `incidentPlan.ts` reads both
  "You told Apollo:" (old saved events) and "You told ApolloSG:".
- Email sender name is now fixed in code as "ApolloSG" (`core/config.py`; owner skipped the settings card). The old
  `EMAIL_FROM_NAME` env value is no longer read and was removed from the parity settings list.
- iPhone share sheet label is "ApolloSG": `plugins/withApolloShareIntake.js` rewrites the share extension's
  CFBundleDisplayName after expo-share-intent generates it. `iosShareExtensionName: "Apollo Share Extension"` stays,
  because it also sets the Xcode target name (`ApolloShareExtension`) that the build setup depends on.
- Known, unrelated: a local `expo prebuild --platform ios` fails inside `plugins/withLiveCallerID.js`
  (`addResourceFile` returns null). Not caused by the rename; check it on the next real iOS build.

## iPhone calls: live caller ID out of the build, "Suspected scam" labels (2026-10-25)
- **Live caller ID removed from the build (owner's choice):** `./plugins/withLiveCallerID` and the `ApolloLiveCallerID`
  appExtensions entry were removed from app.config.js. Why: its `addResourceFile(Info.plist)` crashed `expo prebuild` (Expo's
  template has no "Resources" group), so the WHOLE iOS build failed. Also its Swift was compiled into the main app (the target
  had no build phases), it used an API that doesn't exist (`LiveCallerIDLookup`/`LiveCallerIDLookupExtension`; Apple's is
  `IdentityLookup.LiveCallerIDLookupProtocol` + an ExtensionKit `com.apple.live-lookup` extension), it needs an
  Apple-reviewed entitlement, and there is no PIR server + Privacy Pass issuer. Plugin + Swift files are kept for later;
  `extra.pirServer` / `configurePirServerUrl` stay as unused leftovers (the URL is empty).
- Verified locally: `expo prebuild --platform ios` now finishes; targets = main app + FamilyAssistBroadcast, ShareExtension,
  ContentBlocker, CallDirectory, MessageFilter; no live-caller-id entitlement anywhere.
- **Call Directory (ApolloCallDirectory):** the person's `block` list is still blocked. `autoRisky` numbers (an "avoid" lookup
  on this phone) are no longer silently blocked on iPhone: they ring with the identification label "Suspected scam"
  (`addIdentificationEntry`, ascending order). `allow` always wins; a blocked number is never labelled.
  `callerIdentification` capability = same extension status ("supported"/"permission_required"). The finding's
  "what to do" text on iOS says so. Android is unchanged (still rejects block/autoRisky). Rule book §13 iPhone line updated.
- Needs a real iPhone build to see (Call Directory extensions don't run in Expo Go/web).

## Home header wordmark (2026-10-25)
- Home tab header now uses the owner's "ApolloSG" wordmark: `assets/images/apollosg-wordmark.png` (white background removed,
  trimmed, 1200×282). Onboarding/About still use `BrandBanner` with the shield + "SCAM GUARD" logo (`apollo-sg-logo.png`);
  the splash screen is unchanged.
- Rule book re-stamped. Tests updated for new wording: backend 1212 passed; frontend 935/935; tsc clean.


## KB Reusable Intelligence & Sufficiency (2026-10-25)
**Owner's choices:** show the person when a reused result was last checked; savings in the admin portal + server logs;
automated tests only (no testing agent).
- **Reusable cache** `services/reusable_intel.py` (collection `reusable_intelligence`, NOT the KB): cache_id, subject_key,
  provider, source_type, info_type, knowledge_class, ai_generated, authoritative=False, simulated, payload, provenance,
  created_at / last_verified_at / expires_at (from the one `TTL` table) / purge_at (expiry + 90 days, TTL index), hits.
  Subject keys normalise domains/URLs/entities/ABNs/questions; phone + email are one-way fingerprints. Counters
  (`intel_reuse_metrics`, per day + call site, content-free) + log line `intel_reuse site=… events=…`.
- **Sufficiency** `services/sufficiency.py` `assess()` → KNOWN (KB match, or fresh+complete+usable+uncontradicted record
  for this exact subject) / PARTIAL (expired, missing field, not usable, conflict, `live` check) / UNKNOWN. KB first.
- **Call sites:** Higgins general question (`chat.py` P4: KB → saved Gemini answer → one Gemini call; `reused` on the reply);
  TC FlyBy targeted search (`teddy/search.py`: public identifiers only; person/claim/phrase never keyed; legacy
  `teddy_search_cache` read-only); IPQS phone/URL and RDAP keep their caches, TTL from the table, counted.
- **KB boundary:** saved Gemini answers moved out of `higgins_knowledge` at startup (`migrate_gemini_answers`, idempotent,
  dates/provenance/hits kept). Nothing is promoted into the KB.
- **App:** `src/domain/checkedAgo.ts` `reusedLine()`; Ask Higgins "Saved answer · From Apollo's check 2 hours ago, still
  current, so it wasn't looked up again" (`ask-reused-{id}`); report sources show it under a reused source (`…-reused`).
- **Admin portal:** "Intelligence Reuse" page `/api/admin/intel-reuse` (calls avoided/needed, share, by site/day, inventory, TTLs).
- **Benchmark:** `services/kb_benchmark.py` + `scripts/kb_benchmark.py` (60 cases; baseline top1 0.179, top3 0.196 —
  `tests/kb_benchmark_baseline.json`).
- **Rule book:** section 8 gained "Reusable intelligence (not KB knowledge)"; TC FlyBy/Higgins/Your data/cost lines updated;
  WATCHED += reusable_intel, sufficiency, phonerisk, urlrisk, rdap, checkedAgo.ts; re-stamped.
- **Tests:** `tests/test_sufficiency.py` (18), `tests/test_reusable_intel.py` (36: metadata, keys, TTL, chat reuse/expiry/KB-first/
  simulated/personal, AI never in KB, writers allow-list, Magnum/evidence isolation, TC FlyBy reuse/mixed/expired/negative/
  unsourced/preview, reused sources keep last-checked time, IPQS phone/URL + RDAP, migration, counters, admin page, benchmark),
  `test_teddy_routing.py` (+reused sources e2e), `test_rulebook.py` (+1); frontend `tests/checkedAgo.test.ts` (4).


## Higgins Plain-English Renderer + Fidelity Check, and one Higgins avatar (2026-10-25)
**Owner's choices:** Apollo's wording only (no AI rewrite, no extra cost); applies to TC FlyBy and Magnum DI results; Fidelity
Check results visible in the admin portal; on FAIL the person sees Apollo's own wording.
- **Backend `services/higgins/explain/`:** `facts.py` (authoritative findings from the validated result + routing + sources;
  core vs allowed identifiers, contradictions, deduped "how"), `words.py` (fixed plain swaps, glossary of 19 jargon terms,
  4 severity lines, basis/confidence labels, certainty/safety/softener/escalator word lists), `render.py` (deterministic draft:
  Markdown stripped, swaps outside quotes/identifiers, each point once, every finding kept with "Seen directly by TC FlyBy ·
  High confidence", fixed jargon explanation, outcome label first, fixed severity line; `literal` parts = Apollo's wording),
  `fidelity.py` (PASS only if: outcome label, severity line, every finding in order with same meaning/confidence/basis,
  every result sentence said + no unsupported sentence, identifiers kept/none added, quotes verbatim, contradictions kept,
  no added certainty/safety/softening/escalation, right investigator, every step kept, glossary-only explanations; failure
  details are content-free), `__init__.py` (`explain()`: draft → check → one repair with failed parts literal → check →
  else mode `literal`; `summary()` for routing). General questions (no outcome, no findings) → none.
- **Contract:** `HigginsResponse.plain_english: PlainEnglish | None` (mode plain/repaired/literal, result, severity,
  established[PlainItem], means, matters, todo (1:1 with actions), uncertain, how, fidelity, attempts, attempt_failures).
  Structured result never changed (test). Attached in `coordinator._commit` (`_plain_english`); a renderer error never fails
  the case (`RENDERER_ERROR`, Apollo's wording). `routing.fidelity` = {status, mode, attempts, attemptFailures, by, revision, at}.
- **Admin portal:** Investigations cost report → "Higgins Plain English — Fidelity Check" stats (checked / PASS first time /
  PASS after repair / FAIL) + failure-code table; "Plain English" PASS/FAIL column; drill-down section with mode, per-attempt
  reasons and both texts side by side (decrypted at view time, redacted; "left the server" note after the 24-hour deletion).
- **App:** `shownPlainEnglish()` / `plainReport()` / `stepText()` in `src/domain/reportSections.ts`; Ask Higgins
  (`InvestigationView`) and a threat's Overview (`patrol/[id]`) show the plain English only when PASS and not literal, else
  Apollo's wording via `buildReport`. `ReportBody` shows the severity line (`{ids}-severity`) and each finding's fixed
  explanation (`{ids}-finding-N-explain`). Verified in the preview: "Hi Mum" check → "Likely scam. …", severity line,
  three findings "Seen directly by TC FlyBy · High confidence".
- **Rule book:** section 5 gained "Plain English and the Fidelity Check" (+ cost line); explain/*.py WATCHED; re-stamped.
- **Avatar:** new `src/components/HigginsAvatar.tsx` (rounded square, corner = 25% of side) used on Ask Higgins (header +
  chat), report header, threat Overview briefing, gate details (3), protection details (2), Apollo Protections, Learn header,
  Learn article, About Apollo. Duplicate/unused avatar styles removed; Retrofit "Higgins report" icon is a rounded square.
- **Tests:** `backend/tests/test_plain_english.py` (32: renderer, 20 corruption kinds, repair, literal, admin), `test_rulebook.py`
  +1; frontend `tests/plainEnglish.test.ts` (4), `tests/higginsAvatar.test.ts` (2). Full backend suite 1126 passed; frontend
  931/931; tsc clean. No testing agent (owner's rule).


## Privacy/redaction and knowledge base rules added to the rule book (2026-10-25)
- `backend/content/rulebook.md`: new **7. Privacy and redaction** `{#privacy}` (always removed on the phone; removed again on
  the server; the one Gemini boundary: credential fields dropped, personal fields "[personal data withheld]" outside an
  investigation, tracking links shortened 80/200 chars, research/advisory identifiers labelled; pictures: metadata stripped,
  credentials blacked out on a copy, withheld if not possible or no text reader; what may leave the phone: per-request
  allow-lists, never-accepted fields, links keep path, Threats/Family fixed wording, handoff limits, My Personal Data labels;
  what the server keeps: investigations encrypted, 15-minute working copy, finished record on the phone; chat 5 min).
  New **8. Apollo's knowledge base (KB)** `{#knowledge-base}` (kinds, trusted tiers 24/11/5 websites, Tavily only for KB
  upkeep, weekly run, topics/results per tier, re-reads, page checks, versions/duplicates/historical, publishing to Scam
  Alerts and Learn, deterministic search thresholds, verbatim quoting + general-knowledge note, saving AI answers, where it is
  used). Settling rules is now **9**. Section 1 "Privacy first" points to section 7.
- Auto-sync: WATCHED += `core/redaction.py`, `llm_boundary.py`, `capacity.py`, `retention.py`, `privacyPolicy.ts`,
  `privacy.ts`, `imagePrivacy.ts`, `personalDataStore.ts`, `apollo_kb.py`, `kb_sources.py`, `tavily_client.py`, `knowledge.py`. Re-stamped.
- Tests: `test_rulebook.py` +2 (privacy numbers + redaction behaviour; KB numbers, tier counts, note, storable, trusted
  https) → 15 pass; `ruleBook.test.ts` +1 (phone redaction label, evidence kept, egress refusal message, link cleaning) → 6 pass.
  Frontend 900/900, tsc clean. Not claimed: 24-hour evidence deletion (`EVIDENCE_RETENTION_SECONDS` is defined but not enforced).

## Ask Higgins rules added to the rule book (2026-10-25)
- New section **6. Ask Higgins (the chat screen)** `{#ask-higgins}` in `backend/content/rulebook.md` (Settling rules is now 7):
  what's removed/sent before anything leaves the phone (4,000-character limit, state-only reading); where a message goes,
  first that applies (open case → "I want something checked" form → wayfinding → phone state on the phone → suspicious
  described → fixed Apollo answers → short/unclear → server); what starts a check from a typed message (plain ask AND a
  link/email/phone ≥8 chars/≥30 chars of text); the six + forms with default questions; picture and 10 MB rules; handoffs
  (scam alert, Learn, Patrol/incident/Device Check, case, screenshot); taps and offers (≤2 screens, nothing starts until
  tapped, 2,000-char general answer); retention (phone 1 h / 40 messages; server 5 min, receipt 30 days; Clear chat);
  suggestions (20 quick questions, 4 shown, own most-asked); failures and the resubmit note. Section 5 now quotes the
  off-topic reply word for word; the stale "Ask Magnum DI to investigate" label is now "Ask Apollo to investigate".
- Auto-sync: `services/rulebook.py` WATCHED is now project-root relative and includes the Ask Higgins files on the server
  (`pipeline_submit.py`, `context.py`) and on the phone (`ask.tsx`, `checkIntent.ts`, `intentRouter.ts`, `localResponder.ts`,
  `issueExplanation.ts`, `followUp.ts`, `chatMemory.ts`, `quickQuestions.ts`, `starterMemoryCore.ts`, `HigginsCheckSheet.tsx`,
  `HigginsArtifactInput.tsx`, `resubmit.ts`). Files absent on a server (published backend without app code) are skipped;
  a test checks every watched file exists. Re-stamped.
- Tests: `test_rulebook.py` +3 (watched files exist, Ask Higgins numbers/off-topic text match the server, typed-check rule);
  `ruleBook.test.ts` +1 (quick-question count, clarifying question word for word, form routing, form names). All pass; tsc clean.
- **Known quirk fixed (2026-10-25):** the short-message rule (`intentRouter.ts resolveAmbiguous`) now matches whole words
  only, so "How do I report someone?" goes to Higgins, not protection status. Threat words list their usual forms (scammed,
  hacker…). Rule book updated and re-stamped; `higginsIntentRouter.test.ts` +3 tests.

## Investigation rule book written (2026-06)
- Owner asked for copy-paste rules for Apollo detection, Higgins Triage, TC FlyBy, Magnum DI and Higgins: processes,
  resolution rules, escalation triggers, information requested. Written from the code into
  `memory/APOLLO_INVESTIGATION_RULEBOOK.md` (internal detail) and given in chat. No code changed.


## TC FlyBy stopping rule + one Apollo outcome system (2026-10-24)
**Owner's rule:** a case is RESOLVED at TC FlyBy when further Magnum DI investigation could not change Apollo's finding or
Higgins' action; "Unable to determine" is a valid resolved outcome; a KB pattern match supports the assessment but is never
proof about the sender. Owner's answers: impersonation + brand-new domain → Concerning (no Magnum); "Hi Mum" → check Apollo KB
first, pattern match → Concerning/Likely scam, unclear → Magnum; bare link → stop at Concerning / Unable to determine after all
Teddy resources; outcome labels in the app result AND the admin portal, fed by both layers.
- **Outcomes** `services/higgins/outcomes.py`: no_scam_indicators · concerning · likely_scam · confirmed_threat · unable_to_determine,
  each fixing its assessment. `HigginsResponse.outcome` / `ModelResponse.outcome` (optional; null = general question). Magnum's
  Gemini schema requires `outcome` (criteria in its description); validation rejects an outcome that disagrees with the assessment.
  Preview simulator returns one too. `routing.outcome` stored on every commit.
- **KB scam patterns** `services/higgins/teddy/patterns.py`: 8 Scamwatch-sourced patterns (family new number, organisation phishing,
  delivery/toll, government threat, unexpected money, job/task, investment returns, remote access) stored in `higgins_knowledge`
  as kind `scam_pattern` (markers in the entry; loaded by `knowledge.refresh()` and on first use). Deterministic match:
  full → Likely scam, opening (family pattern only) → Concerning, partial → Magnum.
- **Teddy decide()** (`teddy/__init__.py`): official decisive concern stops early (Confirmed); otherwise official → KB (patterns) →
  targeted search for the planned open checks, then: unreadable image/doc or a register conflict → Magnum; pattern full/opening
  (unless the material's links are the named organisation's own → contradiction → Magnum) → Likely/Concerning; brand named +
  link not its domain + independent fact about that link (new domain, IPQS flag, redirect, download) → Concerning; bare link →
  Concerning / No scam indicators / Unable to determine; any other message → Magnum (message analysis).
- **Results** `teddy/report.py`: `compose()` → threat / pattern / impersonation / link results; findings are the material's own
  words or sourced live facts; KB pattern only in "What Apollo's knowledge base adds" + sourceIds; uncertainties say what was not
  taken further and why. Magnum brief names the pattern check in one line.
- **Admin portal**: Outcome badge column on investigations, Outcome + "Apollo KB Scam Pattern" rows in the drill-down, cost-routing
  table broken down by the five outcomes.
- **App**: `outcome` in `src/investigation/types.ts`; `outcomeLabel`/`outcomeTone` in `messageVoice.ts`; outcome badge
  (`inv-outcome`) on the investigation status card. Verified in the preview: "Hi Mum" text → "Likely scam" badge.
- **Production never loads simulation code**: the indicator reader moved from `preview_analysis.py` to `services/higgins/indicators.py`
  (Higgins Triage imported the preview module in production).
- Tests: `test_teddy_routing.py` (18), `test_one_gemini_call.py` material updated (its ANZ text is now settled by Teddy),
  stale mock fixed in `test_deterministic_higgins.py`; full backend suite 1048 passed. Frontend messageGuardrails + tsc clean.
  No testing agent (owner's rule). Preview: 0 live Gemini calls since 08:00 UTC today.

## Admin portal: "Live AI" / "Simulated" badge on every page (2026-10-24)
- `routers/admin_portal.py` `_ai_mode_badge()` rendered by `_shell` at the top of every signed-in page
  (`#ai-mode-badge`, `data-mode="preview|live"`), read from `provider.get_provider_mode()` + `provider.GEMINI_API_KEY`:
  **Simulated** (amber: preview server, no Gemini calls, simulator + Apollo KB) · **Live AI** (green: every AI request
  goes to Gemini and is billed) · **Live AI — no key** (red: would call Gemini but no key, AI requests fail).
  Signed-out pages show nothing. Each server's own portal shows its own mode (preview → Simulated; published → Live AI).
- Verified in the preview portal (Dashboard + Usage & Costs) with a temporary admin session, then removed.
- Tests: `tests/test_admin_mode_badge.py` (4).

## Preview never calls live Gemini — the simulator answers from the Apollo KB (2026-10-24)
**Why preview went live:** commit 6f025ec (23 Oct 00:59 UTC, an agent fix for production answering from the
simulator) made the simulator depend on `APOLLO_PREVIEW_SIMULATOR=on` in the preview-only slot. That value was never
set, so from 23 Oct 00:44 UTC the preview server ran `provider_mode=live` and billed Gemini.
**Fix:** `provider.preview_environment()` = `APOLLO_PREVIEW_SIMULATOR=on` OR the Emergent preview workspace itself:
`APP_URL` host ends with `.preview.emergentagent.com` (set by the workspace's supervisor, never in `.env`/deployment
secrets; the published app is never served from that domain). Lookalikes/empty/other hosts → live. Startup log now
`provider_mode=preview`; verified 0 live `gemini_usage` records after restart (only `extra.simulated=True`).
**Owner directive:** "calls to gemini in preview should go to simulation gemini. Simulation gemini can use apollo kb as
its information base." `knowledge.related()` / `related_share()` (same-subject match on titles; saved `gemini_answer`
entries never used) feeds `preview_simulator.simulate_generate`:
- Higgins chat miss → quotes up to 2 KB entries with publisher, provenance and link, or says the KB has nothing.
- Investigation → real evidence-derived result + "From Apollo's knowledge base (general knowledge, not a finding…)"
  in `explanationMarkdown` (never a finding, no source ids).
- Device Protection explanation (`ModelExplanation` schema) → labelled SIMULATED, KB excerpt if any.
- Usage records carry `extra.apollo_kb` (kb ids used).
**Never stored as real:** chat skips `remember_gemini_answer` when `final.simulated`; `protection_explanations` returns
`source: "preview_simulator"` without caching; the app never keeps it (`protectionExplanation.ts`) and labels it SIMULATED.
Tests: `test_provider_environment_guard.py` (+workspace/lookalike cases), `test_preview_simulator_specifics.py` (+6),
`test_protection_explanations.py` (+1); 80 related backend tests pass. Production unchanged (stays live) on next publish.

## Change banner: Higgins' "what to do now" line (2026-06)
- `whatToDoNow(change)` in `src/domain/deviceProtectionChanges.ts`: one short, pre-written next step per change kind
  (USB debugging, Developer options, outside-store installs, other VPN, app scanning, screen lock, device admin,
  Accessibility, notification access, certificates; anything else → "Open it to see what Higgins recommends.";
  any move back → "Nothing to do — it's back as recommended."). Never generated — no Gemini call.
- `ProtectionChange.kind` (optional) separates USB debugging from Developer options under the same protection.
- `changeBanner().todo`: the one change's step, or "First: …" for the first change that needs doing when several did.
- Shown as "Higgins: …" on the Home banner (`home-protection-change-todo`), the "Changed since you last looked" rows
  (`ProtectionListRow` `higgins` prop → `device-prot-change-N-higgins`) and each entry in Protection Details "What changed".
- Tests: `tests/deviceProtections.test.ts` (+1 test, banner assertions extended). Native-build only to see live.

## Device Protections + Apollo Protections: exception-first, cached explanations, change detection (2026-06)
**Owner's choices:** Apollo's own protections = "Written once as fixed text"; phone protections = "Pre-write the common
ones" (Gemini only on a genuine miss); manual checks = "No, always 'Check manually'" (no mark-as-done); a change shows as
"Banner on Home plus a 'Changed' tag on the item" until that protection is opened; "Protected" = "Folded, with a count".
- **Names:** "Device Capabilities" → **Device Protections** (`/device-protection`, Home card, Higgins app map);
  "Protection" tab/card → **Apollo Protections** (`/(tabs)/protection`).
- **Store** `src/store/deviceProtectionStore.ts`: one assessment (reading + groups + summary + changes + `unseen`) shared
  by Home, Device Protections and Protection Details. Started in `app/_layout.tsx` (`startDeviceProtectionMonitor`):
  reassesses on open and on return to Apollo, at most once a minute; "Check again" forces it. Snapshot/changes/opened
  ids in AsyncStorage (`apollo.deviceProtections.*`). `acknowledgeProtectionChanges(id)` runs when a protection opens.
- **Change detection** `src/domain/deviceProtectionChanges.ts`: `diffProtectionSnapshots` (USB debugging, developer
  options, side-loading, other VPN, app scanner off, screen lock, new device admins / accessibility / notification
  readers, new certificates, any other verified health move); unread on either side is never a change.
  `unseenChanges`, `changeBanner`. Native reads only — the browser preview never records changes.
- **Apollo grouping** `src/domain/apolloProtections.ts`: action + Setup required → Needs attention; limited /
  unverified / off / checking → Needs checking; Watching + Manual check → Protected; Unavailable → Not available.
- **UI:** `src/components/ProtectionList.tsx` (`ProtectionGroup` with count + fold, `ProtectionListRow` with
  "Changed" tag), `src/components/device/ProtectionChangeBanner.tsx` (Home). Device Protections screen: device card +
  summary + "Check again" → Changed since you last looked → Needs attention → Needs checking → Protected (folded) →
  Optional (folded) → What Apollo can use here (folded `CapabilityTables`). Preview: one folded catalogue list.
  Apollo Protections screen: the three groups above "Browse by category". Home cards show chip + exception summary.
- **Protection Details** (`app/capability/[id].tsx`): status line from the read (`protectionStatusLine`), evidence
  label, "What changed", What it is / Why it matters / What it protects against from `deviceProtectionExplanation`,
  recommendation, steps, and a fixed "stays Check manually" note. The "I've checked this myself" button and
  `protectionChecklistStore.ts` were REMOVED. Gate details shows "Why it matters" from the fixed Apollo text.
- **Backend:** new `GET /api/protections/device/{id}` = pre-written explanation only (404 otherwise; used by the
  browser preview, never calls Gemini). `POST /api/protections/device/explanation` unchanged (seed → cache → one Gemini
  call on a genuine miss). New egress endpoint `protection_explanation` (`protectionId,title,platform,osVersion,oem,model,scope`).
  All 39 catalogue protections are pre-written; only provider rows (e.g. Samsung Smart Call) can reach Gemini.
- Tests: `frontend/tests/deviceProtections.test.ts` (12 new), updated `deviceCapabilities` + `deviceSecurityCatalogue`;
  frontend 926/926, tsc clean; backend `test_protection_explanations.py` 10 passed. No testing agent (owner's rule).
- **Needs a real build:** the OS/OEM reads and change detection only run in an Android/iOS build, not Expo Go/preview.

## Remove unnecessary Gemini calls — Higgins presents what Apollo already knows (2026-06)
**Owner's choices:** keep the ONE Gemini call for a general scam question nothing in Apollo answers; NEVER call
Gemini on a follow-up to a finished investigation (even with a new link/email/number); health check = "Status from
saved records" (key set + how the last real Gemini call went, no test call). No testing agent (owner's rule).
- **Finished Magnum DI follow-ups (0 calls):** `presenter.investigation_follow_up` + `is_finished` + `new_items`
  (link/email/phone ≥8 digits) → "You've mentioned something new (…) that wasn't part of this investigation …
  nothing new has been checked. To have it checked, start a new check." New `recheck` intent; the old "add it and
  Magnum DI will investigate" line removed. Frontend port `src/higgins/followUp.ts` (same wording): `caseStore.ask`
  and `continueWith` answer on the phone when the result is complete/partial with no pending question →
  `CaseState.followUps` rendered in `InvestigationView` (`inv-followup-*`). Works on device-local (purged) cases.
  Server safety net: `POST /investigations/{id}/turns` on a finished case returns 200 `{job: null, followUp}` and
  starts no job (`_finished_follow_up`); `transferManager.runAppend` settles on `job: null`. Answering Magnum DI's own
  pending question (waiting_user) still continues the investigation.
- **Chat (`chat.py`):** saved-report follow-up now checked BEFORE investigation-intent routing; scam alert card not in
  the cache → `presenter.scam_alert_card` (card's own words); "Please explain the learning article: X" →
  `presenter.learn_article` or "couldn't find"; `selected_patrol_record_id` → `presenter.patrol_record`; device state:
  `_ABOUT_STATE` ("my … protection/gates/permissions", "my device security review/assessment", "Apollo says its
  status") always answered from the snapshot, naming matched gates/capabilities (`_named_lines`), else the overview.
  The single `provider.generate` remains last (AST test).
- **Patrol / incident / Device Check "Ask Higgins" handoffs** (no case id): `src/higgins/issueExplanation.ts`
  explains the context in chat with no server call; card `ask-issue-investigate-offer` → "Ask Magnum DI to
  investigate" starts a separate investigation only on tap. Handoffs with a case id open that case.
- **Health check:** `health_check.provider_status()` (gemini_usage, simulated excluded) stored as
  `provider_status`, exposed at `investigation.provider`; Support screen shows "AI service key: set." + "Last Gemini
  call: <time> — it worked / it failed — <reason>" (`src/health/providerStatus.ts`).
- Not changed: `/page/extract` and `/page/crawl` still call Gemini (signal extraction, not used by the app).
- Tests: `backend/tests/test_deterministic_higgins.py` (20), `frontend/tests/deterministicHiggins.test.ts` (6).
  Backend full suite 1001 passed (13 live-API failures were a mid-run restart; re-run passed), frontend 922/922, tsc clean.
  Live: 4 chat questions (device state, alert card, Learn article, latest alerts) → gemini_usage unchanged.


## Phases 3–4: screenshot checks read on the phone, cost dashboard verified, resubmit note on Ask Higgins (2026-06)
**Owner's choices:** screenshot checks = "Phone reads the text, then Apollo checks it" (the picture never leaves the
phone; Gemini only via Magnum DI's one call if Triage escalates). No readable text = say so, no check, pick another
image or type. Resubmit reminder = "Only on the Ask screen" (a note, no pop-up elsewhere).
- **Earlier in this phase (previous session):** Tavily-maintained Apollo KB (`services/apollo_kb.py`, `kb_sources.py`,
  `tavily_client.py`, admin `/api/admin/knowledge` + Refresh now, weekly loop in `server.py`); deterministic Higgins
  (`services/higgins/presenter.py`, `knowledge.py`, `chat.py`); scam-alert analysis now deterministic
  (`scam_analysis.py`, `method: deterministic_source_rules`, no Gemini); `/message/extract` + `extract_message_screenshot`
  DELETED (backend test asserts 401/404); account screenshot check reads text on the device.
- **Message screenshot check (`app/message.tsx`):** `screenImage(uri, "message_screenshot")` → redacted
  `extractedText` + `detectedSender` → the ordinary `checkMessage` (text box opened so the person sees what was
  checked). The old "Before you upload" modal (`ImageUploadPrep`) and the "sent copy" image evidence were removed from
  this screen — nothing is uploaded, so neither was true any more. Empty read → `message-screenshot-error` card
  ("Choose another screenshot" / "Type or paste the message"); wording differs for preview, no recogniser, and no
  text found. Preview only: "Use a preview sample screenshot" (`message-sample-picker`) registers a sample's known
  text, so the success path can be seen in the preview. Verified: bank-SMS sample → read → Triage → Magnum DI answer.
- **Cost dashboard** (`/api/admin/investigations-cost`) screenshotted: cases, Gemini calls, calls per investigation,
  est. cost per investigation, banner "One investigation = one Gemini call" (first call / one retry / over the limit,
  plus Gemini calls outside investigations). Today: 307 cases, 1.00 call each, 0 over the limit.
- **Resubmit note:** `src/investigation/resubmit.ts` `StoppedCase {caseId, jobId, resubmitAt, expiresAt, status}`,
  `dueReminder` (pause over, not dismissed, not expired, not the case on screen), `withStopped` (same pause keeps a
  dismissal; a new pause re-arms). `src/store/resubmitReminderStore.ts` (AsyncStorage key `…resubmitReminders.v2`, ids
  and times only). `caseStore.useInvestigation` remembers a failed + resubmittable case with `resubmitAt` and forgets
  it on working/answered/waiting_user or `remove()`. `attach(caseId, stoppedJobId?)` now restores a stopped job
  (`getJob` → phase failed + failure + job) — before, a reopened stopped case (status `partial`, no active job) showed
  as idle with no Resubmit. `src/components/ResubmitReminder.tsx` = inline gold note above the Ask conversation
  (Open / dismiss). Ask's generic "Retry" button now only shows when no case opened (the case's own Resubmit, with its
  countdown, covers the rest). Verified in preview: note → dismiss persists; Open → "Resubmit" → finished; note cleared.
- **Found while verifying:** from ~05:20 to ~07:18 UTC every Gemini call failed with HTTP 402 "prepayment credits are
  depleted" (Google AI Studio billing); calls succeed again from 07:22. Apollo classifies 402 as
  `provider_configuration` ("isn't configured correctly") — wording could name the billing cause (not changed).
- Tests: `tests/resubmit.test.ts` 9 (4 new). Frontend 914/914 + all `test_*.mjs`, tsc + ESLint clean; backend
  `test_gate2_message + test_one_gemini_call + test_apollo_kb` 22 passed.


## Magnum DI: one investigation = one Gemini call (2026-06)
**Owner directive:** each investigation makes exactly one Gemini call — no multi-round loops, no nested research
calls, no second call by Higgins to present the answer. Owner's retry rule: "only 1 additional retry then ask user to
submit again in an appropriate time" → about 5 minutes; the failed case keeps everything submitted + Resubmit button.
- **Enforcement point:** `repo.claim_gemini_call(owner, job_id, MAX_GEMINI_CALLS=2)` — atomic `$inc` on the job's new
  `gemini_calls` field, taken in `coordinator.run_turn` right before the only `provider.generate`. Refused ⇒ outcome
  `call_limit_reached`, nothing sent. Crash recovery / duplicate workers can never make a third call.
- **jobs.py:** one retry (4 s pause) for retryable provider failures and `response_invalid`; `provider_configuration`
  never retried. Then `_fail_resubmit`: `retryable=True`, `retryAfterSeconds=300`, new `Failure.resubmitAt`, job
  `resubmit_at`; message from `resubmit_message()` ("Magnum DI tried twice, but … Please resubmit in about 5 minutes —
  everything you submitted is kept, so it's one tap."). Old 3 transient retries and the sweeper's Phase-2 auto-resume
  (up to 2 resumes × 4 calls) are DELETED — only the person resubmits.
- **Resubmit = `POST /investigations/{id}/jobs/{job}/resume`:** 429 (`rate_limited`, retryAfter) before `resubmit_at`;
  afterwards resets `gemini_calls` to 0 and records a `manual_retry` in retry history.
- **Nested research removed:** `tools.py` lost the function-calling `DECLARATIONS`/`execute`, `_grounded` research,
  `research_settings`, `research_application`, `lookup_*`, `ask_user` (all unreachable or Gemini-calling). The
  settings-plan endpoint no longer runs a research call — its steps are Magnum DI's own action text.
- **Vision Gate:** `/vision/investigate` no longer pre-analyses the image with Gemini (that was a 2nd call per image
  investigation). The privacy-screened image + device-recognised text go to Magnum DI as evidence for its one call;
  the immediate result is Apollo's own deterministic checks. `VISION_INVESTIGATE_PROMPT` deleted.
- **Higgins:** already presents Magnum DI's response verbatim (no presentation call); chat routes investigation
  intent to the pipeline without a Gemini call.
- **Frontend:** `src/investigation/resubmit.ts` (wait/labels, pure) → `InvestigationView` "Resubmit in 4:32" (disabled,
  live countdown) → "Resubmit"; hidden when `retryable:false`. `retry_scheduled` now shows as working, not "reconnecting".
- **Still 2 calls (not changed, owner to decide):** screenshot message/account checks call `/message/extract` (Gemini
  text extraction) before the check, which may then escalate to Magnum DI.
- Tests: `backend/tests/test_one_gemini_call.py` (10), `frontend/tests/resubmit.test.ts` (5). Full suites: backend 977
  passed, frontend 910/910, tsc + ESLint clean.
- Owner (2026-06): proxy setup DROPPED — no proxy URL will be provided; ACSC stays on the Internet Archive relay.

## Hamburger menu on every full screen + title icons + junk drafts purge (2026-06)
- `src/components/AppMenu.tsx` `AppMenuButton`: hamburger (Settings, About, Privacy, Support) — always the LAST
  (far-right) header icon on full screens: Home, Threats, Scam Alerts, Ask Higgins, Learn, Protection/guard,
  Check, Protections, Settings (tab), About, Privacy, capability, device-protection, gate-details, email accounts,
  Feed Health, vision, article, scam detail, and CheckToolHeader non-modal tools (account-monitor, call-guard,
  patrol history, saved-checks). Hidden on pop-ups: `src/navigation/modalRoutes.ts` MODAL_ROUTES drives BOTH the
  root Stack's `presentation: "modal"` and the menu's self-hiding. Screens closed with an X (ChildScreenHeader,
  CloseButton screens, Family Help) never include it. Visual 34pt + hitSlop (44pt target).
- Threats + Scam Alerts titles lead with `HeaderIconTile` (red ShieldAlert / orange Megaphone, 42pt).
- `FitTitle` (+ `src/utils/fitTitle.ts`) keeps header titles on one line (28→min 20) — ScreenHeader + Ask Higgins.
- Junk Learn drafts: `learning_feeds.purge_listing_page_links()` at startup deletes automated articles/candidates/
  feed items that are links back to a listing page itself (year/category filters, ?page=, "Skip to…"); preview:
  45 articles (44 drafts + 1 published) + 46 items/candidates removed; 10 real in-review alerts kept.
  `_html_items` now drops any link to the listing page path (ignoring query/fragment).
- Tests: `tests/appMenu.test.ts`, `backend/tests/test_learning_feed_listing.py`.

## Preview ≠ production: root causes fixed + parity check (2026-06)
**Owner complaint:** production Learn showed 6 articles, preview ~57. Root causes (all verified against the live production API):
1. The 43 curated en-AU articles (`content/learning_catalogue_au.json`) only ever reached the PREVIEW DB via the
   one-off `scripts/import_learning_catalogue.py --publish`. Production never ran it. Production's other 39
   articles are feed-derived en-US/en-GB/EU items, hidden because the Learn screen requests `language=en-AU`.
   FIX: `learning.seed_catalogue_articles()` + `seed_learning_articles()` now run at startup (idempotent, never
   overwrite admin edits/archives); thumbnails from `content/learning_thumbnails.json` (Emergent storage is shared —
   all 49 paths verified served by production).
2. Production's server is refused by Scamwatch/FTC/ACSC (cloud-address blocks) while preview's is not.
   FIX: `learning_feeds.refresh` falls back to the Internet Archive (`archive_relay`) when a source refuses
   (fetch_failed or 403/406/429/503); `relay_used` shown on Feed Health. ACSC always relayed (RSS `/rss/alerts`).
3. Both environments: RSS items lost description + pubDate (Element truthiness bug) and FBI items were all rejected
   (URL only in <guid>). FIXED in `_xml_items` (`_find`, guid fallback).
4. Preview's backend `.env` has a BLANK `EMERGENT_LLM_KEY` (managed key) → preview file storage fails (Learn
   thumbnails 404 in preview, work in production). NOT changed by agent (managed key rule) — needs owner OK.
**Parity check:** `GET /api/health/parity` (device-authed, no secret values: code hash, Learn counts/curated hash,
feeds status/via, non-secret settings, credential presence booleans, file storage) +
`python scripts/parity_check.py --production https://threat-patrol-1.emergent.host` (feed-grown counts reported
separately as expected). Before redeploy it reports production has no parity endpoint (older build).
Two anonymous parity-check devices registered on production (tokens cached in /tmp/apollo_parity_tokens.json).
Tests: `tests/test_environment_parity.py`; full backend suite 966 passed.

## ENISA feed fixed + listing-page parser (2026-06)
- ENISA retired its RSS (old and documented URLs both 404). `enisa-news` in `content/learning_catalogue_au.json`
  now reads `https://www.enisa.europa.eu/news` as an `approved_listing_page` limited to `/news/` (re-seeded at
  startup, so production picks it up on redeploy). First live sync: 11 articles, Healthy.
- `learning_feeds._html_items`: filters by the feed's allowed path BEFORE the 100-item cap (ENISA's articles sat
  after 100+ menu links), trims hrefs, keeps repeated links once, drops links back to the listing page itself
  (Scamwatch "Skip to content" junk). Tests: `tests/test_learning_feed_listing.py`.
- Feed Health wording: `fetch_failed` now reads "The source never answered Apollo's server…" (was wrongly
  "safety checks refused"). ACSC (cyber.gov.au) times out from the pod on every fingerprint since 24 Sep —
  needs `OUTBOUND_PROXIES` (http/https proxy URL, ideally Australian residential/ISP IP; socks5 would need
  `socksio`). Setting it routes ALL public fetches (feeds, page crawls) through the proxy.

## Feed Health screen + old test fix (2026-06)

**Feed Health** — Settings > Diagnostics > Feed health (`/settings/feed-health`), visible to everyone.
- Backend `GET /api/feeds/health` (device-authed, `services/feed_health.py`): one row per enabled government
  feed with source, last successful sync, records in the last sync (`item_count`), last error (plain words +
  code/detail) and a status badge. Rule: failing = latest attempt failed; stale = no successful sync in 24 h
  (incl. never synced); healthy otherwise. Sorted failing → stale → healthy.
- `learning_feeds.refresh` now also stores `error_detail` (Apollo's own ValueError reason / OutboundBlocked
  code) so the screen can explain failures; cleared on success.
- Frontend: `src/domain/feedHealth.ts` (labels, tones, relative times), `src/components/FeedHealthRow.tsx`,
  `app/settings/feed-health.tsx` (waits for device identity, pull to refresh, retry). New Settings group
  colour `groupDiagnostics`. Higgins app maps updated (Settings now has eight groups).
- Tests: `tests/feedHealth.test.ts`, `backend/tests/test_feed_health.py`.

**Old test fix** — `tests/nativeDependencyGuard.test.cjs` preflight fixture now copies `plugins/` (app.config.js
requires `withRestrictedPhonePermissions`) and resolves `@expo/config-plugins` via NODE_PATH. Full frontend
suite: 901/901 pass.

## Post-publish: tombstone sweep timeout on Atlas + remaining live-answer rejections — FIXED (2026-10)

**Publish actually succeeded**: production served the new backend (`providerMode: live` present). The
shared log line was a runtime defect, not a deploy-step failure (root `/health` and `/api/health` are
DB-free liveness probes).
1. `maintenance_component_failed component=tombstones type=TimeoutError` — `sweep_tombstones` re-scanned
   the 200 oldest (long-deleted) cases every cycle with up to 600 delete round trips: instant on local
   MongoDB, >15 s on Atlas, never progressing. Rewritten to be driven by the content that exists (one
   `$group` per content collection, one case lookup per 200 groups, deletes only for real orphans).
   `tests/test_tombstone_sweep.py` (orphan semantics + 3 000 deleted cases never visited).
2. Live Gemini still failed ~1 in 3 production investigations: with `sourceIds` closed, Gemini moved its
   search citations ("1.1.4") into `evidenceIds`. `response_schema()` now also limits
   `findings[].evidenceIds` / `remainingEvidenceIds` to the supplied evidence ids and offers `basis:
   observation` only when evidence exists. Live batch on preview: 5/5 answered on the first Gemini call.
Deployment-agent BLOCKERs (TTL/maintenance deletions, `.env` in `.gitignore`) again NOT applied — they are
the intended 15-minute privacy retention and secret hygiene, and did not stop this publish.

## Deploy failure: EAS update "Cannot read properties of undefined (reading 'transformFile')" — FIXED (2026-10)

**Root cause (reproduced exactly):** the Emergent deploy builder installs WITHOUT devDependencies, and
`babel-plugin-module-resolver` (the plugin the production Babel branch uses to swap `@/src/simulation`
for `simulationAbsent`) was a devDependency → "Failed to construct transformer: Cannot find module
'babel-plugin-module-resolver'" → Metro's `Bundler._transformer` undefined → `reading 'transformFile'`.
It surfaced now because the babel change (preview only when the backend is a preview server) made the
deployed app correctly take the production branch for the first time; before, the deployment wrongly took
the preview branch, which loads no plugin (and carried the simulation).
**Fix:** moved it to `dependencies` (`yarn remove` + `yarn expo install babel-plugin-module-resolver@5.0.3`;
yarn.lock byte-identical). Guard test in `tests/previewIsolation.test.ts`. Verified with a copy of the
frontend installed `--production --frozen-lockfile`: android + ios `expo export` succeed and contain zero
simulation markers; hiding the plugin reproduces the exact deploy error.
**Deployment-agent findings deliberately NOT applied:** removing `eas.json` (store builds need its env),
committing `.env` files via `.gitignore` (would leak secrets to GitHub; deploys use the workspace
snapshot), removing the TTL/maintenance deletions (intentional 15-minute privacy retention), and
`ios.googleServicesFile` (iOS push wiring, unrelated to this failure).

## Production ≠ preview audit (owner: "no simulation code in a production build or deployment") (2026-10)

**Platform fact (Emergent support):** a deployment is a snapshot of the whole project; there is NO
documented way to exclude a folder, no backend pre-start hook, and no reliable preview-only env var.
So the backend simulator files cannot be kept out of the deployment — the guarantee is that production
never LOADS them: `server.py` imports the dispatch only behind `APOLLO_PREVIEW_SIMULATOR=on`, and
`tests/test_provider_environment_guard.py::test_production_startup_loads_no_simulation_module` imports
the whole app without the switch and asserts no `services.higgins.preview*` / `preview_analysis` module
is in memory.

**Frontend deployment:** `babel.config.js` now bundles the simulation only when the flag is `included`
AND `EXPO_PUBLIC_BACKEND_URL` is an `https://*.preview.emergentagent.com` server. The deployed app talks
to the production backend, so it can never carry the simulation even though it shares the one-slot
flag. `verify-no-simulation.mjs` production mode now reproduces a deployment (flag `included`, backend
`https://verify.emergent.host`) and finds zero simulation; `--preview` still finds 9/9 markers. EAS
store builds remain forced to production.

**Root cause of "preview fine, production broken":** the simulator took over at the TOP of
`provider.generate()`, skipping model capability, image authorisation, credential stripping, the privacy
boundary, token budget and timeouts. It now replaces ONLY the network call — every production check runs
first in preview too (`test_preview_runs_every_production_check_before_the_simulator`).

**Production-only bugs found by running every Gemini feature live (all FIXED, all live-verified):**
1. Investigations rejected (made-up citation ids) — per-call `response_schema(source_ids, capability_ids)`
   limits every id list to registered ids; Google Search grounding chunks are registered as case sources
   after a validated answer (`tools.grounding_sources`). Live: completion complete, DI `Live`.
2. `/message/extract` — `Purpose.EXTRACTION` didn't exist and `images=` isn't a gateway argument →
   now `[image part, prompt]` with `PAGE_SIGNAL_EXTRACTION`. Live: text + sender extracted.
3. `/vision/investigate` with an image → `privacy_violation` (VISION_INVESTIGATION not image-authorised);
   added to `_BINARY_AUTHORISED_PURPOSES`. Live: CommBank SMS recognised.
4. `/vision/investigate` text-only (image withheld on device) never opened a case (`UnboundLocalError`
   on `_redacted_image_bytes`) — initialised up front; failure now logs its traceback. Live: case opened.
5. Learn: waits for the device credential (`deviceId`) and shows the real reason on failure.
Live OK without changes: Higgins chat, page screenshot, page crawl, scam-alert analysis, provider health check.
Guard test: every `Purpose.X` named in code must exist.

**Other differences (not code):** ~20 settings have separate preview/production values (models match);
production holds 9 dead settings (APOLLO_ENV, APOLLO_PROVIDER_MODE, EXPO_PUSH_ENABLED,
EXPO_PUSH_ACCESS_TOKEN, EXPO_PROJECT_ID, EMERGENT_INTEGRATIONS_BASE_URL, EXPO_PUBLIC_PREVIEW_SAMPLES,
EXPO_PUBLIC_SECURECORE_MODE, EXPO_PUBLIC_SECURITY_MODE) — owner can delete them in the deployment panel;
production Learn has the 6 seed articles vs preview's 50 (feed-grown); preview is web, so native-only
features need a device build.

## Production was answering from the preview simulator — fixed with one explicit switch (2026-10)

**Proven on the live deployment** (`threat-patrol-1.emergent.host`): a Netflix scam text came back as the
simulator's canned "ING impersonation" answer and its DI record read `Simulated / Preview`; an email check
did the same. Cause: `server.py` installed the simulator whenever `services/higgins/preview/` could be
imported, on the assumption the folder is not deployed — Emergent deploys the whole project, so production
never called Gemini. The owner's empty DI tab on the deployed app was the same root cause.

**Fix.** `provider.preview_environment()` is true ONLY for `APOLLO_PREVIEW_SIMULATOR=on`; `server.py` installs the
dispatch only behind it, and `register_preview_handler()` refuses otherwise. Missing / empty / any other
value = live Gemini (never fake answers). Startup logs `provider_mode=…`; `/api/ai/capabilities` now
returns `providerMode` so production can be checked without a paid call. A NEW name was chosen on
purpose: the deployment's secrets still hold a stale `APOLLO_ENV` (very likely `preview`, copied when
`backend/.env` carried it), and redeploys don't overwrite existing deployment secrets — production has
never had `APOLLO_PREVIEW_SIMULATOR`, so it is guaranteed live. The preview needs
`APOLLO_PREVIEW_SIMULATOR=on` in its test slot only (owner skipped the card, so the preview currently
calls live Gemini too). `EXPO_PUBLIC_PREVIEW_BUILD` has only one slot, so it cannot differ per
environment; store builds are already forced to production by `babel.config.js`.
Requires a redeploy. Tests: `tests/test_provider_environment_guard.py` rewritten to the new contract.

**Hiding removed (owner's follow-up).** Simulated output is now LABELLED everywhere, never withheld:
`GET /investigations/{id}/di` returns every record in every environment (the `get_provider_mode() != "preview"`
filter is gone); `DiReport` dropped its `!record.simulated || simulation.included` filter and its label no
longer borrows the preview-only `simulation.tag` (empty in production) — it reads "SIMULATED — …" in every
build. The verdict itself: `GeminiResult.simulated` (set by the simulator) flows into
`ProviderResult.simulated` on the turn commit, so a simulated answer is no longer stored as a Gemini one;
`SimulatedAnswerNotice` (in `DiReport.tsx`, driven by the case's DI records via `useDiTransactions`) shows
"SIMULATED ANSWER — not from Gemini" above the tabs on both Ask Higgins (`InvestigationView`) and the Threat
Case screen; the PDF export prints the same statement. The build-time strip of preview SAMPLE content
(`simulationAbsent`) is deliberately kept — that is fake input, not hidden results.
Verified: backend 103 targeted tests, frontend 859/859, tsc + ESLint clean, all 8 CI steps, screenshot of
the notice + labelled DI record.

**Found while verifying — live Gemini answers are ALL rejected (`response_invalid`).** With Google Search
attached, Gemini cites sources as made-up ids ("1.1.4", "1.2.3"); the single-call coordinator (rewritten
2026-10-20) registers no sources before or after the call, so `validate()` rejects every finding with
"references unknown ids". Three live attempts on a preview case all failed this way. The simulator always
produced valid answers, which masked it. NOT FIXED — awaiting the owner's decision (production will hit this
as soon as it calls Gemini).

## Device Capabilities: desktop protections, grouped by category (2026-06)

**Catalogue wired to the engine.** `src/domain/deviceSecurityCatalogue.ts` (18 protections) +
`deviceProtectionTypes.ts` are resolved by `buildDeviceCapabilities` and read through
`deviceCapabilityState.toSecurityRead()` — Android posture snapshot, cross-platform device signals,
Private DNS status, and the desktop host's audit (`securityAdapter.getDeviceSecuritySignals()` when
`desktopHostKind()` answers). Desktop entries: Firewall, Antivirus (real-time protection), Disk
encryption (BitLocker / FileVault), System protection (SIP / Gatekeeper / tamper protection),
Windows & macOS screen lock, OS updates, Find My Device. Nothing is inferred: a read that doesn't
answer becomes `not_verifiable` ("Apollo can’t verify this") and still carries the recommended
configuration, the steps and a deep link; `protectionChecklistStore.ts` records the person's own
"I’ve checked this myself" with the date, always labelled as their statement, never Apollo's.

**Grouped by category.** `protectionsByArea()` orders rows into Calls and messages → Apps on this
device → Web and network → Who can get in → Updates and system → If it is lost or stolen;
`NativeProtectionTable` renders one table per category. The browser preview shows the WHOLE
catalogue with every row `not_readable_here` ("Can’t be read in this preview"), so the wording and
the categories can be reviewed without a build.

**Owner's follow-ups.** The "Apollo’s capabilities on this device" heading and its summary line were
removed, and the separate capability table went with them: every capability now carries an `area` and
sits inside the SAME category table as the device's own protections covering that ground
(`DeviceAreaTables`, one table per category, protections first then capabilities, every row a link
into Capability Details). `protectionsByArea` is generic over anything carrying an `area`, so one
grouping serves both. Category mapping: call history, messages, notification access and both
phone-own scam warnings → Calls and messages; app permissions, accessibility services, overlays,
installs, installed apps, management profile → Apps on this device; VPN status and app network
activity → Web and network. A new test asserts every capability belongs to a declared category and
that grouping neither loses nor duplicates a row.

**Share removed.** "Share this report" is gone from the Device Capabilities screen at the owner's
request, and with it the only caller of the PDF chain — `src/utils/shareDeviceCapabilityReport.ts`,
`src/domain/deviceCapabilityReport.ts` and `tests/deviceCapabilityReport.test.ts` were deleted rather
than left as unreachable code (recoverable from git if a share entry is wanted elsewhere).

**Verification.** `tests/deviceCapabilities.test.ts` 32/32, `tests/deviceSecurityCatalogue.test.ts`
19/19, `tsc --noEmit` clean, ESLint clean, preview
screenshotted through every category. Real states still need an Android/iOS (or desktop) build.


## Device Capabilities as a table + Capability Details screen + dead-link sweep (2026-06)

**Owner's three corrections, all implemented.**

**1. Plain-English statuses.** `CAPABILITY_CLASS_LABEL` is now exactly: `Available to Apollo` /
`Permission needed` / `Managed by your device` / `Not available to Apollo` / `Apollo couldn't check`,
plus a sixth honest state `Can't be read in this preview`. "Not on this device" is gone from every
capability status (a unit test asserts it can never come back). A new `hostIsDevice: false` input
makes every row `not_readable_here` when Apollo isn't on the phone — the browser preview used to
claim all 13 capabilities were "Not on this device", which read as nonsense; an unread capability is
now stated as unread, never as absent.

**2. No "verdict" anywhere user-facing.** The two rows are now `Your phone's own scam-call warning`
and `Your phone's own spam-text warning`; details, evidence lines and Higgins' snapshot lines say
"classification" or "finding". The provider notes that surface in the UI were rewritten from API
jargon into plain English in `GuardDogExpoModule.kt` (5 notes) and `nativeProtectionEvidence.ts`
(2 iOS notes) — e.g. "Samsung does not share Smart Call's scam classification with other apps, so
Apollo cannot use it as evidence."

**3. Table + Capability Details.** `src/components/device/CapabilityTable.tsx` renders two tables:
`NativeProtectionTable` (provider | status, opens in place — the provider owns everything on the row)
and `CapabilityTable` (capability | status, every row a LINK). A status legend under the table
explains only the statuses actually present. `app/device-protection.tsx` lost its five separate
class sections in favour of the one table, ordered usable → permission → device-managed → couldn't
check → unreadable here → absent (`allCapabilityRows`).

New screen `app/capability/[id].tsx` answers the three questions the owner asked for:
**What it does** → **How it helps protect you** → **Current status** (the exact class label + the
honest sentence + "Reported by <provider>") → **What you should do** → primary action
("Check Samsung Smart Call settings", "Open notification access", …) → "Ask Higgins about this"
(opens Higgins pre-filled with the capability and its status). Content comes from two new catalogue
fields, `what` and `benefit`, written for all 13 capabilities, and from the pure state-driven
`capabilityAdvice(row)`: nothing to do when Apollo already has it; "Allowing <x> helps Apollo …" when
permission is needed; "Keep <provider> switched on …" when a provider manages it; "Nothing to do,
<OS> keeps this private …" when the OS withholds it; "Apollo simply could not read this" after a
failed read. A provider-managed scam warning now also carries a settings action, so the Samsung case
reads exactly as specified.

**Shareable report** follows the screen: the per-class bullet lists became one
`Capability | Status | What this means` table.

**Follow-ups the owner asked for straight after.** The Device Capabilities screen lost the
"Check Device" button and the "Your recent checks" card, and gained a pinned **last device check**
strip under the title — `Last device check — today, 1:05 pm` + the outcome chip (`resultChip`) + the
stored summary, or "not run yet" when the history is genuinely empty (the duplicate clock line in the
device card was removed). Home's **Device card now carries a capability health score**, colour coded
red / amber / green: new pure `capabilityHealth(view, hasNativeHost)` scores ONLY what the person can
change — granted vs awaiting-permission vs unreadable — and deliberately excludes capabilities the OS
or a provider keeps to itself, so an iPhone is never marked down for being an iPhone. 100% is green,
≥60% amber, below that red, and no native host means **no score at all** ("Not read", grey) rather
than a green light. The card line reads e.g. "6 of 9 ready. 3 need your permission. The rest is in
place." 4 new tests cover the bands, the exclusion rule and the no-score case.

**Dead-link sweep** (the owner's earlier ask, done properly this time). Checked every route literal
in `app/` and `src/` against the route files (44 targets, all exist); every `Pressable`/
`TouchableOpacity` opening tag for a missing `onPress` (0 found); every `visible={…}` sheet for a
setter that never opens it; every empty handler; every `Linking.openURL` target. Found and removed:
- `app/app-check.tsx` — a "Technical details" Sheet that nothing could open (`setTech(true)` never
  existed after the CheckResultScreen migration), plus dead `sdkVisible` state and the capability
  read effect that only fed it, and dead `reportState` / `showFull`.
- `app/account.tsx` — dead `actionGuidance`, `reportState`, `tech`.
- `app/account-monitor.tsx` — `previousScan`, written on every reload and read by nothing.
The two remaining `onPress={() => undefined}` are deliberate backdrop/tap-swallowers.

**Verification.** `tests/deviceCapabilities.test.ts` 26/26 (new: plain-English labels with
"Not on this device" banned and "verdict" banned, preview reports unreadable-not-absent, every
capability can answer the three questions, advice is state-driven) and
`deviceCapabilityReport.test.ts` 8/8. Full frontend suite 757 tests / 732 pass / **the same 25
legacy failures** as the baseline (was 742/717/25, so +15 new passing, zero regressions).
`backend/tests/test_higgins_device_snapshot.py` 3/3 after updating the prompt wording. `tsc --noEmit`
clean, ESLint clean on every file touched. Verified in the preview: the preview state ("Can't be read
in this preview" on all 13), the Android branch by temporarily pinning the view inputs (Samsung Smart
Call "Active on your device", Google Messages "Installed, not active", 6 available / 3 permission /
4 device-managed), the Samsung Smart Call details screen (exactly the owner's example wording), and
"Ask Higgins about this" landing in Higgins with the question pre-filled. **Real-device confirmation
still needs an Android/iOS build.**


## Device Capabilities — real reads, five honest states, native evidence wired in (2026-06)

**Objective.** Apollo must understand (1) what protection the device already provides, (2) what Apollo
is actually allowed to use, and (3) how to leverage a permitted native classification as evidence and as
a trigger for Apollo's EXISTING investigation — with attribution to the OS/OEM preserved. The Device area
shows the person: what my device protects → what Apollo can use → what Apollo cannot access → what extra
native protection I can enable, plus Device Check and previous check outcomes.

**What was wrong before this change (all verified, not assumed).**
- `app/device-protection.tsx` read `callProt.provider / .summary / .enabled` from
  `summariseCallProtection()`, which returns `hasNativeProtection / activeProviders / detail`. Eight
  TypeScript errors; the guard was always false, so **no Samsung / Google / carrier protection ever
  rendered**. The only rows shown were two hardcoded ones.
- Those hardcoded rows asserted "Google Play Protect — on" and "Lockdown Mode — off". Apollo cannot read
  either state. Truth-of-state violation.
- "Apollo can use" was `available: Platform.OS === "android"` — a platform guess. It ignored
  `AppDeviceSdk.getAppDeviceCapabilities()` (which already returns `supported / permission_required /
  unsupported`). Someone who had denied Call Log still saw "Call history ✓ Apollo can use".
- "Checked today / x days ago" read `apollo.lastDeviceCheckAt`, a key nothing in the codebase writes —
  so it always said "Not checked yet".
- `buildNativeClassificationEvidence` had **zero callers**; nothing called the classification intake
  anywhere. The native-evidence → investigation path existed on paper only.
- "What additional native protection can I enable" did not exist at all.
- `detectNativeProtection()` swallowed Android read failures into `EMPTY_CAPABILITIES`, turning a broken
  read into "your device protects nothing".

**New pure engine `src/domain/deviceCapabilities.ts`.** `buildDeviceCapabilities({platform, caps, native})`
resolves a 13-entry catalogue into exactly the five declared classes — `apollo_can_use`,
`permission_required`, `not_exposed`, `unavailable` — plus an honest `unknown` for a failed read, which is
**never** upgraded. Native protections managed by the device are tracked separately as
`NativeProtectionRow` (`active` / `installed_not_default` / `absent` / `unknown`) so the provider, not
Apollo, owns the row. `native_call_verdict` / `native_message_verdict` resolve from
`classificationAccessible`: shared → usable evidence attributed to the provider; present but not shared →
`not_exposed` with "Apollo will not guess it from blocked calls or unknown numbers"; nothing recognised →
`unavailable`. `caps: null` or `native: null` ⇒ `unknown`, never "clear".

**Recommendations Apollo cannot verify** use the owner's exact wording: title → `Recommended protection`
→ "Apollo can't verify whether this is currently enabled." → "Higgins recommends checking that Play
Protect is turned on." → "Check Play Protect →", then a sheet with WHY it matters and the exact numbered
setting path. Android: Play Protect, caller ID & spam (Samsung vs Google steps chosen from the real
default handler), Messages spam protection. iOS: Silence Unknown Callers, Filter Unknown Senders, plus
Lockdown Mode as `Optional protection` — "Higgins only recommends this if you believe you are being
personally targeted." Any provider that is installed but not the active handler gets a generated
"choose your phone/messaging app" recommendation.

**Screen rebuild `app/device-protection.tsx`.** Sections in the person's order: This device (+ last check
from the real check-history store) → Check Device → What your device protects → What Apollo can use →
Needs your permission → What Apollo cannot access → Apollo couldn't tell (only when a read genuinely
failed) → More protection you can turn on → Not on this device (compacted) → previous check history.
Reads are real: `getAppDeviceCapabilities()` + `detectNativeProtection()` via `Promise.allSettled`, each
failure landing as `null`. No native host (browser preview) is reported as exactly that, distinct from a
failed read.

**Native classification wired into the existing investigation** (`src/domain/nativeClassification.ts` +
`ApolloContext.checkCall` / `checkMessage`). `readNativeClassification()` asks the intake; when a provider
ever shares a verdict it becomes (a) the FIRST `why[]` line, worded "…This is <provider>'s finding,
reported by Apollo — not an Apollo detection", (b) an original-source field "<provider> said:
<classification> (<confidence> confidence)", (c) `evidence_provenance: "native_protection"` with the
provider on `source_metadata.provider` / `provider_classification` / `provider_confidence`, and (d) a
trigger that opens Apollo's existing Magnum DI investigation even when Triage found nothing. The
investigation itself is unchanged. Attribution is carried through to the case screen: `caseSources`
("<provider> classified this as … That is <provider>'s finding — Apollo investigated it from there"),
`threatCase.sourceLabel`, and the `patrol/[id]` provenance line. Today no provider exposes a verdict, so
the path is inert by design — and tested so it cannot silently start claiming one.

**Android package visibility (needs a native build to confirm).** `com.google.android.dialer`,
`com.samsung.android.dialer`, `com.samsung.android.smartcallprovider`, `com.hiya.star`,
`com.tmobile.scamshield`, `com.att.callprotect`, `com.verizon.callfilter` added to
`AppDeviceCatalog.NATIVE_PROTECTION` and the `<queries>` block (44 ≡ 44, parity asserted by
`AppDeviceCatalogTest`). Without them Android 11+ returns NameNotFound for non-launchable providers and
Apollo reported "not installed" when the honest answer was "Android will not say". The manifest/catalog
comments no longer contain the literal `QUERY_ALL_PACKAGES`, which was itself failing that JUnit guard.

**Other real bugs found and fixed on the way.**
- `src/domain/privacy.ts`: `push_preferences` and `device_posture` were missing from `EgressEndpoint` and
  `ALLOWED_KEYS`, so `enforceEgress` threw on `ALLOWED_KEYS[endpoint].has(...)`. Notification-category
  sync and every Device Posture Monitor report to `/api/devices/posture` were failing silently inside
  their `try/catch`. Both endpoints declared with explicit allow-lists.
- `src/domain/deviceReview.ts`: the >5-month security-patch branch returned `{detail, recommendation}`
  instead of `{risk, remediation, verifiedBy}`, so a badly out-of-date device showed "Action required"
  with no risk text and no instruction. Now uses the `action()` builder.
- `src/security/nativeBridge.ts`: `getNativeProtectionCapabilities` and `getDevicePostureSnapshot` were
  missing from `ApolloSecurityNativeModule`, so neither bridge call was type-checked at all.
- `app/device.tsx`: check history was recorded on EVERY refresh, including the automatic one on open, so
  "Checked today" could mean "you opened the screen". History now records the same user-initiated checks
  Patrol does, keyed on the same `briefingRun`.
- `app/alerts.tsx`: dead `status !== "duplicate"` filter ("duplicate" is not an `EventStatus`).

**Verification.** `tests/deviceCapabilities.test.ts` 19/19 (five classes exact, failed read never
upgraded, Apple/Android attribution verbatim, provider verdict shared vs withheld vs absent, no
recommendation ever claims a setting is on, Samsung-vs-Google step selection, Lockdown optional,
attribution + provenance + investigation trigger). Full frontend suite 742 tests / 717 pass / 25 fail —
**the same 25 that fail on a clean stash**, i.e. zero regressions, +19 new passing. `tsc --noEmit` is now
fully CLEAN (it had 6 errors before, 8 of them in the broken Device screen). ESLint clean on every file
touched. Web preview verified (honest no-native-host copy) and the Android branch verified by temporarily
pinning the view inputs — Samsung Smart Call "Active on your device", Google Messages "Installed, not
active", 6/13 usable, 3 permission-gated, 4 withheld by Android, both scam verdicts attributed to their
provider, and the Play Protect sheet. **Real-device confirmation still requires an Android build.**

**Known, not fixed (out of the approved scope).** `app/device.tsx`'s "Add my report to Higgins" button
writes `submission` state that nothing reads — the self-report switches already feed `assessDevice()`
live, so the button is redundant rather than lossy.

## Investigations can complete again + hero artwork + one way out of every screen (2026-06)

**P0 FIXED — every investigation was failing `response_invalid`.** Not a Gemini fault and not a preview
fault: `services/higgins/evidence.py::model_parts` recorded an examination mark ONLY for
character-counted evidence, so the `URL from message` item that every message/email check registers
(`ingest_url` → `unit: "items"`) stayed `not_started` for ever. The coordinator then reported it as
unexamined material content and Apollo's own validator rejected any answer that said
`completion: "complete"` — the turn failed with `response_invalid` no matter what came back. Item-counted
evidence is now marked examined when it is sent (the whole item is in the request, so sending it IS the
examination). Regression test `backend/tests/test_url_evidence_examined.py` (2 tests, proven to fail
before the fix and pass after); `test_gemini_request_shape + test_magnum_di_acceptance +
test_investigation_engine` 44 passed, `test_recovery_fencing + test_enforcement_evidence_gate +
test_p0_evidence_receipt_indexes` 58 passed.

**Scam Alerts cards restyled** (`app/higgins/scams.tsx`, owner's wording): title now sits ABOVE the pills,
the severity/region pills are 35% smaller (new opt-in `compact` variant on the shared `Pill` — standard
pills elsewhere are untouched), and the 44pt severity badge is halved to 22pt and moved to the card's
top right beside the title. Same treatment on the "Sent by your family" rows.

**Home hero artwork** (`app/(tabs)/home.tsx`). The 3:1 landscape was `contentFit="cover"` on a card whose
height is driven by text, so ~45% of the picture was cropped away; `contain` then letterboxed it with a
hard edge. It is now a full-width band pinned to the bottom of the card, sized by its OWN proportions
(`aspectRatio: 2000/667`), so every device width shows the whole picture undistorted and uncropped
however tall the card grows. A vertical wash blends the top of the band into the card colour and the
existing horizontal wash (softened) keeps the text readable.

**One way out of every non-tab screen** (owner: back chevron or X only — no "Done"/"Close"/"Back" buttons).
Audited all 54 non-tab routes:
- `app/(tabs)/check-it.tsx` had NO dismiss at all although it is always pushed (Settings → Run a manual
  check, Support, Higgins) — added a back chevron beside the title.
- `app/higgins/scam/[id].tsx` used an arrow — now a chevron.
- Removed screen-level text dismissals: `recheck-close`, `patrol-history-close`,
  `share-load-error-dismiss`, and the privacy statement's ghost "Back" (replaced by a header back chevron
  while setup is still running; the X stays once setup is done).
- The two full-screen modals that read as screens now use an X: the evidence full-screen viewer
  ("Close" text) and `EvidencePopup` ("Done" text).
- Left alone deliberately: Done/Close/Cancel inside bottom sheets and confirm dialogs (overlays, not
  screens), the in-screen chevron on `message-picker` (returns to the thread list), and the setup wizard
  (`onboarding`, `setup-gates`, `first-check`) which is entered with `router.replace` and has no history.

Verified in the preview: Privacy statement (chevron, no Back button), Check (chevron, returns Home),
Scam Alerts list, Scam Alert detail, Threat Case → Evidence. tsc + ESLint clean.



## Evidence follow-ups: threat cases, chat capture, pack layout, side-by-side (2026-06)

All four of the owner's picks, built on the `EvidenceArtefactCard` from the restyle.

**1. Threat cases look the same.** `app/patrol/[id].tsx` now leads both its Evidence branches with the
same artefact card and no longer uses `ImageEvidenceCompare`/`OriginalSourceView` (both files
deleted — nothing else imported them). The card reports back through `onAvailable`, so the older
field-by-field views only render when the exact original is NOT on the phone: no case shows the same
material twice, and nothing is lost when it isn't there ("What Apollo found", "Observed",
provenance and the Magnum DI fallback all stay). The card now takes `caseKeys: (string|null)[]` —
a threat case is filed under its event id *and* its investigation id, and the original may be under
either.

**2. Chat capture.** The Higgins artefact sheet asks "Which app did it arrive in? (optional)" for
messages and calls, with chips for SMS, WhatsApp, Messenger, iMessage, Telegram and Instagram.
The choice is recorded as a `Source app:` header line on the captured text — the same form
`describeArtefact` already reads — so a pasted WhatsApp message lands in the chat layout. Chips stay
in step with a sample that declares its own app (`SimulatedText.app`, plus a WhatsApp family
impersonation sample). Verified end to end: paste → tap WhatsApp → Evidence shows "WhatsApp chat".

**3. Evidence pack reads like the screen.** The artefact HTML moved to a pure, testable
`src/domain/evidencePackHtml.ts` (`evidencePack.ts` keeps only printing/sharing) and now renders the
same layouts: email card with sender, subject, body and attachments; message/chat as a bubble under
its sender; post with page and platform; screenshot deferring to the reproduced images. Plus
"Headers as captured", "Links in this material", and "Copy sent for investigation" — included **only**
when the redaction actually changed something. Captured text is escaped, so no pasted markup can
reach the PDF. 6 tests; rendered and eyeballed at A4 width.

**4. Side by side.** Screenshot cases get a third segment next to Original and Redacted that shows
both pictures with captions ("Original on this phone" / "Copy sent for investigation"), each tappable
for full screen. On the sign-in-code sample the blacked-out box is obvious at a glance. The segment
only appears where there are two versions of a picture to compare. Screenshots also now render at
their own proportions (`Image.getSize`) instead of a fixed 3:4 box.

**Verified in the preview**: threat-case Evidence (email check → Threats → case → Evidence) shows the
email layout; the seeded device case degrades to the observation view; chat chips produce a chat
layout; side-by-side renders both images. 49/49 across the evidence, preview and image-privacy
suites; tsc + ESLint clean.


## Evidence tab restyled: the artefact, as it arrived (2026-06)

**What the owner asked for.** Restyle the case Evidence tab to the attached design — separate screens
per evidence type, "for a type with a specific design use the message type as the default", and
"try to cater for the specific evidence type". Owner's three calls: **(1a)** omit anything Apollo
never captured, **(2a)** build all five layouts with calls/files/apps/links falling back to the
message layout, **(3a)** keep "Share evidence pack" and "Remove original" under Source details.

**Structure** (`src/components/evidence/EvidenceArtefactCard.tsx`, replaces the old
`OriginalSourceView` + `ImageEvidenceCompare` pair in `InvestigationView`'s Evidence tab):
icon + "Original Source / <type> · Preserved on this device · Unaltered" + (i) → **Original |
Redacted** segmented toggle + (i) → email-only **Email | Headers | Details** tabs → the artefact in
its own "as received" frame → actions (View full screen / Copy text / Open in browser) →
**Source details** (type, platform, captured, stored, links, what was blacked out, Share pack,
Remove original) → an info banner naming exactly what is on screen.

**Five layouts** (`src/components/evidence/ArtefactLayouts.tsx`):
- **email** — sender row with initial avatar, To, time, subject, body with live links, attachments
- **screenshot** — the image at its real proportions (read with `Image.getSize`), extra shots as a
  thumbnail strip, tap for full screen
- **message** (the default) — sender strip, date chip, incoming bubble, links tappable; the strip is
  dropped when there is nobody to attribute (a link, a file), and device/network captures render
  their recorded JSON in the bubble
- **chat** — as message, headed by the app the capture names
- **post** — page/handle, platform, post text, link and media

**The toggle now means something.** Original = what was captured on this phone. Redacted = the exact
copy that left it: text through `redactInvestigationSecrets`, URLs through `purposeLimitedUrl`, and
for screenshots the real `sentUri`. On the new sign-in-code sample the toggle visibly flips between
the readable code and the blacked-out copy. When nothing needed hiding the banner says so rather
than implying a redaction happened.

**Nothing is reconstructed** (`src/domain/evidencePresentation.ts`, pure + 14 tests). The layout and
every header fact come from saved capture fields, or from header lines the captured text itself
carries ("From:", "Subject:", "Source app: WhatsApp", "Page: …", "From AusPost:"). Saved fields beat
parsed ones. A scam that merely *mentions* WhatsApp in its body is still a message — the platform
must be named by the capture, not the content. An empty capture produces empty facts, and
"last seen", reaction counts and profile photos are simply absent.

**Supporting changes.** `ask.tsx` now records `{kind:"screenshot"}` for image-only submissions (an
image-only case had no original record at all); the card also falls back to the image evidence
record so older cases still render. `ApolloContext` now carries attachment names and the mailbox
provider into the captured fields. `SimulatedText` gained an optional `app`, with a WhatsApp
impersonation sample so the chat layout is reachable in the preview. The server-side duplicate of
the same original is no longer listed under the local card (the full chain is still one tap away).

**Verified in the preview**: message, email (+ Headers tab), screenshot (Original vs blacked-out
Redacted), WhatsApp chat and a pasted Facebook post all render in their own layout;
`evidencePresentation.test.ts` 14/14, image/preview suites 43/43 together, tsc + ESLint clean.
`app/patrol/[id].tsx` still uses the older pair — adopting this card there is the obvious next step.


## Preview-only simulation of the image privacy screening (2026-06)

**Why.** Apollo screens every image on the device before it is sent: on-device text recognition
(ML Kit / Apple Vision via `expo-ocr-kit`) reads the text, credentials are blacked out on the copy
that leaves the phone, and anything that can't be verified is withheld. No web preview can run that
native module, so `screenImage()` returned `ocr_unavailable` and EVERY image dead-ended at
"Image not sent" — including Apollo's own sample screenshots (owner's screenshot of the Higgins "+"
sheet).

**The external read — and only that — is replaced.** New `src/preview/simulatedScreening.ts`
(gated on `PREVIEW_SAMPLES_ENABLED`, so it is dead in every shipped build) is consulted by
`imagePrivacy.screenImageInner` ONLY after the real `extractTextLocally()` has already failed. What
it returns goes through the real `classifyRegions` → real credential detection → real redaction →
real fail-closed rules, unchanged:
- **A preview sample screenshot** → the text those pixels actually show, with its real box.
  `scripts/make_preview_screenshots.py` now records every text block it draws and generates
  `src/preview/simulatedScreenshotText.ts`, so the "read" can never disagree with the picture.
- **Any other image** (the person's own photo/gallery/file pick) → **no text at all**, because
  nothing read it. Apollo never borrows another sample's text, and the popup says plainly that
  nothing was checked.

**The popup carries the label** (owner's choice: popup only). `ScreeningResult.previewNotice` →
`ImageUploadPrep` → `ImageUploadWarning` renders a dashed-gold **PREVIEW ONLY** card above the
normal warning. Two wordings: "…Apollo screened the text this sample image is known to contain;
nothing was read from the picture itself" (sample) / "…no text was read from this image. Nothing in
it has been checked for passwords, PINs or codes" (own image). `screeningSummary` says
"Text recognition simulated in this preview." and reports "no text was read, so nothing in the
image was checked" instead of "no sensitive content detected" when nothing was read.

**Two new samples, two real outcomes** (owner asked for both):
- `sim-shot-sms-code` — a six-digit sign-in code in its own bubble → detected as a credential with a
  usable box → blacked out on the copy → **sent**, real Triage/Magnum DI ran on it.
- `sim-shot-email-password` — a temporary password the recogniser reads but cannot place → **refused**
  ("Image not sent", Crop offered).

**Genuine production fix found on the way.** `ImageUploadPrep` blacked out credentials by drawing a
box at the region's frame; a credential region with a zero-size/absent frame produced a zero-area
box, so the password would have been sent plainly visible. It now fails closed on any credential
without a usable frame.

**Verified in the preview** (web, three full runs): sample-with-code → PREVIEW ONLY notice → Continue
→ investigation completed; sample-with-unplaceable-password → "Image not sent" + the can't-place
reason; own image uploaded through the file picker → "no text was read from this image" → sent as a
metadata-stripped copy. `tests/previewScreening.test.ts` 5/5; `imagePrivacy.test.ts` 20/20,
`test_anti_drift.mjs` 127/127, `test_screenshot_privacy.mjs` 30/30, `previewGating.test.ts` 4/4;
tsc + ESLint clean.

**Note (pre-existing, not changed):** the backend's `core/redaction.py` `_SECRET` regex treats any
word following "code" as a secret, so the sample question "Is this code message real?" came back as
"Is this code [redacted] real?". The sample's question was reworded; the regex was left alone.


## Remote alerts moved to Apollo's managed push relay (2026-06)

**Why.** Two faults, both proven from the real delivery history. (1) `subtitle: null` made the provider reject whole
batches with HTTP 400 — see the entry below. (2) Every registration in `push_registrations` carried Expo project
`47cd97c4-…` (the project Emergent's build pipeline uses) while the backend was configured to send from `b2eb337d-…`
(the owner's own project in `app.config.js`): registrations from a real build were rejected 422, and the older tokens all
came back `DeviceNotRegistered`. Owner's decision: move to the managed relay rather than reconcile Expo projects.

**Backend (`routers/push.py`).** Sends now go to `https://integrations.emergentagent.com` with `X-Push-Key:
$EMERGENT_PUSH_KEY`: `POST /api/v1/push/users/register` on registration and `POST /api/v1/push/trigger` to send.
`EXPO_PUSH_ENABLED` / `EXPO_PUSH_ACCESS_TOKEN` / `EXPO_PROJECT_ID` are gone from `.env` and the code;
`EMERGENT_PUSH_KEY=placeholder` is in `.env` and the build pipeline fills in the real value at publish (never edit it).
`push_configured()` is false while the key is still the placeholder, so `/register-push` and `/push/test` fail closed
with a typed 503 that says the alert channel is switched on at publish time — no silent pretend-success.
- **Device tokens are no longer stored.** `register_push` forwards the native FCM/APNs token and keeps only
  `{device_id, registration_id, platform, provider, registered_at}`, `$unset`ting any legacy `token`/`project_id`.
  `scripts/purge_expo_push_registrations.py` removed the 19 stale Expo rows (those installations re-register on next
  launch, which the app does on every open).
- **The durable delivery ledger is unchanged** (`push_deliveries`: one row per owner/event/channel/recipient, payload
  digest, attempt history, bounded retries). Relay 202 → `provider_accepted` (a hand-off, never a sighting). Billing
  refusals (`insufficient_credits`, `integration_disabled`, `daily_limit_reached`) are recorded as the failure reason
  and never retried in a loop; 401 → `push_key_invalid`; timeout → `outcome_unknown`. `409
  idempotency_key_in_progress` is retried with the same key (3× / 3s) because it is not a failure.
- Expo receipts no longer exist, so `reconcile_receipts` and its 5-minute loop in `server.py` are deleted;
  `device_observed` stays in the state union for historical rows only.

**Frontend.** `registerRemotePush()` uses `getDevicePushTokenAsync()` (native token) and posts `{platform,
device_token}` — no `projectId`, no Expo token. The egress allow-list for `push_register` shrank to those two fields.
`app/_layout.tsx` already satisfies the rest of the contract (module-scope `setNotificationHandler` + channels, warm
`addNotificationResponseReceivedListener`, cold-start `getLastNotificationResponseAsync`, listener cleanup).
`expo-notifications` bumped to 57.0.23. Android `googleServicesFile` (Firebase `apollo-243ad`, package
`app.apollo.hwg`) and the `expo-notifications` plugin with both alert sounds were already wired in `app.config.js`.
Deliberate deviation from the playbook: no weekly "notifications are off" nudge dialog — the owner removed inline
notification nudges in favour of the alert bell's warning dot plus Settings → Notification check.

**Tests.** `tests/test_push_message_shape.py` now pins the relay payload (`_relay_data`): subtext/action_url/sound
omitted when blank, never null, channel and sound per alert type. `tests/test_iter6_push.py` asserts the placeholder-key
503 instead of the old Expo-token rules. `test_iter6_push + test_iter33_api_regression + test_device_auth` = 43 passed;
`test_family.py + test_family_nudge.py + test_family_weekly_push.py` = 17 passed, 6 skipped.

**Still only provable on a real build.** Expo Go and the web preview cannot obtain a native push token (the Notification
check screen says exactly that), and the managed key only exists after Publish → Deploy → Generate build, where the
build UI also asks for a Google service account JSON (Android) and an APNs `.p8` key (iOS).


## Header truncation, production-shaped entry popup, and the push notification investigation (2026-06)

**Headers never cut their own words.** The Higgins header is now a column: avatar + "Higgins" + the three iconbuttons (clear chat / alerts bell / about) on one row, and the subtitle on its own full-width line below — the icons
can no longer squeeze it (it used to render "Apollo's t…"). The one-line clamps were also removed from every header
title that sits beside icons: `CheckToolHeader`, `app/gate-details.tsx`, `app/patrol/[id].tsx` (`tc-case-id`),
`src/components/EvidencePopup.tsx`, `app/message-picker.tsx`; `ScreenHeader`'s title gained `flexShrink: 1` so a long
root title wraps instead of overflowing.

**The check entry popup looks exactly like production.** `HigginsArtifactInput` no longer renders the preview sample
lists inside the entry sheet. The popup is just the production fields (Content / URL + optional question + "Ask Higgins
to investigate"); a "Use a preview sample" ghost button opens a second "Preview samples" sheet, and choosing a sample
fills the fields and returns to the popup. The button only exists when `PREVIEW_SAMPLES_ENABLED` is true, so a shipped
build has no sample affordance at all.

**Verified in preview (specific findings regression, owner item 1a):** simulated bank-impersonation email → real Triage
escalation → Magnum DI → case `TC-2026-78DBB` Overview shows the actual findings, not generic text: "The link goes to
commbank-alerts.co", "the sender address is security@commbank-alerts.co — the domain … is not an official address",
plus a WHAT ISN'T SETTLED section. `investigationCaseUpdate.ts` is doing its job.

**Push notifications — two real faults found (owner item 2b).**
1. **FIXED (server, confirmed live):** `routers/push.py::_message` always sent `"subtitle": data.get("subtext")`, so any
   sender without a subtext sent `subtitle: null`. Expo validates the whole batch and answers **HTTP 400
   VALIDATION_ERROR** (`"0.subtitle": Expected string, received null`) — which is exactly the `provider_http_400` state on
   every family weekly/nudge delivery in `push_deliveries`. `subtitle` is now only included when it is a non-empty
   string. Verified against the live Expo API with a non-existent token: all three real payload shapes now return HTTP
   200 with a per-message ticket. Unit test: `backend/tests/test_push_message_shape.py` (4 pass).
2. **OPEN (needs the owner's decision):** every stored push registration carries Expo project
   `47cd97c4-e5a6-41fa-9fde-257a5de031af` (the project the installed builds were made under), while the backend's
   `EXPO_PROJECT_ID` is the canonical `b2eb337d-2687-46bf-b1cc-292d30c0b601` from `app.config.js`. So today a real build
   is REJECTED at `/register-push` with 422, and the older tokens all came back `DeviceNotRegistered` from Expo. Remote
   alerts (app closed) cannot work until the build and the server agree on one Expo project, or push moves to the
   Emergent-managed path (`google-services.json` for `app.apollo.hwg` / Firebase `apollo-243ad` is already in the repo).

**New screen `app/notification-check.tsx`** (Settings → Alerts & voice → "Notification check", modal): shows the three
separate states from their real sources — OS permission, the Android "Apollo alerts" category, and the server's
registration (`GET /push/registration`) — plus the last recorded failure (`apollo.notif.lastFailure`). Two honest tests:
"Send a test alert to this phone" (real local schedule) and "Send a test alert from Apollo's servers" (registers a fresh
token, then `POST /push/test`), each reporting exactly what the device or the relay answered — never claiming delivery.
`/push/test` accepts an empty body and its 409 carries `detail` so the app can show the reason.

**Independent disclosures on a check result.** On `CheckResultScreen` "What Apollo checked" and "Full investigation
details" shared one `fullOpen` state, so opening either expanded both. "What Apollo checked" now has its own
`checkedOpen` state.



## Preview Gemini simulator + DI tab (2026-06)

**Simulator at the boundary only.** New provider mode `APOLLO_PROVIDER_MODE=simulated` (set in the preview backend .env;
production stays `live`). `services/higgins/preview_simulator.py` builds nothing of its own: `provider.generate()` runs the real
request composition (real Magnum DI/Higgins system prompt, real evidence brief, real privacy screening + redaction, real
post-redaction attachment parts), then the EXTERNAL CALL ONLY is replaced. It always succeeds and returns one fixed V1 response
(`FIXED_PREVIEW_RESPONSE`, the owner's text verbatim) — delivered in the shape the caller asked for, so the REAL validator,
the REAL commit and the REAL Higgins workflow process it unchanged (verified: `validate()` returns no errors). Usage is recorded
with `extra.simulated=True`. Magnum DI, evidence handling, privacy/redaction, Higgins, findings, state and reporting are untouched.

**DI transaction record (production feature too).** `services/higgins/di_record.py` persists one `di_transactions` document per
boundary call — live and simulated: the actual system prompt, the actual investigation prompt/context, each attachment
(MIME, size, image dimensions read from the bytes, privacy-screening and redaction status, transmitted post-redaction form —
never an original), the complete provider response, and processing stats (tokens with estimated/simulated provenance, cache
status, attachment count, payload size, measured duration, Gemini calls, retries, estimated cost). Served by
`GET /api/investigations/{case_id}/di`, authorised against the case document directly so an expired case can still show how it
was processed. `provider.register_di_owner()` scopes records to the owning device.

**DI tab.** `src/components/DiReport.tsx` renders Investigation / Sent to Gemini / Gemini (or Simulator) response / Processing,
with the dashed "SIMULATED — No Gemini API call was made" banner, "Simulated"/"Estimated"/"Measured" labels on every number, and
cost never presented as Gemini billing in preview. Added as the fourth tab on BOTH the Threat Case screen (`app/patrol/[id].tsx`)
and the Investigation Report (`src/components/InvestigationView.tsx`): Overview | Evidence | History | DI. Evidence is unchanged —
it remains the original evidentiary source; DI is only Magnum DI's processing record.

**Verified end-to-end in preview:** simulated bank-impersonation email → real Triage escalation → Magnum DI → simulator →
validated response → Higgins narrative on Overview → DI tab showing Preview/Simulated, model `gemini-3.8-flash`, status success,
the real prompts, the response and the processing statistics.

## Preview simulated selections: messages, calls, apps, files (2026-06)

Preview has no SMS list, no call log, no installed-app list and nothing in the file picker, so those checks couldn't be
exercised. `src/preview/simulatedItems.ts` now supplies INPUT ONLY — `SIMULATED_TEXTS` (6), `SIMULATED_CALLS` (5),
`SIMULATED_APPS` (4), `SIMULATED_FILES` (4) — each item carrying a `probes` note describing what it CONTAINS, never a verdict.
`src/components/SimulatedPicker.tsx` renders them identically on every screen (dashed gold border, "PREVIEW ONLY" tag, explicit
"this is not your real list / nothing is read from this device" note) and only when `PREVIEW_SIMULATION`
(`Platform.OS === "web" || IS_PREVIEW_HARNESS`).

Wiring — all through the screens' existing real flows, no preview path, no mock Triage/Magnum DI, no predetermined verdicts:
- `app/text-guard.tsx`: `runWith({sender,text})` calls the same `checkMessage`.
- `app/call-guard.tsx`: `runInvestigation(pickedNumber?)` — same reputation check then real Magnum DI where it escalates
  (the `number` state was renamed `numberState` so the picked value can shadow it inside the function).
- `app/app-check.tsx`: fills the same answers a person gives (name, developer, package, source, purpose, permissions) and an
  effect then runs the ordinary `run()`.
- `app/file.tsx`: `checkSimulatedFile` writes the sample to a REAL temporary file (Blob URL on web, `Paths.cache` via
  expo-file-system on native) and calls the same `analyseAsset`, so Apollo's own inspection reads real bytes.

Verified in preview: text sample ran the real message check; app sample escalated and the real Magnum DI reported honestly that
its analysis service isn't configured here (no Gemini key in this environment); file sample was genuinely inspected
("Filename: Invoice_4471.pdf.exe, Size: 48 bytes"); call and text cards render and feed their real checks.

## Preview email inbox simulation (2026-06)

**Purpose: input only.** `src/preview/simulatedInbox.ts` holds 10 sample emails (`SIMULATED_EMAILS`) with `from`, `subject`,
`body` and a `probes` note describing WHAT EACH CONTAINS — never a verdict. Coverage: ordinary receipt (no links/requests),
normal newsletter with a well-known domain, bank impersonation with lookalike domain + deadline + credential request,
government/ATO impersonation with arrest threat + voucher payment + TFN/safe-account request, CEO gift-card request from free
webmail, delivery pretext asking for the SMS one-time code, tech-support remote-access/installer, crypto extortion,
advance-fee inheritance, and a plain booking email whose only link is an unfamiliar domain reputation services may not know.

**No separate path.** `app/email.tsx` `run()` now takes an optional `source` ({from, subject, raw}); selecting a simulated email
calls that same `run()` — same `analyseEmail`, same `POST /message/analyse` (real deterministic Triage, and real Magnum DI only
where Triage escalates), same `evaluateLinkGuardFindings`, same `upsertEvent`. No mock Triage, no mock Magnum DI, no
predetermined verdict, no alternative engine. Checks recorded from it are tagged `account: "Simulated inbox (preview)"`.

**Clearly marked.** The card (`email-simulated-inbox`) has a dashed gold border, the heading "Simulated inbox" with a
"PREVIEW ONLY" tag, and states it is not a connected mailbox, that no real email is read, and that Apollo decides each outcome
himself. It renders only where a real mailbox isn't reachable (`Platform.OS === "web" || isMock`) and never when Gmail is connected.

**Verified in preview:** benign sample → "Ordinary email… Nothing to do" (deterministic, no AI); bank-impersonation sample →
Triage escalated and the real Magnum DI ran, reporting honestly that its analysis service isn't configured in this environment
(no Gemini key here) rather than inventing a result.

## Home polish round (2026-06)

- "Important for you" card: the summary sentence was removed (the title is descriptive enough) and `threatReason()` deleted
  with it; spacing tightened so the title sits straight under the date and "View threat" sits straight under the title.
- Hero swipe: `Gesture.Pan` (activeOffsetX ±20, failOffsetY ±14) moves between the things needing attention, wrapping both
  ways via `runOnJS(stepHero)`; the dot indicator still advances on tap and shows "N of M".
- Brand title: "Apollo" stays bold/dark, " Scam Guard" is nested in a lighter, muted, slightly smaller style (`brandTitleSoft`).
- Tagline is now "Better Protected. Safer You. Safer Tomorrows."

## Home: hero rotation + "Important for you" card reorganised (2026-06)

**Hero rotation.** `buildHeroLines(voice, attention)` (in `higginsHomeVoice.ts`) returns the primary voice line plus one line per
remaining attention item (each naming the real finding via `findingSentence`, else the item's title; duplicates and the primary
route are skipped). `app/(tabs)/home.tsx` cycles them every 7 s, resets on list change, and shows an indicator
(`home-hero-dots`: a dot per item, active dot widened, plus "N of M") that advances on tap. Tapping the hero opens the case for
the line currently shown.

**"Important for you" card.** Icon + time + status pill share one compact row; the title (up to 3 lines) and the reason (up to
4 lines) sit beneath at full card width with no gap under the date; "View threat" stays bottom-right. (The pill was briefly
moved to the action row at the owner's request and then moved back.)

## Hero line: the stated finding, full width, taps through (2026-06)

`findingSentence(event)` (exported from `src/domain/higginsHomeVoice.ts`, local evidence only) picks the ONE sentence that
states what Apollo found — it drops instruction sentences (anything with "Settings", "Open", "Tap", "go to" or "→"), strips
"In it," style connectors, clips at 170 chars on a word boundary, and returns null when the event has no such sentence (the
hero then names the check instead of inventing detail). Used by both the single-finding and driving-event hero paths. The
example now reads: `Apollo found one active management profile, "Acme IT Mobile Device Management" (com.acme.mdm.agent),
installed 15 Oct 2026.` Tested: `tests/findingSentence.test.ts` 4/4.

Hero layout uses the available width: text sits under Apollo's avatar, up to 5 lines, only `spacing.sm` right padding.
Tapping the hero (including the line itself) opens the exact case — verified: tap → `/patrol/preview-mock-threat-001`.

## Home hero: short line, text under Apollo, full width (2026-06)

**Wording.** `buildHomeVoice` no longer pastes the case narrative into the hero. One short line only:
single finding → "Apollo found <the specific thing or 'something in the X check'>. It needs your decision." (barking) /
"Apollo flagged <…>." ; driving-event path (3c) → "Apollo is reacting to <the specific thing / something in the X check>."
No case title and no what-to-do steps — both live in the case. `tests/developerCorrectionRegression.test.ts` T17 updated to
accept "needs your decision".

**Layout.** `app/(tabs)/home.tsx` hero is now a column: Apollo's avatar and his state sit on one row, and the line he's
saying runs the full width underneath (`home-hero-voice`, max 3 lines, right padding so it stops before the artwork). The
readability gradient was extended (locations 0 / 0.62 / 0.88 / 1) to cover the wider text.

**Also verified for the owner:** status changes stick across a full reload — Resolved → Reopen (Attention) → Mark as handled
(Resolved) → reload → still Resolved; `mergeLocalAndRemoteEvents` keeps a local resolution unless genuinely newer evidence
arrives, and a user reopen beats an older server resolution.

**OPEN (awaiting owner decision):** `tests/architecturalRegression.test.ts`, `tests/phase2Corrections.test.ts` and
`tests/higginsBehavioural.test.ts` all import the deleted `src/domain/protectionDetails.ts` (`buildProtectionFindings`,
`countDistinctFindings`) — they fail to load, so ~40 assertions are silently dead. Options offered: rewrite against the
current protection code, strip only the dead assertions, or defer.

## Bug fix: reopening the example case didn't stick (2026-06)

Cause: the example-case refresh added earlier replaced the stored event wholesale with `MOCK_THREAT_EVENT` on every app start,
overwriting the reopen (so the case showed "Resolved" again when re-entered). `ApolloContext` now refreshes only the sample
wording and preserves what the person did with it: `status`, `state`, `resolved_at`, `reopened_at`, `previously_resolved_at`.
Verified: reopen → full reload → case stays "Attention" with the re-check action and the History reopen step.

## Reopen recorded in History + re-check after action + status pill moved (2026-06)

**History records the reopen.** `PatrolEvent.previously_resolved_at` (new, client-set) preserves the resolution time a reopen
clears, so `buildTimeline` still shows "Resolved" and adds a "Reopened by you" step at `reopened_at` ("You reopened this case,
so Apollo is tracking it again."). `ApolloContext.reopenEvent` sets it.

**Re-check after you've taken action.** New pure `src/domain/recheckPlan.ts` → `recheckPlan(event)` decides, from the case record
only, what Apollo can honestly re-run: `link` (re-runs `checkLink` on the recorded URL), `message` (re-runs `checkMessage` from
the original kept on this device; honest toast when the original isn't there), `number` (re-runs `checkNumberRisk`), `gate`
(device/app/connection/account/file → opens the Gate that performs the live read, with the reason), or `none` with the reason.
`RecheckCase` renders on the Overview when a case is reopened and still open; a direct re-run opens the fresh case, and the
helper text states the pipeline ("his own checks first, and a Magnum DI investigation only if those find a possible threat").
Tested: `tests/recheckPlan.test.ts` 4/4.

**Status pill moved** out of the screen header onto the category-badge line in the source card, aligned far right
(`tc-status-pill`), giving the case title the full width.

## Share pack, case numbers on rows, and the on-device evidence policy (2026-06)

**Share beside Copy.** The Evidence Pack row now has "Copy facts & sources" + "Share" (`tc-evidence-share`, React Native
`Share.share` with the pack text and the case id as title) so the pack can go straight into email, WhatsApp or Messages.

**Case number on every Threats row.** `app/(tabs)/patrol.tsx` meta line reads `TC-2026-10745 | 15 Oct 2026, 9:00 pm | Device`.

**OWNER POLICY — on-device evidence is never deleted automatically.** The original item the person submitted AND the redacted
copy Apollo sent both stay on this phone until the person deletes the case, removes the original, or wipes all data. Only copies
that leave the device are temporary. Code already behaved this way (`src/store/originalSource.ts`, `src/store/imageEvidence.ts`
and `src/investigation/deviceStore.ts` have no TTL/expiry sweep); the WORDING was wrong and is now fixed:
- `src/domain/privacyData.ts`: Higgins row clarifies the 15-minute erase applies to the copy on Apollo's services; new
  "Evidence for your cases (this phone)" row states both copies are never deleted automatically.
- `src/components/EvidencePopup.tsx`: "Evidence Content Expired" → "Server copy deleted", body/meta rows now say the server
  copy was deleted and the phone copy is kept ("Server copy deleted" date row, status "Server copy deleted (24h). Device copy kept.").
- `src/components/InvestigationView.tsx`: the expired/purged notices say the same.

## Threats row specificity + Evidence Pack + uncoloured Higgins report (2026-06)

**Threats rows name the thing.** `subjectRowLabel(event)` (in `src/domain/threatSubject.ts`) returns "paypal-secure.top",
"From: billing@acme.co", "Caller: +61 412 345 678", "App: …", "File: …" from recorded identifiers only; `app/(tabs)/patrol.tsx`
`cardSubtitle` now uses it (message preview remains the only fallback). Tested in `tests/threatSubject.test.ts` (7/7).

**Evidence Pack.** New pure `src/domain/evidencePack.ts` → `buildEvidencePack({ event, facts, sources })` renders a plain-text
pack: case id, status, type, detected/closed times, WHAT APOLLO FOUND (the recorded facts), SOURCES APOLLO USED (each source,
whether it answered, what it returned, its link and time), and a closing line stating no interpretation was added. Honest
"nothing was recorded" lines when there are no facts/sources. A "Copy facts & sources" button (`tc-evidence-pack`,
expo-clipboard) sits under the Sources card on both Evidence branches and confirms with a toast. Tested: `tests/evidencePack.test.ts` 2/2.

**Higgins report (Overview) rewritten.** Severity tints removed — the card is a neutral panel (the status pill carries severity).
It now opens with the ACTUAL name (recorded subject, else the finding statement), follows with Higgins' evidence summary
(established + meaning, never duplicated), and always ends with a WHAT TO DO line that says "Nothing to do." / "Nothing to do —
this case is closed." / "Nothing to do right now. I'll tell you as soon as the investigation finishes." when no action is needed.
The separate blue "info" banner was removed as a duplicate of that line.

## Threat Case: sources used + what each returned; example case on every device (2026-06)

**New pure helper `src/domain/caseSources.ts`** — `buildCaseSources({ event, investigation })` lists every source Apollo
actually consulted for a case and exactly what it returned, from recorded data only: the finding's provenance
(this device / Apollo's known-threat list at DNS / Apollo's servers / original source unavailable), the intake
mailbox, the stored Triage record ("N of M applicable checks completed, K matched. No AI calls."), every Coverage
Gap mapped to the real source that didn't answer, Apollo's own enforcement mechanism + result, the Magnum DI
investigation (honest "Result not stored on this device" when it isn't), each cited `SourceReference` with the
findings that cite it (or "Appeared in search results only" / "Could not be retrieved"), and event-level
supporting references. Unit-tested: `tests/caseSources.test.ts` 4/4.

**Evidence tab** now carries a "Sources Apollo used" card (name → what it returned → link → time, with
"— didn't answer" on failed sources) in both the investigation and deterministic branches, alongside the
facts-only "What Apollo found" list. **History tab** gains one step per source ("Checked <source>" /
"Couldn't check <source>" + a one-line result), merged chronologically with detection, enforcement,
investigation and resolution steps; `buildTimeline(event, sources)` takes the list, and `HistoryContent`
loads the saved investigation through the new `useCaseInvestigation` hook.

**Example threat case on real devices.** `MOCK_THREAT_EVENT` is no longer web-only: it is seeded once on any
platform when Patrol is empty (`apollo.example.threat.seeded`), and a stored copy is always refreshed from the
current definition so an older example never shows stale text. Every visible field still says "Example".

## Threat Case: specific subjects + facts-only Evidence/History (2026-06)

**Specific threat wording.** New pure helper `src/domain/threatSubject.ts` (`threatSubject`, `subjectDescriptor`, `shortDomain`, `stateHeadline`, `subjectLabel`) reads ONLY identifiers Apollo actually recorded (intake `source_metadata`, `local_indicator`, `indicator_host`, `claimed_brand`); when nothing was recorded it returns null and callers keep their plain wording. URLs reduce to the recognisable domain ("https://www.paypal-secure.top/login" → "paypal-secure.top"), long values clip at 42 chars. Applied to: `homeStatusResolver` headlines ("Apollo is growling at paypal-secure.top"), `push/localAlerts` notification titles, `higginsHomeVoice` biting/driving-event paragraphs, `PatrolItem` cards (subject line, hidden when the headline already names it), Threat Case evidence header. Tests: `tests/threatSubject.test.ts` 6/6; `tests/localAlerts.test.ts` title expectation updated.

**Evidence tab = what was found, nothing else.** Removed the "Where to report this" card (`ReportScamHelper`) from both Threat Case evidence branches (owner decision). The deterministic branch no longer repeats Overview's analysis: it now lists "What Apollo found" — the finding statement, Apollo's recorded signals (`why[]`) and the evidence captured by the deterministic Triage rules that were MET (deduplicated, internal codes filtered) — plus an "Observed:" timestamp and the honest "only available on the device where it happened" line when provenance isn't local. Device/app/network cases, which carry no sender or URL, now show their real detail instead of only "Source: captured on this device".

**History tab = record of what happened and when.** `buildTimeline` detection row names the actual subject ("Website detected: paypal-secure.top", else the finding statement); the analysis row is a factual "Automatic checks completed" entry (the briefing prose stays on Overview); a new Triage row records outcome + "N of M applicable checks completed on this device. No AI calls were made."; enforcement names the destination domain; "Investigation requested" names the subject; related rows show the related item's subject, not its narrative.

**Gemini usage unchanged:** Triage and device observations are deterministic (0 calls); only Magnum DI makes a call, and only for POSSIBLE THREAT cases.

**Fix:** removed a stray whitespace text node introduced in the Threat Case source card (RN web "Unexpected text node" toast on all three tabs).

## Hidden fallback audit — truthful failure reporting across Apollo (2026-06)

Full audit of error paths (not keyword searches). Every try/except, catch, default value, timeout path,
provider switch, cache recovery, parse/validation recovery and native-capability read was classified
KEEP / CHANGE / REMOVE. Full record with per-item rationale: `/app/memory/hidden_fallback_audit.md`.

**Removed manufactured results (5).** The worst: `services/higgins/coordinator.py` built a complete-looking
HigginsResponse out of raw text when Gemini's reply failed validation, including the fabricated finding
"Investigation completed. Review the analysis above." and `completion: "complete"`. Now the turn fails and
**Gemini's actual reply is passed on verbatim** (redacted, ≤4000 chars) in `DiagnosticDetail.provider_response`
with model + finish reason, surfaced in the Investigation technical details and copyable diagnostics. Also
removed: First Check grading a device from signals it never read; `coverage: parsed.source` (a non-existent
field) recording every link as checked; call-guard reporting a never-created investigation as `completed`;
and the shared native-SDK helper that made a failing native module indistinguishable from "nothing found"
(replaced by `nativeJson` → absent = declared no-capability value, failing = `NativeCallFailed` + recorded).

**Real bugs the swallows were hiding.** Tier-2 escalation was DEAD on the message, call and number-risk gates:
the three endpoints were missing from `EgressEndpoint` (TypeError inside `enforceEgress`), `client_item_id`
wasn't a UUID (422), the case id was read from the wrong field, and Apollo's deterministic findings were sent
under a key the route doesn't accept. All fixed; failures are now stated on the event.

**Truth-preserving changes.** `_launch_investigation` returns `(case_id, job, error)` and the gates expose
`investigation_error`; redirect expansion reports `(chain, complete, reason)` so a truncated chain is never
called the final destination (degrades coverage, raises a `NETWORK_CHECK_FAILED` Triage gap); a failed
capability read renders as `unverified`/"Couldn't check" rather than Off/Not available/pending; "Apollo will
reject future calls automatically" now requires device confirmation; native read failures are recorded and
listed in Support → App Logs & Diagnostics.

**Verification.** Backend `pytest tests/` — 857 passed (the 3 failures in that run were a stale dev server;
`pytest tests/test_triage_live_api.py tests/test_p0_policy_regression.py tests/test_iter33_api_regression.py`
= 37 passed after `supervisorctl restart backend`). Frontend `node --test tests/*.test.ts` — 556 passed /
25 pre-existing loader failures (unchanged baseline). ESLint clean on `src` and `app`. Per the owner's
instruction, no new scenario/mock tests were written for the Gemini passthrough path.

## Alert Freshness Badge — "Updated 2 hours ago" on scam alerts (2026-06)

**Why:** people couldn't tell whether a scam alert list was minutes or weeks old, so there was no basis to trust it.

**New pure helper `src/domain/alertFreshness.ts`:** `alertFreshness(lastSourcedAt, now?)` → `{ label, stale, exact }` using the backend's REAL `lastSourcedAt` (last successful official-source pull). Labels: "Updated just now / N minutes ago / N hours ago / yesterday / N days ago / 3 Jun 2026". Honest failure modes — a missing/unparsable timestamp returns "Checking official sources…" and NEVER the word "Updated"; a future timestamp clamps to "just now"; anything older than 24h sets `stale`. Unit-tested: `tests/alertFreshness.test.ts` 5/5.

**Surfaces:**
- `app/higgins/scams.tsx` — header line is now `Updated 2 hours ago · Official sources read 10 Jun 2026, 9:14 am`, plus `· Apollo is still trying to refresh` when stale, keeping the existing `· Reading N new…` pending suffix. testID `higgins-scams-sourced` unchanged.
- `src/components/PriorityScamNotice.tsx` — reads `lastSourcedAt` from the same `/higgins/scams` response. Compact (Home) card shows the freshness line on the left of "View scam alert" (`home-priority-scam-freshness`); full card appends it to the source/date meta line (`priority-scam-source`).

**Verification:** `tests/alertFreshness.test.ts` 5/5; ESLint clean; live `/api/higgins/scams` confirmed to return `lastSourcedAt`. The badge itself only renders with a real device credential — the web preview is fail-closed, so it shows the honest "Checking official sources…" fallback there and needs an Android/iOS build for visual sign-off.

## Triage hardening close-out + parcel-scam severity correction (2026-06)

**Client spoofing of Triage records — CLOSED.** `triage_investigation` is strictly server-owned: `routers/patrol.py::upsert_event` nulls any client-supplied value, and only `services/triage/store.py` ever writes it. New live regression test `tests/test_triage_live_api.py::test_client_cannot_spoof_triage_investigation` posts a forged record (`geminiCalls: 99`) and asserts both the response and the stored Patrol event carry no triage payload. Backend triage suites green: 27 passed (contract + live API, 0 Gemini calls).

**Parcel-delivery severity (owner decision).** `src/domain/messageAnalysis.ts` no longer escalates courier/parcel lures to **barking** on a non-official URL or payment request alone — they now settle at **growling** (credible suspicion), consistent with the toll scenario (M03). Barking is still reached when threat intelligence marks the destination malicious (`urlVerdict === "malicious"` override). `tests/messageAnalysis.test.ts` 23/23 green (M01 restored to growling); gate5 + round1MessageRegression + triage suites unaffected (38/38).

**Note on the frontend test runner:** `node --test tests/*.test.ts` reports ~25 file-level failures that are NOT product bugs — they are `ERR_MODULE_NOT_FOUND` from Node's type-stripping requiring explicit `.ts` extensions on relative imports (e.g. `src/domain/gates.ts` imports `./gateRegistry`). Metro bundles these fine. Verified by A/B run: the pre-change tree failed 26, the post-change tree fails 25 (one fixed, none broken).

## Universal Check Result — shared screen + Link Gate reference (Phase 1) (2026-06)

**Standing principle:** Apollo investigates. Higgins explains. ONE result, ONE Higgins paragraph, ONE itemised list, ONE actions row. No competing verdict cards, no auto-asked follow-up questions, no repetition. Technical evidence preserved behind progressive disclosure.

**New shared model `src/domain/checkResult.ts`:** canonical `CheckResultModel` + `CheckItem` + `EvidenceRow` for every Apollo manual check (Link / Site / Text / Call / Internet / App / Device / Email / File / Account + Higgins First Check & Re-check). Statuses: `clear` / `concern` / `incomplete` / `unavailable` / `not_configured` / `error` / `not_performed`. `STATUS_LABEL` + `STATUS_TONE` for consistent pills.

**New shared component `src/components/CheckResultScreen.tsx`:** full-screen Check Result with the agreed layout — Gate title + check type → ONE outcome Pill + Confidence Pill + headline → **Higgins says** (2–4 sentence paragraph + Hear-Higgins) → optional **What to do** → **What Apollo checked** (plain-English items, each expandable to raw JSON) → **Full investigation details** (progressive disclosure for all technical evidence, privacy processing, adapter, event id, redirects, intel coverage, domain registration) → secondary row (Ask Higgins about this result + gate-specific actions). Close returns via `goBackOrHome`.

**Link Gate reference implementation:**
- `src/domain/linkCheckResultAdapter.ts` (pure): `buildLinkCheckResult({ outcome, liveEvent, rawInput })` turns the existing `CheckOutcome` into a `CheckResultModel`. Items derived from REAL evidence: Apollo threat list, Google Safe Browsing, Higgins investigation, Domain registration (RDAP), On-device heuristics. Higgins' paragraph is state-driven and honestly qualifies when checks were incomplete (e.g. HTTP 403 restricted page inspection). Clean results don't force a "What to do" action.
- `app/check.tsx` rewritten so when a check completes, the entire screen becomes the shared `CheckResultScreen` — the old chain (`MessageAssessmentResult` → `check-result-card` "Apollo technical decision" → `GateInvestigation` auto-ask → `check-gate3-actions`) is gone. Actions row carries "Show me how to check the website", "Deep technical details", "Report mistake", "Save this check". "Ask Higgins about this result" opens Higgins pre-seeded with the specific link context + a plain follow-up prompt. Input + "Check with Apollo" + page-screenshot / safe-inspect buttons remain on the entry view when no check has been run.

**What this does NOT change:** no reduction in what Apollo actually investigates — every check still runs. Saved reports, technical evidence, provider responses, confidence methodology, privacy-processing disclosure, enforcement evidence remain fully accessible via "Full investigation details" + "Deep technical details" sheet.

**Still to do (Phases 2–4):** route Text / Call / Internet / App / Device / Email / File / Account / Higgins Re-check / First Check through `CheckResultScreen` via per-gate adapters; progress indicators while a check runs; cross-screen consistency (Patrol / Home / Gates / Higgins all read the same canonical result).

**Verification (code-level only — no automated tests run per rule):** `tsc --noEmit` clean; ESLint clean; Android bundle HTTP 200. Full visual verification needs a native build + your sign-off on the Link Gate before I migrate the rest.

## Universal Check Result — Phase 2 Batch 1: Call, File, Network Gates (2026-06)

**Migrated three more Gates** to the shared `CheckResultScreen` component, eliminating legacy duplicate verdict cards and bringing them in line with the "Apollo investigates, Higgins explains" principle.

**Call Gate (`app/call.tsx`):**
- New `src/domain/callCheckResultAdapter.ts`: `buildCallCheckResult({ analysis, event, number, transcript })` maps `CallAnalysis` to `CheckResultModel`. Items: What they asked, Claimed identity, Caller number, Voicemail/transcript, Threat Scent correlation. Higgins paragraph composed from verdict + why + recommendation, tone-driven. Evidence rows: caller, claims, scenario, basis, transcript.
- When a result exists, the entire screen becomes `<CheckResultScreen>` with actions: Verify safely, Trust/untrust number, Check related gates (App Gate for install requests, Account Gate for code/password requests), Mark as handled, Check another call. RecoveryFlow and Verify Caller sheet retained as overlays.

**File Gate (`app/file.tsx`):**
- New `src/domain/fileCheckResultAdapter.ts`: `buildFileCheckResult({ analysis, event, fileName, submissionId })` maps `FileAnalysis` to `CheckResultModel`. Items: File signature, Extension mismatch, Embedded links, Content sample. Higgins paragraph qualifies inspected scope — never claims safety beyond what was actually checked.
- When a result exists, early return renders `<CheckResultScreen>` with actions: "I installed it — check the app/device", Check embedded links, Check another file. RecoveryFlow retained. Old "Higgins card", "Technical details sheet", and `GateInvestigation` inline component removed — all now handled by the universal screen's "Full investigation details" and "Ask Higgins" button.

**Network/Internet Gate (`app/network.tsx`):**
- New `src/domain/networkCheckResultAdapter.ts`: `buildNetworkCheckResult({ analysis, event, context, submissionId })` maps `NetworkAnalysis` to `CheckResultModel`. Items: Connection type, Wi-Fi encryption, Network name, Captive portal, VPN status, Network context, Threat Scent. Higgins paragraph honestly qualifies what platform signals can and cannot establish.
- When a result exists, early return renders `<CheckResultScreen>` with actions: Check sign-in page, Check device, Trust network, Save check, Check again. Dashboard and input form remain on the entry view.

**Code cleanup:** Removed unused imports (`GateInvestigation`, `Pill`, `toneColor`, `STATE_LABEL`, `STATE_NAME`, `issueContext`, `Sheet`, `PhoneOff`), dead state variables (`why`, `tech`, `showFull`), deduplicated `higginsHandoff` imports.

**Still to do (Phase 2 Batch 2):** Text Gate, Email Gate. **Batch 3:** App Gate, Device Gate. **Deferred:** First Check, Re-check (different UX pattern).



## Scam Share + "What Apollo has done today" Protection Timeline (2026-06)

## Universal Gate Results — Complete Phase 2 & 3 + Android Native Updates (2026-06)

**Phase 2 complete:** All 8 manual Gate screens now use the shared `CheckResultScreen`:
- Batch 1: Call Gate, File Gate, Network Gate (adapters + early return pattern)
- Batch 2: Text Gate, Email Gate (adapters + early return, removed MessageAssessmentResult)
- Batch 3: App Gate (adapter + early return with permission review), Device Gate (adapter + Ask Higgins button), Account Gate (adapter + early return)

**Phase 3 cleanup:** Removed `GateInvestigation`, `MessageAssessmentResult`, duplicate verdict cards, "Why Apollo reacted" sections, and technical detail sheets from all manual gate screens. All replaced by `CheckResultScreen`'s integrated Higgins paragraph + expandable evidence. Unused imports (`toneColor`, `Pill`, `STATE_LABEL`, `STATE_NAME`, `issueContext`, `Sheet`, `GateInvestigation`, `MessageAssessmentResult`) cleaned from all migrated files.

**Android notification update:**
- Title changed from "Apollo · Site Gate" to "Apollo"
- Text changed from "Site Gate is on — Apollo is watching..." to "Apollo protection service is running."
- Tap now opens Home screen (`apollo:///`) instead of Patrol (`apollo:///patrol`)
- Channel name simplified to "Apollo"

**BlockTest decoupled:**
- If BlockTest server is unreachable or binding mismatches, protection STILL starts in Website Gate-only mode (M2)
- New `establishWithoutBlockTest()` method creates TUN with only DNS gateway routes
- `TunPacketReader.dropReporter` made nullable for Website Gate-only mode (no M1 packet reporting)
- BlockTest retained for testing/diagnostics but no longer required for normal protection


**Scam Share:**
- Both `app/higgins/scams.tsx` and `src/components/HomeScamAlerts.tsx` gained a one-tap "Share alert" chip next to "Ask Higgins" / "Open source".
- `shareScamAlert` / `shareHomeScam` compose a plain-text share message — title, source name + date, severity, Higgins' whatHappened one-liner, the official source URL, and an "Apollo Cyber Security" byline — then open React Native's native share sheet (`Share.share`, no new dependency). The OS routes the forward (SMS, WhatsApp, Email, etc.); nothing is sent via Apollo's servers.
- Icons: `Share2` from lucide. Dismissed sheets or OS errors are swallowed silently (no toast noise). New testIDs: `higgins-scam-{i}-share`, `home-scam-{i}-share`.

**Protection Timeline — "What Apollo has done today":**
- New `src/domain/protectionTimeline.ts` (pure, 6/6 unit tests): `buildTodayTimeline({ events, gateHealthLog, now?, limit? })` merges two REAL on-device sources — today's patrol events (flagged / investigating / blocked / resolved — any category: scam text, malicious email, insecure connection, device setting change, verified block, etc.) + today's Gate Health Log "Watching confirmed" entries. Local-timezone day boundary (`isSameLocalDay`), newest-first ordering, capped at 12 entries. `quietDayLine()` returns an honest reassurance when nothing happened — never fabricates activity.
- New section in `app/protection-details.tsx`: "What Apollo has done today" card between the Higgins voice and the per-Gate findings. Each row = a small tone-coloured dot (resting/ears_up/growling/barking/biting), a short title + plain-English summary + a local time label. Tappable rows jump to the related investigation. Honest empty state uses `quietDayLine()`.

**Verification:** `tsc --noEmit` clean; ESLint clean; `node --test tests/protectionTimeline.test.ts` 6/6; Android Metro bundle HTTP 200.


## Apollo Guard Dog — Higgins-led Home + Protection Details screen + "Ears Up" rename + Scam deep-links (2026-06)

**Home (`ApolloHero` + `app/(tabs)/home.tsx`) — Higgins is now the single voice:**
- Patrolling (resting) is the one "all is well" state — simple meaning line, no CTA button.
- Every other state (sniffing / ears_up / growling / barking / biting) now shows ONE short Higgins paragraph assembled from REAL data, with ONE primary action.
- Gate names in the paragraph are dynamically generated from the live affected set (`capabilities[]` + `health.gates[]` + active patrol events). No hardcoded "Link, Site, Internet, Known Threat" strings.
- Covers ANY detected concern — not just protection visibility: scams (growling text/email events), malicious messages, insecure connections, device setting changes, verified blocks (biting). Routes to the specific investigation when there's one driver, otherwise to the new Protection Details screen.
- Removed the "Needs your attention" list from Home — Protection Details owns per-gate findings now.

**New `src/domain/higginsHomeVoice.ts` (pure):** `buildHomeVoice({ resolution, attention, gates, capabilities })` → `{ text, ctaLabel, ctaRoute, spoken }`. Priority chain: biting-with-verified-block → multi-issue (names every affected gate) → one-attention-item (names the gate, points to it) → driving-event-only → visibility-lost → recovering → fallback. Verb/opener per state ("Apollo is biting", "Apollo is barking about X", "Apollo has his ears up"). Never claims a block without `verified_block`.

**Widened `src/domain/homeAttention.ts`:** growling and ears_up events now appear as attention items too (previously barking-only), ranked barking → growling → ears_up by newest-first. Suspected scam/malicious concerns reach Protection Details. Optional setup still never raises an item (no false barking). Unit tests updated (7/7 pass).

**New screen `app/protection-details.tsx` (`/protection-details`, modal):** reusable `ChildScreenHeader` with ⓘ "About Protection Details" popup. One Higgins voice card at the top (same copy as Home) + a card per affected Gate with: **What Apollo found** / **What it means** / **What to do** + a Pill for status + a Pill distinguishing **Manual check** vs **Automatic protection** + a direct "Open [Gate]" action to the gate / investigation / settings. Honest empty state when nothing's affected.

**New `src/domain/protectionDetails.ts` (pure):** `buildProtectionFindings({ capabilities, gates, attention, events })` → ordered, de-duplicated findings. Sources: attention items first (action gates + active events), then non-active capabilities (Link Gate / Site Gate / Internet Gate / Known Threat Lookup / Share to Apollo / Text Gate / App Gate), then limited/unverified-tone gates. Manual capabilities are never represented as automatic protection.

**"Ears Up" rename (`src/domain/types.ts`):** `STATE_NAME.ears_up` = "Ears Up" (was "Growling"); `STATE_LABEL.ears_up` = "Apollo has his ears up" (was "Apollo is growling"); `STATE_MEANING.ears_up` = "Apollo noticed something and is looking at it more closely." Hero GIF reuses the sniffing animation — ears_up is the "something caught my eye" variant of sniffing. Higgins voice treats ears_up like sniffing (no decision needed yet).

**Scam deep-links:**
- `app/higgins/scams.tsx`: tapping anywhere on an alert card now opens the official source (`Linking.openURL`). The "Ask Higgins about this" chip remains the one-tap shortcut into the Higgins chat pre-seeded with `{ scamTitle, scamSource }`. "Open official source" row kept as the visible affordance.
- `src/components/HomeScamAlerts.tsx`: tapping the row (or the "Open source" chip) opens the official source directly; a dedicated **Ask Higgins** chip (`home-scam-{i}-ask`, `MessageCircle` icon) opens Higgins pre-seeded with the alert.

**Verification:** `tsc --noEmit` clean; ESLint clean; `node --test` — homeAttention 7/7, apolloStateLabels 1/1, messageGuardrails + gatesOverview + messageVoice 34/34 (no regressions). Android Metro bundle HTTP 200. Native-shell preview is Safe Start so visual verification happens on an Android build.


## Multi-Select filter verification + Scam v5 re-analysis validation (2026-06, fork)

**Multi-Select filter (`src/components/MultiSelectFilter.tsx`) — VERIFIED on Patrol + Scams:**
- Patrol (`patrol-filter`): "Filter activity" opens the Sheet (Show all / Needs you / Warnings / Threats stopped / Resolved), multi-select shows a count badge, and the activity list filters by OR semantics. Confirmed via screenshot (badge "2", "Nothing matches the filters you chose.").
- Scams (`scam-filter`): "Filter alerts" (Australia/USA/UK/Europe/Global/High/Extreme). Confirmed by text assertion: AU+EXTREME correctly HIDES ASOS (Moderate/Global/potential) while KEEPING NASC (Extreme, AU-confirmed) and the AU Scamwatch "Food delivery" alert; "Show all" restores every alert. Empty selection = show everything.

**Scam Alerts v5 re-analysis — VALIDATED (backend):** `learning_feed_items` 96/98 at `analysisVersion:5` (2 transient pending, hourly loop fills). Breakdown: 6 `specific_scam` + 5 `emerging_pattern` consumer alerts surfaced; 85 `general_education` + 27 `organisation`-audience items excluded. Spot-checks: "Incident affecting ASOS customers" → specific_scam/consumer (SHOWN); "Iranian cyber targeting of dissidents", Europol law-enforcement items → organisation (HIDDEN). Nation-state/espionage/APT correctly filtered out; consumer-brand breaches retained. Official source acronyms expanded (e.g. "UK National Cyber Security Centre").


## Home + Higgins + Patrol navigation reshuffle (2026-06)

**Home (`app/(tabs)/home.tsx`):**
- Removed the "Recent patrol" section (full feed still lives on the Patrol tab). Dropped now-unused `PatrolItem`/`projectPatrolOutcomes` imports and `recent`/`attentionEventIds`.
- Added a "Learn with Higgins" card (GraduationCap icon) just below Scam alerts → routes to `/higgins/learning` (`home-learn-higgins`).

**Home scam alerts (`src/components/HomeScamAlerts.tsx`):** fixed the misleading empty state — the card showed "No current scam alerts" while loading OR on fetch failure, so a transient hiccup looked like "no scams" even though the feed has EXTREME alerts. Now three explicit states: loading (`home-scam-loading`), error with retry (`home-scam-error`/`home-scam-retry`), and the genuine empty only when the feed truly returns zero. Ranking now prioritises severity (EXTREME→LOW) then growling, preserving the backend's most-recent-first order (stable sort).

**Higgins tab (`app/(tabs)/ask.tsx`):** removed the ⋮ three-dot menu and its Sheet. "Clear chat history" is now a trash button (`higgins-clear-chat`) next to the ⓘ About button in the header (still opens the existing confirm Sheet). About Higgins stays on the ⓘ button. Scam alerts (Scams tab), Learning (Home card), Saved reports + Higgins history (Patrol buttons) are reachable elsewhere. Removed unused `menuOpen`/`goMenu`/`EllipsisVertical` and the menu styles. Updated `tests/phase2Hub.test.ts` (5/5 pass) for the new design.

**Patrol tab (`app/(tabs)/patrol.tsx`):** added a row of 3 labelled buttons under the header — Higgins history (`patrol-nav-higgins-history` → `/higgins/history`), Saved reports (`patrol-nav-saved-reports` → `/saved-reports`), and Patrol history (`patrol-nav-history` → scrolls the FlatList to the top of the activity feed). Removed the duplicate small saved-reports header icon (export PDF icon kept).

**Verification:** tsc + ESLint clean; phase2Hub 5/5. Owner verifies visually on a native build (web preview is fail-closed Safe Start). No automated tests run per owner rule.


## Home status card now details the exact issue Apollo is reacting to (2026-06)

**Problem:** When Apollo was barking, the Home status card only showed a generic line ("This device needs your decision.") — the specific issue lived in the "Needs your attention" section below the fold. The real detail (what happened + Higgins' step) was already in the data (`resolution.drivingEvent` / `buildHomeAttention` → `attention[0]`) but the hero deliberately omitted it.

**Change (frontend only, no new data/backend):**
- `src/components/ApolloHero.tsx`: when there's a real issue (`primary = attention[0]`), the card now shows the specific gate title, a PROBLEM block (the driving event's what-happened) and a HIGGINS block (his plain-English explanation + next step), plus a smaller "See what needs attention" button that routes straight to that item. "Hear Higgins" reads the specifics aloud (unchanged `spokenText`). New testIDs: `apollo-state-problem-title`, `apollo-hero-problem`, `apollo-hero-problem-text`, `apollo-hero-higgins-text`. Reused the previously-unused `problemBox`/`higginsText` styles.
- `src/components/HigginsSpeakButton.tsx`: added optional `small` prop (slimmer height/face/label) used on the Home card.
- `app/(tabs)/home.tsx`: de-duplicated — the "Needs your attention" list now renders `attention.slice(1)` (the top issue is on the card) and only shows when more than one issue exists.

**Verification:** tsc + ESLint clean. Home renders fully only on a native build (web preview is fail-closed Safe Start); owner verifies visually. No automated tests run (owner approval rule).


## Deployment readiness health check (2026-06)

**Genuine config fixes applied (safe, verified — backend 200, preview 200):**
- Quoted two malformed `.env` values that start with `/`: `backend/.env` `INVESTIGATION_KEY_FILE="/app/backend/.secrets/investigation.key"` and `frontend/.env` `METRO_CACHE_ROOT="/app/frontend/.metro-cache"` (python-dotenv strips the quotes at runtime — confirmed).
- Removed the `.env` / `.env.*` / `*.env` lines from `/app/.gitignore` so the deployment pipeline can read the env files (`.env.local`/`*.env.local` still ignored).

**Flagged-but-ACCEPTED by owner (intentional design / platform-managed — do NOT "fix"):**
- **TTL + maintenance cleanup** (`services/higgins/retention.py` TTL indexes on `ask_messages`/`ask_handoffs`/`voice_cache`; `services/higgins/repository.py` sweep via `maintenance.supervise_maintenance`): this IS Apollo's privacy feature (submitted evidence auto-erases within ~15 min; stale investigation records swept). Owner decision: KEEP as accepted design. The static deploy check will keep flagging it as "destructive_db_startup".
- **Secrets in `backend/.env`** (SAFE_BROWSING/GEMINI/encryption/email/etc.): `backend/.env` is the platform's managed secret store; removing breaks runtime. Owner decision: KEEP.
- **Push** (`routers/push.py` sends directly to Expo with `EXPO_PUSH_ACCESS_TOKEN`, `EXPO_PUSH_ENABLED=true`): not the supported production push path. Owner decision: LEAVE enabled as-is for now; proper Emergent push is pending Task 2 (needs Firebase google-services.json).
- **`frontend/eas.json`**: retained — carries production build config (GuardDog enforcement engine, controlled host/IP, preview-harness off) that a pipeline-generated default would lose. Owner decision: KEEP.

NOTE: Because the four accepted items are deliberate, a re-run of the deployment health check will still report them as blockers by design; this is expected and acknowledged by the owner.


## Share to Apollo — multi-file correction + honest preservation (2026-06)

**Scope:** corrections to the EXISTING Share-to-Apollo feature (no new Gate/route/backend). KISS.

**Defects fixed**
1. Multi-file shares only inspected the first file (`file.tsx` read `shared.files[0]`), yet the batch could claim it was checked. NOW: when >1 files are shared, `app/share.tsx` renders `src/components/ShareFileBatch.tsx` which accounts for EVERY file, inspects each individually with the SAME engine (`readInspection` + `analyseFile`), shows a per-file status (waiting/checking/checked/couldn't-check), per-file verdict, flags files whose contents couldn't be read, shows "N of M checked", and lets each file be opened on its own in the full File Gate (fresh single-file intake). Never a single batch "all clear".
2. iOS extension silently discarded extra URLs (`urls.first`). NOW every shared URL is preserved — `webUrl` keeps the first for routing and all URLs are merged into the combined `text` so none are lost (`ShareViewController.swift` commit()).
3. iOS extension silently truncated long text at 200k chars. NOW it appends a plain-English note that the text was shortened.
4. Image classification wording: no longer claims an image IS a message screenshot. `SHARE_KIND_LABEL.screenshot` = "an image"; reason explains the screenshot check is optional and "Apollo doesn't know what's in it until it looks".

**Reuse / helpers**
- `src/domain/fileInspection.ts`: added `readInspection(asset)` (web fetch / native File handle → Inspection), reused by the batch; single-file `analyseAsset` left untouched (no regression).
- Android `ShareIntakeListener` already mapped ALL files into the intake; batch now consumes them.

**Verification (code-level only — native Share requires a device build)**
- tsc + ESLint clean; `yarn test:share` 13/13 green; app boots with ShareIntakeListener mounted.
- NOT validated on a physical device yet: Android ACTION_SEND/SEND_MULTIPLE menu registration, iOS Share Extension activation/App Group handoff, and real multi-file/URL/screenshot shares. These must be tested in an installed development/release build (Expo Go/web are not acceptable proof).


## Scam Alerts correctness overhaul — three-tier + AI-grounded facts + UI refinements (2026-06)

**Problem:** Scam Alerts were showing generic scam *education* and generic Higgins filler as if they were newly detected campaigns. User's non-negotiable: alerts must describe specific, evidence-backed scams actually reported by official sources, with facts drawn only from the source.

**Approach (user-approved):** fetch each official advisory's article and use **Gemini 3.1 Pro** (`gemini-3.1-pro-preview` via `EMERGENT_LLM_KEY`) to classify + extract facts strictly from the text (never invent); analyse+cache once at ingest.

**Backend**
- `services/scam_analysis.py` (NEW): fetches the source article (`outbound.public_get`, HTML→text), strict JSON prompt → `{tier, severity, severityReason(cited), confidence, australianRelevance(+reason), reportedDate(YYYY-MM-DD/YYYY-MM/''), facts{who,what,how,where,when,whatCriminalsWant,evidence}, sections{whatHappened,whereHappening,whatItMeansForYou,whatToWatch,whatToDo}}`. `_coerce` clamps to the contract (a malformed reply can never yield a High alert; education forced to LOW). Free `_obviously_not_an_alert` pre-filter for nav/index/pagination links (no AI spend). `analyze_pending(limit)` caches on `learning_feed_items.scam_analysis`. `ANALYSIS_VERSION=2`.
- `services/government_alerts.py`: `refresh_all()` now also runs `analyze_pending(8)` (hourly loop). `snapshot()` returns `{coverage, generatedAt, feeds, alerts, emerging, pendingCount, lastAnalysedAt, lastSourcedAt, growling}` — **general_education excluded**; specific→alerts, emerging_pattern→emerging. Per alert: real source name, `reportedDate`, `dateLabel` ('Month YYYY'/'Date not stated'), `effectiveDate`. **Recency:** items older than ~15 months (RECENCY_CUTOFF) dropped; lists sorted most-recent-first. **Growl:** specific HIGH/EXTREME that is AU-confirmed (even undated) or AU-potential+fresh.
- Tests: `tests/test_scam_analysis.py` (10) + `tests/test_scam_intel.py` green. Live curl confirmed: specific AU HIGH/EXTREME alerts with grounded whatHappened/severityReason, dateLabel month/year, recency sort, growling, lastSourcedAt.

**Frontend**
- `app/higgins/scams.tsx`: three-tier UI (specific alerts list + 'Emerging patterns' footer + 'Learn with Higgins' link). **Removed** the redundant collapsible Higgins explanation; card now shows real source name + month/year, body = whatHappened, 'Ask Higgins about this' + 'Open official source'. Header uses the new `info` template (title + ⓘ popup) instead of a long inline paragraph; 'Last sourced <date>' line replaces the status pill.
- `src/components/InfoButton.tsx` (NEW) + `info` prop on `RootScreenHeader`/`ChildScreenHeader` = reusable 'title + ⓘ → popup' template for all screens.
- `src/components/HomeScamAlerts.tsx`: uses `r.alerts`; each row tappable → opens the official source; shows source + month/year.
- `src/higgins/hubClient.ts`: types updated (alerts/emerging/pendingCount/lastSourcedAt; tier/facts/reportedDate/dateLabel).
- `src/components/AboutApolloSheet.tsx`: added 'Social Media & Messaging Protection' section (Facebook, Instagram, TikTok, X, Messenger, WhatsApp, Snapchat; protection via existing Gates).
- tsc + ESLint clean. NOTE: v2 backlog re-analysis still filling (hourly loop); pendingCount>0 is expected transient. User will self-test (declined automated frontend test this round).


## Privacy & Data — honest retention inventory + "Delete My Apollo Data" (2026-06)

**Problem/Task 1 (P0):** Give the person an authoritative view of everything Apollo stores for their anonymous device, and a verified, complete "Delete My Apollo Data" workflow with honest offline/pending states.

**Backend:**
- New `services/account_deletion.py` — authoritative, device-scoped (owner_id == device_id). `CATEGORIES` maps 7 service-side groups (Higgins conversations, Investigations & saved reports, Patrol activity & records, Trusted links, Email & account monitoring, Family links & guardians, Diagnostics & app signals) to their collections + id fields.
  - `inventory(device_id)` → honest per-category counts (zeros reported truthfully, missing collections skipped).
  - `purge_device(device_id)` → (1) invalidates the investigation `generation` first so late workers can't publish, (2) `delete_many` across every category by `device_id`/`owner_id`/`recipient_id` (+ family keys protected/guardian/owner_device_id), (3) revokes family-assist sessions, (4) **deletes the device identity** itself. Returns per-category removed counts.
- New routes in `routers/devices.py` (device-auth): `GET /api/devices/data-inventory` and `POST /api/devices/delete-data`. Another device's data is never touched.

**Frontend:**
- `src/domain/privacyData.ts` — `RETENTION_INVENTORY` (plain-English what/where/retention per category incl. a local-only row), `wipeLocalApolloData()` (AsyncStorage.getAllKeys → multiRemove every `apollo.*` key), `DataInventory`/`DeleteDataResult` types, `PENDING_DELETE_KEY`, `CONFIRM_WORD="DELETE"`.
- `src/auth/deviceIdentity.ts` — new `clearDeviceIdentity()` (full clean wipe, no reset marker → true first-run).
- `ApolloContext.requestDataDeletion()` — calls `/devices/delete-data`; on success wipes local + clears identity + resets in-memory state (events/trust/ssids/verified cleared, deviceId null, setupDone false) + `qc.clear()`. On failure (offline) persists `PENDING_DELETE_KEY` and auto-retries on the next backend-reachable event.
- `app/privacy-data.tsx` — modal screen: intro, live inventory (service counts + "On this device" rows), pending banner, type-to-confirm `DELETE` input gating a danger button → confirm Sheet → delete → toast + `router.replace("/onboarding")`.
- Settings → "Privacy & data" section gains a top `Privacy & data` NavRow → `/privacy-data`; registered as a modal in `app/_layout.tsx`.

**Verification:** tsc + ESLint clean. Backend `tests/test_delete_my_data.py` 3/3 (inventory counts this device only; delete erases everything + kills the identity (token→401); delete doesn't touch another device); `test_device_auth.py` 11/1-skip regression green. Live curl: register→inventory(0)→delete→token 401. UI: screen renders in web preview; type-to-confirm enables the danger button and opens the confirm sheet. NOTE: the happy-path delete needs a registered device token (native/real install); in web preview with no token the live inventory shows its honest fallback and delete follows the pending path.


## Device Gate cross-platform Security & Privacy Review + positive framing + deep links (2026-06)

**Platform typing (P0):** `DevicePlatform` expanded to `ios | android | windows | macos | web`; `firstCheckSignals.currentPlatform()` and `firstCheck.platformName()` now handle Windows/macOS (desktop no longer collapsed to web); `deviceAnalysis.path()` desktop-safe.

**New engine `src/domain/deviceReview.ts` (P0):** registry-driven cross-platform review. 9 categories (access/system/malware/apps/personal_info/privacy/network/administration/data), 6 exact outcomes (`OUTCOME_LABEL`: Checked / Review recommended / Action required / Manual review required / Unavailable / Not applicable). ~18 checks, each declaring applicable platforms + per-OS Settings destinations + a pure evaluator that reuses existing `DeviceSignals`/self-report/protection health. Android/iOS read real signals; Windows/macOS return guided **Manual review** until native collectors land (never false "Checked"). `runDeviceReview()` returns per-check `{outcome, risk, evidence, remediation, settings, verifiedBy}` + honest `overall` (action/review/manual/clear/unknown) with coverage counts — **"clear"/Protected only when zero action/review AND zero skipped checks** (no-false-PASS). `groupByCategory`, `overallState`, `OUTCOME_TONE` helpers. Fully unit-tested: `tests/deviceReview.test.ts` (safe/unsafe/unknown/failed/user-confirmed/not-applicable/4-platform coverage/no-false-PASS).

**Device Gate UI (`app/device.tsx`, P2):** new "Security & privacy review" section groups results by category; each shows title + outcome Pill + risk + "What to do" (Higgins remediation) + evidence + verifiedBy note + a **deep-linked "Open Settings"** button (`openDeviceSettings` via `REVIEW_TARGET`). Status card now driven by the honest `overall`/coverage. Replaced the old single-severity findings list.

**Positive reframing (user ask):** negative "Apollo cannot…" copy reframed to what Higgins *can* do — Device Gate's "What Apollo can't see here" → "Where Higgins can help"; `deviceAnalysis.cannotSee[]` strings; app-check scope + `app-capability-evidence-note` + self-report blurb; review engine's manual/unavailable evidence. Fixed two pre-existing test failures from an earlier GateAbout edit (`fileDeviceGateUi`, restored app-check phrase) and updated `gate7` for the new positive iOS-management wording.

**Not yet done (remaining):** full First Check / Higgins Re-check UI rebuild to the per-setting model (Phase 2 remainder); native collectors for Windows/macOS + deeper iOS/Android signals (Phase 3); positive-tone pass across non-device gates; the dev-only Safe Start screen still reads "GuardDog production authority". tsc + ESLint clean; suite 485/493 (8 failures all pre-existing app.json/source/brand scans).


## Higgins starter memory (2026-06)

Higgins now remembers the ordinary questions a person asks most often and offers them back as one-tap chips. Pure logic in `src/higgins/starterMemoryCore.ts` (`recordInto`, `topStarters`; unit-tested in `tests/starterMemory.test.ts`), local-only persistence in `src/higgins/starterMemory.ts` (AsyncStorage key `apollo.higgins.starter-memory.v1`, stored as JSON string). Wired into `app/(tabs)/ask.tsx`: records each ordinary chat message (min 6 chars), shows repeated questions (count ≥ 2) — merged into the welcome starters when empty, and as a slim horizontal "ask again" row above the composer during a chat (only when the input is empty). Cleared alongside Clear chat history. tsc + lint clean, tests pass.


## Higgins tab → full chat experience (2026-06)

Rebuilt `app/(tabs)/ask.tsx` as a messaging screen ("Open Higgins. Start talking.").
- **Header**: small avatar (logo) + "Higgins" + subtitle "Apollo's trusted adviser" + discreet ⋮ menu (`higgins-menu`). Removed the old "Ask Higgins" badge / oversized heading / hub cards.
- **Header menu (Sheet)**: About Higgins, New scam alerts, Learning, Saved reports, Higgins history, and **Clear chat history** (with a confirm Sheet — `higgins-clear-confirm`/`cancel`). "About Higgins" Sheet states real capabilities + limits ("Apollo acts; Higgins interprets").
- **Conversation**: full-height ScrollView; user bubbles right (brand), Higgins bubbles left (with mini avatar) + subtle timestamps; animated typing indicator (`src/components/TypingDots.tsx`); smart auto-scroll (sticks to bottom only when the reader is already near the bottom).
- **Welcome**: when no history, one Higgins welcome bubble + 3 tappable starters ("Why is Apollo barking?", "Is my device protected?", "Explain a scam warning.") that submit as ordinary messages; disappears once chatting starts (no permanent card).
- **Composer**: anchored above the tab bar via keyboard-controller KeyboardAvoidingView, placeholder "Message Higgins…", multiline (max 120dp), prominent round Send. Error bubble has **Try again** (`retryLast`) that re-sends the last user message without duplicating it.
- **Preserved**: local + server chat history rules, redacted Apollo context, and the entire Apollo→Higgins **investigation hand-off flow** (handoff/resume params, `startInvestigation`, `InvestigationView`, investigation offers/check-it offers) — unchanged. Removed the old `higgins-hub*` dashboard; `tests/phase2Hub.test.ts` rewritten to assert the chat-first design (5/5 pass).
- Removed the bottom chip bar, the standalone "Clear chat history" button and the long redacted-context disclaimer from the body.

Verified: tsc clean, ESLint clean, phase2Hub tests pass. Visual/keyboard behaviour verifies on an Android build (web preview is fail-closed Safe Start for the whole app).


## Home redesign + specific-problem status + tappable notification (2026-06)

**Notification tap → Patrol:** `ProtectionNotificationFactory.build` now sets a `contentIntent` that deep-links `apollo:///patrol` (ACTION_VIEW, app package, NEW_TASK|SINGLE_TOP) so tapping the protection notification opens Apollo on the Patrol tab. Native → only on an Android build.

**Home (`app/(tabs)/home.tsx`) rebuilt to a 4-part hierarchy, all from REAL data (no invented text / no parallel status system):**
1. Status card (`ApolloHero`, now compact: emblem 104dp, rings shrunk, padding reduced). When there's a real issue it shows a boxed "<Gate> needs …" title + the specific Problem + "Higgins: <next step>" + action button. Driven by new `attention` prop.
2. `CoverageCard` rewritten — lists every gate that is verifiably Watching (tone good + automatic.running + !manualOnly), "N gates Watching", tap opens the gate. No hard-coded subset/count. "On" → "Watching".
3. "Needs your attention" section — renders only when real issues exist; one `AttentionCard` per issue (gate failure or active barking event) with Problem / Higgins / action / Dismiss (events).
4. Recent Patrol — `PatrolItem` redesigned: gate chip + severity + time (overlap fixed with flex), headline, summary, "Higgins recommends: <what_to_do>", "Open investigation ›" + Dismiss (barking only).
- Removed the duplicate "Gates Protection" card and the Home `GateNudge`. Compact single-line background indicator replaces the bulky wrapping card. Weekly digest headline now wraps (numberOfLines 2).

**New domain `src/domain/homeAttention.ts`** — `buildHomeAttention({gates, events})` → ordered `AttentionItem[]`: gates in verified "Action needed" first, then ACTIVE barking events (needs a decision). Optional setup and "worth checking" growls are deliberately excluded (no false barking). Problem/recommendation come from gate.currentHelp/limitation and event.what_happened/what_to_do. Pure, unit-tested (`tests/homeAttention.test.ts`).

**Gate terminology (`gates.ts`):** "Ready to check" → "Manual check", "Setup available" → "Setup required" (Watching/Action needed/Limited/Off unchanged). Updated `guard.tsx`, `settings/index.tsx` fallbacks and the label tests.

**Patrol "needs you" tightened:** `matchesPatrolFilter("needs_you")` is now barking-only (a growling "worth checking" item is no longer a "Needs you" decision). Tests updated.

Verified: `tsc` clean, ESLint clean, all touched/new unit tests green (gatesOverview, phase2Patrol, messageGuardrails, homeAttention). Pre-existing unrelated failures (app.json-based navigation/source-scan/brand tests) confirmed present at baseline with changes stashed. Home + notification only render on a production Android build (web preview is fail-closed Safe Start).


## Check screens — compact "Find out more" about headers (2026-06)

Replaced the wordy intro/about paragraphs at the top of every check screen with a compact header: a short title + a "Find out more" link that opens a popup (Sheet) holding the full detail. New reusable component `src/components/GateAbout.tsx` (title, optional `control` slot for an inline switch, optional `sheetTitle`, children = popup detail). Applied to: Call Gate (`call-guard-auto`, keeps the auto-check toggle as the `control`), Text/Email Gate (`message-privacy`), Internet Gate (`network-cannot-see`), App Gate (`app-check-scope`), Email Gate (`email-processing-scope`), Check My Accounts (`monitor-intro`), Device Gate (`device-gate-scope`), Link Gate (`check-privacy-scope`), File Gate (`file-inspection-scope`), Higgins Re-check (`recheck-intro`). Original testIDs preserved on the GateAbout card; the link adds `<testID>-more`. Each popup also shows a "WHAT TO LOOK FOR" tip block (`tip` prop, testID `<testID>-tip`) with a short, concrete example of warning signs for that gate. No logic/engine changes. tsc + ESLint clean. Visual check only on an Android build (web preview is fail-closed Safe Start).


## Unify Saved Items + Text Gate Messages-style picker (2026-06)

**Unify Saved Items:** App Gate saved reports now appear in the single **Saved checks** list. `savedCheck.ts` gained gate `"app"` (GATE_LABEL "App check"). `app/saved-checks.tsx` loads both `listSavedChecks()` and `listAppReports()`, maps app reports into the SavedCheck shape (`fromAppReport`), merges newest-first, and routes delete to the right store. App Gate's save button + intro now point to `/saved-checks` (old `/app-reports` route left in place but unreferenced). Check It "Saved checks" card copy updated to include app checks.

**Text Gate — Messages-style inbox picker (Android, READ_SMS):**
- Investigated access: the native `listRecentSms()` (READ_SMS, on-demand, already in `phonePickers.ts`) returns a flat `{address,body,date}` list — no unrestricted Google Messages inbox API exists, so a familiar inbox is built by **grouping client-side** (no new native infra). Where READ_SMS is unavailable/denied/off-build, the person is routed to **Share → Apollo** (existing share intake).
- `src/domain/smsConversations.ts` (pure, 4/4 tests): `groupSms` (group by sender, conversations newest-first, messages oldest→newest), `filterConversations` (search sender+body), `timeLabel`, avatar initials (letters→initials, numbers→last two digits).
- `app/message-picker.tsx` (new full screen, replaces the cramped bottom sheet → fixes overlap/unresponsive-row issues): conversation inbox (avatar, name/number, preview, timestamp, search) → tap → chat-bubble thread → **Check with Apollo** on a single incoming message → `router.replace("/message", { text, sender, source: "inbox_picker" })` which auto-runs the scam analysis. Never selects a whole thread. Full permission contract (checking/need_permission/requesting/denied/unsupported) with Share fallback. No message content persisted or logged.
- `app/message.tsx`: "Pick a text from your inbox" now pushes `/message-picker`; removed the old SMS `PhonePickerSheet` usage/state (Call Gate still uses the sheet).

**Note:** The re-pasted App Gate Investigation brief was already fully implemented earlier (two-layer summary, evidence-backed permission findings, direct Android settings per permission, re-verify-on-return, qualified Higgins language) — see the earlier PRD entry; no further change needed.

**Verification:** tsc + ESLint clean; tests — smsConversations 4/4, savedCheck 2/2, appPermissionFindings 7/7, gatesOverview 17/17, messageGuardrails 6/6, gate7 44/44, systemHealth 5/5 (no regressions). App bundles (expected Safe Start). The inbox picker, READ_SMS flow and selection round-trip verify on a physical Android build.


## Saved Checks Everywhere + Settings reorganisation (2026-06)

**Saved Checks Everywhere (link / message / internet):**
- `src/domain/savedCheck.ts` (pure, 2/2 tests): `SavedCheck`/`buildSavedCheck` (drops empty sections, stamps savedAt) + `GATE_LABEL`. `src/store/savedCheckStore.ts`: local save/list/delete, cap 40, newest first, no server.
- "Save this check" button added to `app/check.tsx` (link), `app/message.tsx`, `app/network.tsx` result actions — builds a snapshot (title, subject, state, summary, recommendation, sections: why/signals/technical/intelligence). After saving the button becomes "Saved ✓ — View saved checks".
- `app/saved-checks.tsx` viewer: lists all saved checks (gate label + subject + time), inline-expands to full sections, per-item delete. Entry point: new "Saved checks" card on the Check It tab (`check-it.tsx`, bookmark icon).

**Settings reorganisation (`app/settings/index.tsx`, full rewrite per brief):**
- Replaced the long stack of separately-framed cards with 6 concise grouped cards of slim rows (reusable in-file `NavRow`/`SwitchRow`, 48px targets, chevron/switch/badge — not all three):
  - **Protection & permissions** — "Website protection" nav row → Gates (`/(tabs)/guard?gate=site`); the Android Site Gate VPN enable action shows only when setup is required (no redundant healthy status card; no "Protection on"/unverified "Watching").
  - **Alerts & voice** — security-alert OS label (never a delivery claim) + contextual allow/open-settings, Preview an alert; Quiet hours toggle (times when enabled); Higgins voice toggle + Hear a sample.
  - **App preferences** — Battery saver toggle (never implies protection off); Minimise Apollo as a row.
  - **Family & trusted links** — Family sharing → /family; Trusted links count with inline expand + per-link revoke (one exact link, never overrides a confirmed threat), empty "No trusted links".
  - **Privacy & data** — Privacy statement is now a single tappable row → `/privacy-disclosure` (removed the inline `PRIVACY_POLICY_SUMMARY` bullet list from Settings only; disclosure page unchanged); Clear Patrol history (keeps the confirm dialog). Anonymous device reference removed from Settings (lives in Support).
  - **Help & about** — Get help → /support; How to share into Apollo as a brief expandable help row; concise About Apollo (Harmony Wellness Group; Apollo checks/protects, Higgins explains). "Support Apollo" contribution card feature-gated behind `SHOW_CONTRIBUTION = false` (no live payments).
- All functional testIDs preserved (push, quiet, higgins, battery/minimise, family, trust/revoke, clear-patrol, support, site-enable/status, alert-preview). systemHealth settings test still passes.

**Verification:** tsc + ESLint clean; tests — savedCheck 2/2, appReport 1/1, appPermissionFindings 7/7, gatesOverview 17/17, systemHealth 5/5, messageGuardrails 6/6 (no regressions). App bundles (expected Safe Start). Saved-check persistence and the reorganised Settings verify fully on an Android build.


## Saved App Reports + summary-first Internet Gate (2026-06)

**Saved App Reports (App Gate):**
- `src/domain/appReport.ts` (pure, 1/1 test): `AppReportSnapshot` + `buildAppReportSnapshot` — a faithful on-device copy of a completed App Gate investigation (identity, permissions+statuses, why, network, reputation, evidence, severity, coverage/limits). Keeps the honest coverage caveats; a saved report is never a safety guarantee.
- `src/store/appReportStore.ts`: local `saveAppReport`/`listAppReports`/`getAppReport`/`deleteAppReport`, capped 30, newest first. No server storage.
- `app/app-check.tsx`: "Save this check" button in secondary actions (snapshots current result + derived sections); after saving the button becomes "Saved ✓ — View saved checks". Intro has a "Saved app checks" link.
- `app/app-reports.tsx`: list of saved checks with inline full detail (same organised sections as the live full investigation) + per-item delete.

**Internet Gate summary-first (app/network.tsx):** result reorganised to outcome → **What to do** → the direct action (check sign-in page / check device / trust network) up top, with "Why Apollo reacted" + technical + scenario ref folded into a **View full details** toggle. Dropped the raw scenario pill and the redundant STATE_LABEL line from the summary (consistent with App Gate).

**Link/Site Gate (app/check.tsx):** already summary-first (decision headline → why → what-to-do → actions, technical in a sheet) — left as-is; it already matches the pattern.

**Verification:** tsc + ESLint clean; tests — appReport 1/1, appPermissionFindings 7/7, gatesOverview 17/17, gate7 44/44, messageGuardrails 6/6 (no regressions). App bundles (expected Safe Start). Saved-report persistence and the reorganised screens verify fully on an Android build.


## Gate Health Log + App Gate results redesign (2026-06)

**Gate Health Log:**
- `src/store/gateHealthLog.ts`: per-gate on-device history of "confirmed working" timestamps, recorded only when a gate's status is **Watching** (never fabricated). Throttled (1/10min per gate), capped (10). `relativeTime()` helper for friendly labels.
- `guard.tsx`: GuardScreen records working gates whenever `buildGatesOverview` reports Watching; each HealthCard shows a "Protection history" block — "Last confirmed working: X" + up to 3 recent timestamps, or "Not yet confirmed working" for gates never seen Watching.

**App Gate results redesign (app-check.tsx) — presentation + remediation only, engine untouched:**
- **Two layers.** Layer 1 summary card: Apollo status + app identity line (`result.sdk?.appName`/developer/source) + 2–3 sentence outcome + top 2 findings + the one primary action + prominent **View full investigation** toggle. Layer 2 (`showFull`): organised sections (Identity & provenance, Permissions & actual access, Why, Network, Reputation, Evidence & detection methods, Findings & severity incl. scenario ref + risk score, Confidence/coverage/limits, timestamps, raw technical) — all from existing data, no new scanning.
- **Evidence-backed permission findings** (`src/domain/appPermissionFindings.ts`, pure, 7/7 tests): maps the app engine's `permissionNotes` against the native SDK's `permissionStates`/`specialAccessStates` → `Access enabled — Review recommended` / `Access not allowed — No action needed` / `Permission requested — Access not verified` (grant unknown) / `Special access enabled — Review recommended` / `Current status unavailable` (SDK present, no evidence) / `Reported by you — …` (no SDK/iOS). Never guesses "granted". Replaces blanket "More than it needs".
- **Direct Android settings per finding** (`deviceSettings.ts` `permissionSettings()`): a "Review [X]" button opens the closest supported destination (overlay/notification-listener/accessibility/VPN/device-admin/unknown-sources/all-files screens, else app list) and shows the remaining navigation step ("then → <app> → Permissions") — honest that RN can't open another app's exact toggle. Desktop (Windows/macOS) and iOS show the path to follow.
- **Re-verify on return** (AppState listener): after opening Settings from a finding, on return Apollo re-reads that app's permission states (Android + picked package) and reports honestly — `confirmedResolved()` detects enabled→off ("Apollo confirmed: Camera is now off") or says it couldn't confirm. Never claims remediation just because the user came back.
- **Tidied actions**: primary action + View full investigation in the summary; Ask Higgins, recovery, device-check, mark-handled, report kept as secondary. Removed the raw scenario-code pill from the summary. Higgins/engine already use qualified language ("did not establish a specific concern…"); optional reviews stay ears_up/growling, never escalate to barking.

**iOS/desktop:** iOS cannot read other apps' permissions (OS limit) → findings reflect user-reported input and show the Settings path; re-verify is Android-only. Windows/macOS use the desktop adapter and path-guidance fallback.

**Verification:** tsc + ESLint clean; tests — appPermissionFindings 7/7, gatesOverview 17/17, messageGuardrails 6/6, accountMonitor 7/7, gate7 44/44 (no regressions). App bundles (renders expected Safe Start). Native deep-links, re-verify-on-return and the health log over time need an EAS Android build to verify on-device.


## Resolve & Snooze + Gate-status standardisation + Internet Gate (2026-06)

**Resolve & Snooze (Account Gate):**
- `accountMonitor.ts`: new `HandledMap`, `outstandingExposures(scan, handled)`; `deriveGateState` and `buildWeeklyReport` now take an optional `handled` map. A fully-handled address drops out of outstanding/gate-state and gets a "Marked as handled" report section; a brand-new breach name makes it outstanding again. `accountMonitorStore.ts`: `getHandled`/`markHandled`/`unmarkHandled`, cleared on email removal; `runScan` + on-open hook filter new exposures against handled so handled breaches never re-alert. Screen (`account-monitor.tsx`): "Exposures found" card with per-address Mark-as-handled / Mark-as-outstanding; report recomputed live from scan+history+handled. Test: `accountMonitor.test.ts` 7/7 (incl. handled behaviour).

**Gate-status standardisation (single source `src/domain/gates.ts`):**
- New 9 standard statuses replacing the old 10: **Watching** (good/green — verified active automatic protection ONLY), **Ready to check** (neutral — manual available), **Check in progress** (neutral), **Setup available** (neutral — optional, incl. permission/connection not yet granted; never an alarm), **Off** (grey), **Limited** (amber — active but restricted coverage), **Action needed** (red — verified failure of enabled protection), **Unavailable** (grey — unsupported), **Unable to verify** (amber — can't confirm from evidence).
- GateTone expanded to `good|limited|action|neutral|off|unavailable|unverified`; `gateTone()` maps to Pill tones (good→resting, action→barking, limited/unverified→ears_up, off/unavailable→unknown).
- Watching gating: `running && !manualOnly && !coverageLimited`. Manual-only gates (**Link, Account, File, App**) carry `manualOnly:true` → "Ready to check" even when active. Text/Call = Watching when their automatic handling is verified running. New `interrupted` automatic state (enabled+permitted but not operating) = **Action needed**; stale-but-operational = **Unable to verify**. Internet Gate without VPN = **Limited** (coverageLimited), with VPN = **Watching**. Email optional-not-connected = **Setup available**.
- Only tone `action` drives the "needs your attention" summary/primary/reduced-coverage — optional setup never barks (spec §6).
- **Home and Gates derive from the same `buildGatesOverview`**: `home.tsx` GateRow now renders `gate.statusLabel`/`gate.tone` directly (no independent recompute) → identical on both surfaces.
- **Higgins per-gate explanation**: `guard.tsx` HealthCard now shows an explanation heading + limitation + the correct action button for EVERY non-Watching state (not just attention), heading varies by tone (Needs your attention / Working with limits / Couldn't be verified / Optional — set up when ready / Turned off / Not available here / Checking).
- **Network Gate → Internet Gate** (user-facing only; internal `network`/`connection`/route unchanged): `gates.ts` TITLE + purpose, `network.tsx` header, `checkIt.ts` label ("Check my internet", Wi-Fi/mobile data), `higginsChecks.ts`, `app-check.tsx` copy, `appAnalysis.ts` recommendation, Desktop/Web adapter capability titles, healthStore placeholder title.
- Tests updated: `gatesOverview.test.ts` 17/17 (new labels, interrupted→Action needed+reduced coverage, manual gates Ready to check, optional setup not an alarm, Internet Gate Limited/Watching), `messageGuardrails.test.ts` ALLOWED_GATE_LABELS updated 6/6. Consumers updated: `ask.tsx`, `ApolloHero.tsx`, `healthStore.ts`.

**Native capability/evidence gaps (deliverable #7):** status derivation relies on the native SecurityPlatformAdapter (`protection.operational`/`lastVerified`, capability `status`, `messaging`/`calls`, `network.vpnActive`/`inspectable`). Web preview is fail-closed (Safe Start) so these states, the `interrupted`→Action-needed path, and Internet Gate Wi-Fi/mobile reporting can only be visually verified on an EAS Android build.

**Verification:** tsc + ESLint clean; node --test suites: accountMonitor 7/7, gatesOverview 17/17, messageGuardrails 6/6, gate3–8 + messageAnalysis + firstCheck + support + messageVoice + higginsGreeting all pass; app bundles (renders expected Safe Start). On-device Android build needed to confirm live gate states.


## Account Gate — exposure monitoring BUILT (2026-06)

Built the full personal account-exposure monitoring feature with XposedOrNot (free, no key); HIBP is a drop-in for later.

**Backend:**
- `services/breach_check.py` — provider-agnostic: `scan_email(email)` routes to HIBP when `HIBP_API_KEY` is set, else XposedOrNot (`/v1/check-email/{email}`, rate-limited 0.6s floor, serialized). Honest statuses clear/found/unavailable; never fabricates "clear" on failure; no passwords/secrets. `active_provider()`/`source_label()` carry attribution.
- `POST /api/account/monitor/scan` (in `routers/analysis.py`, device-auth, bounded): body `{device_id, emails[≤10]}`; validates each address; returns `{provider, source_label, checked_at, results:[{email,status,breaches:[{name,date}],password_exposed,detail}]}`. Live-verified: `test@example.com`→found(25), random→clear, `notanemail`→unavailable.

**Frontend:**
- `src/domain/accountMonitor.ts` (pure, unit-tested 6/6): `maskEmail`, `isDue`/`DUE_MS`(7d), `scanSummary`, `deriveGateState` (8 states: not_set_up/monitoring/checking/no_exposure/exposure_found/action_needed/unavailable/overdue), `diffExposures` (new vs resolved), `buildWeeklyReport` (Higgins Weekly Account Exposure Report — sections accounts monitored/new/exposures found/no-longer-showing/couldn't-check/what-to-do/coverage; generated even when clean; partial coverage flagged; never leaks raw email — masked only; attributes source).
- `src/store/accountMonitorStore.ts` — local persistence: monitored emails (add/remove, cap 10), last scan, scan history (cap 12), last report, lastCheckedAt. `runScan(deviceId)` calls backend, diffs vs previous, builds+persists report; preserves prior good scan on total failure.
- `app/account-monitor.tsx` — "Check My Accounts" screen: status card, monitored-email management, "Check my accounts now", weekly report render, XposedOrNot attribution + "exposure ≠ compromise" / "not found ≠ secure" copy.
- `src/hooks/useAccountMonitorDueCheck.ts` — on-app-open due check (mounted in `(tabs)/_layout.tsx`): if emails exist and 7+ days elapsed, runs scan in background; raises ONE Patrol `account` event only for newly-appeared exposures (dedup); best-effort, never blocks app or overwrites good results.
- Check It tab (`check-it.tsx`): new dedicated "Check My Accounts" card → `/account-monitor`. Gates tab (`guard.tsx`): read-only "Account exposure" status card (controls live only in Check It), opens the screen.
- Egress: new `account_monitor` endpoint (`{device_id, emails}`) in `privacy.ts`; `/account/monitor/scan` added to client LONG_PATHS.

**History Card extended (P1):** "Your recent checks" `CheckHistoryCard` now wired into `app/app-check.tsx` (gate `app`), `app/network.tsx` (gate `network`) and `app/device.tsx` (gate `device`) — previously only Call/Message.

**Deferred:** HIBP wiring (P2) awaits the user's HIBP key — abstraction is ready, no code change needed beyond setting `HIBP_API_KEY`.

**Verification:** tsc + ESLint clean; `tests/accountMonitor.test.ts` 6/6; firstCheck 9/9, support 6/6, messageVoice 11/11, messageGuardrails 6/6, gate8 34/34 (no regressions); backend endpoint live-verified against real XposedOrNot data; web bundle compiled (2256 modules). NATIVE: UI not visually testable in web preview (fail-closed Safe Start — needs EAS Android build to verify on-device). On-app-open trigger + Patrol event need a device build to confirm end-to-end.


## Specific Gate Links + Check History Card + Scrub Everywhere (2026-06) + Account Gate PLAN

**Done & verified this session:**
- **Scrub Everywhere:** `scrubMessage` now also wraps saved-report overview/explanation (`app/saved-report/[id].tsx` + the report row in `InvestigationView.tsx`) and family alert headline/what_to_do (`app/family/alert/[id].tsx`). Live model/synced free text is scrubbed of internal codes everywhere it renders.
- **Specific Gate Links:** protection-health notifications (`localAlerts.protectionLocalAlert`) now deep-link to `/(tabs)/guard?gate=site`; `guard.tsx` reads the `gate` param and highlights the targeted gate card ("Opened from your alert", gold border).
- **Check History Card:** new `src/store/checkHistoryStore.ts` (per-gate, cap 10, plain-English summaries only) + `src/components/CheckHistoryCard.tsx` ("Your recent checks", outcome chip via `resultChip`). Wired into `app/call.tsx` and `app/message.tsx` (record on each manual check + render). Pattern ready to extend to app-check/network/device.
- Verification: tsc + ESLint clean; full suite 445/452 (same 7 pre-existing env/native/tab-order/brand-asset failures); Android bundle HTTP 200.

**ACCOUNT GATE — audit + agreed plan (NOT yet built; next build):**
- Audit: `/account/status` (reports `HIBP_API_KEY` configured bool — currently NOT set), `/account/breach` (real HIBP v3 breachedaccount, server-side key, honest not_configured/clear/found/unavailable, no passwords), `/account/analyse`. Frontend `app/account.tsx` = one-shot manual lookup, no persistence/monitoring/weekly/report.
- User decisions: (1) Provider = **XposedOrNot** (free, documented) for dev/testing now; **HIBP wired later** when key provided. (2) Weekly check = **on-app-open "due check"** (runs when app opens and 7+ days elapsed) — must be labelled truthfully (OS may delay; not a guaranteed background job). (3) Sequencing: the two follow-ups first (done) → then Account Gate.
- MUST route XposedOrNot through `integration_expert` before coding (free API: `https://api.xposedornot.com/v1/check-email/{email}` + breach-analytics endpoint; attribute + respect rate limits).
- Phases: (A) backend monitored-accounts (add/verify/enable-weekly/remove/status) + scan storage + XposedOrNot provider abstraction (provider-agnostic so HIBP drops in) + findings diff/persistence; (B) Check-tab Account Gate card (monitored count, last check, unresolved count, weekly status, "Check My Accounts") + 8 states (Not set up / Monitoring enabled / Checking / No exposure / Exposure found / Action needed / Check unavailable / Monitoring overdue); (C) on-app-open weekly due-check that persists scan outcome, diffs vs previous (no dup alerts), never overwrites good results on failure, records Patrol activity; (D) **Higgins Weekly Account Exposure Report** generated from the actual stored scan (sections: accounts monitored, new exposures, previous exposures, outstanding, resolved, recommended actions, coverage/sources, next scan) — generated even when clean, explains failures instead of false-clean, partial coverage flagged, each report linked to its scan, history retained; Higgins interprets in plain English and distinguishes exposure vs confirmed compromise. Gates = passive status only (no manual controls); Check = manual only.
- Privacy: never store passwords/secrets; authorise each monitored address; opt-out removes data; keys server-side only; "no breach returned" ≠ "secure".


## Scan Gate Chat + History Everywhere (2026-06)

- **Scan Gate Chat (live free-text scrub):** `messageVoice.scrubMessage()` rewrites any internal-code token (snake_case / known map like known_threat→"website safety", ears_up→"worth a look") to plain English before display, and `console.warn`s in `__DEV__` so the source leak gets fixed too. Applied to EVERY Higgins free-text render in `InvestigationView.tsx` — turn/response overview, attentionReason, explanation (`plain()` now scrubs), findings text, uncertainties, scope, question text/reason, source retrieval, and the recheck observation note. This closes the one real remaining gap in the standing requirement: model-authored replies could previously echo a code.
- **History Everywhere:** `messageVoice.investigationHistory()` builds a plain-English, code-free progress list (opened → follow-ups → current status: investigating / waiting on you / completed within scope / partial / has a question / stopped), rendered as an "Investigation history" card (`inv-history`) in `InvestigationView.tsx`. Check results already carry history via Higgins Re-check diff; event detail has the `eventHistory` "Status history" card from the prior pass.
- Guardrails extended: `messageGuardrails` now asserts the investigation view live-scrubs `response.overview`; `messageVoice` tests cover `scrubMessage` and `investigationHistory`.

Standing-requirement status: substantially complete. §1 offenders all fixed; §2 examples honoured; §3 six-part standard applied on covered surfaces; §4 deep-links carry specific event ids (a couple of protection-health notices still open the Gates tab — minor); §5 surfaces covered; §6 acceptance enforced by automated guardrails incl. live free-text scrubbing.

Verification: tsc + ESLint clean; messaging tests 17/17; full suite 445/452 (same 7 pre-existing env/native/tab-order/brand-asset failures); Android bundle HTTP 200.


## Messaging follow-ups 2 — guardrails, timeline, smart links, inbox (2026-06)

Notification naming check: PASS — all notification copy uses "Apollo" (+ retained "Apollo is barking/biting/growling" vocabulary); no "guard dog"/"guarddog" in `src/push`.

- **Expanded guardrails** (`tests/messageGuardrails.test.ts`, now 6 tests): added (1) Gate-alert coverage — every `buildGatesOverview` presentation's statusLabel is from the allowed set, currentHelp/purpose/limitation carry no code, and primaryAction has a non-empty label+id to route with; (2) Higgins-reply coverage — `assessmentLabel`/`attentionLabel` cover all enums with no raw passthrough, and a source assertion that `InvestigationView.tsx` never interpolates raw `assessment`/`attention` enums.
- **Status Timeline**: `messageVoice.eventHistory()` builds a plain-English, time-ordered history (detected → updates → resolved), replacing the raw "Issue timeline" in `app/patrol/[id].tsx` with a "Status history" card that always shows (even with one revision) and never leaks a revision code.
- **Smart Reply Links**: notification deep-links now carry `?focus=alert` (`localAlerts.ts`); `patrol/[id].tsx` reads `focus` and shows an "Opened from your Apollo alert" banner pre-selecting that exact finding.
- **Support Inbox**: `supportReference.ts` records a reference history (cap 25) on every mint/new-request; `reopenSupportReference` makes a past reference current again; Support screen shows a "Past requests" list (`support-inbox`) with a Reopen action.

Verification: tsc + ESLint clean; messageVoice+guardrails 15/15 (incl. eventHistory); full suite 443/450 (same 7 pre-existing env/native/tab-order/brand-asset failures); Android bundle HTTP 200.


## Messaging audit — Phases 2–4 + Email copy (2026-06)

Completed the four follow-ups to the Phase-1 message-voice foundation:

- **Finish The Sweep:** Higgins investigation verdicts no longer show raw enums — `messageVoice.assessmentLabel`/`attentionLabel` map them to plain English in `InvestigationView.tsx` (assessment/attention Pills), and the action note no longer exposes raw observation status/`unavailableReason`. Check results already use proper STATE label maps (raw intel values stay under the "Technical details" expander, which the spec permits). Onboarding title fixed earlier; error copy is already friendly.
- **Universal Deep Links:** Notifications deep-link to the exact event (`/patrol/{id}`), and the Home/Apollo status reason now carries `reasonRoute` to the specific driving event instead of a generic tab (`stateMachine.ts`). Patrol list/detail already route by event id.
- **Message Guardrails:** NEW `tests/messageGuardrails.test.ts` (4 tests) fails the build if any generated message leaks an internal code (`looksLikeInternalCode` across every category×state×verified), overstates a block without verified enforcement, or routes to a non-existent screen (checks the deep-link target route file exists). Covers `projectedEventVoice`, `patrol_sync` egress output, `resolveApolloState` reasons, and `eventLocalAlert` routing.
- **Email Me A Copy:** Support screen has an optional "Your email (for a copy)" field, persisted (`apollo.support.user_email.v1`); `openSupportEmail` CCs the user (MailComposer `ccRecipients` + mailto `cc=`), so a copy lands in their inbox as well as their Sent folder.

Verification: tsc + ESLint clean on all touched files; new guardrails + messageVoice 12/12; full suite 440/447 (same 7 pre-existing env/native/tab-order/brand-asset failures, none messaging-related); Android bundle HTTP 200.


## Apollo-wide message & event-messaging audit — Phase 1 + partial 2/3 (2026-06)

Standing requirement: every user-facing message answers What/Where/Why/What-Apollo-is-doing/What-to-do/Where-to-go, never leaks internal codes, never overstates status, and deep-links to the exact record. Root cause of the screenshot ("known_threat check", "ears_up", "Something changed", "server_projection_of_recorded_outcome") was the privacy/sync projection layer substituting code-exposing text that the UI rendered verbatim.

**Phase 1 (done, tested) — central voice + generation fix:**
- NEW `src/domain/messageVoice.ts` — single source of truth: `areaLabel` (category→plain, e.g. known_threat→"a website safety check"), `resultChip` (ears_up→"Worth a look", not "Something changed"), `sourceLabel` (user_started→"Started by you"), `displayStateLabel` (PatrolDisplayState→plain, no snake_case), `humanizeReason` (strips snake_case codes like server_projection_of_recorded_outcome, keeps genuine prose), `apolloStatusLabel` (never "stopped" without verified block), `projectedEventVoice` (privacy-preserving synced-event text with zero codes/detail leak), `looksLikeInternalCode`.
- `privacy.ts` (authoritative patrol_sync egress) + `patrolPayload.ts` now emit `projectedEventVoice` text — no raw category/state codes on the wire or on any device that renders the projection.
- `patrolOutcomes.ts`: `result()`→resultChip; investigation title no longer generic "completed an investigation update" (evidence-based); resultBasis via `humanizeReason`.
- `app/patrol/[id].tsx`: humanises title/what-happened/what-to-do/read-aloud for any already-synced cached event that still carries codes; source + timeline use plain labels.
- Tests: `tests/messageVoice.test.ts` 8/8; updated `p0TruthPrivacyFile` verified-block headline.

**Phase 2/3 (partial, tested):**
- `stateMachine.ts` barking/growling/ears_up reasons now name the area ("A phone call needs your decision.") instead of "Something needs your decision."
- `localAlerts.ts` notifications deep-link to the specific event (`/patrol/{id}`) not a generic tab (retained dog-vocab titles kept).
- `InvestigationView.tsx` action note no longer exposes raw observation status/`unavailableReason` codes.

**Remaining (not yet done):** Gates alert tone (optional setup like Email-Gate-not-connected must not bark), Home dashboard status surfaces, Check results wording, Higgins conversation surfaces, onboarding/permissions/error messages, universal deep-linking for every message type (gate details, Check result, permission screens, Support), and automated routing/consistency tests. Then the "Copy of support email to user" item (user chose: CC the user + Sent copy; capture email once in Support).

Verification: tsc + ESLint clean on all touched files; full suite 436/443 (7 failures are pre-existing/environmental — app.json missing for iosSourceReadiness, native-bridge/iOS-config/tab-order/brand-asset source assertions — none reference the message layer). Android bundle HTTP 200.


## Support screen enhancement + Apollo naming standard (2026-06)

**Apollo naming standard** — Customer-facing wording uses "Apollo", internal `GuardDog` identifiers retained (per rule). Thorough repo scan done: the ONLY user-facing rendered "guard dog" string was the onboarding hero title → now "Meet Apollo, your calm guard dog for the links you tap." (keeps the allowed dog metaphor). App display name is already "Apollo"; notifications already say "Apollo". All other ~249 hits are internal (Kotlin `com.guarddog.*`, class/method names, `guarddog_production` env, config plugin, SharedPreferences keys) or code comments — correctly left untouched. The email body keeps the spec-mandated product descriptor "Apollo Cyber Security Guard Dog".

**Support screen (app/support.tsx, full reorganise into 5 collapsible sections):**
1. App & Device Details — real metadata via expo-application/expo-device/expo-updates (`src/support/supportInfo.ts`). OTA bundle date vs native install/update dates reported distinctly; unknown → "Unavailable"; preview builds flagged, never fabricated. Kept `support-version`/`support-build`/`support-more-details-panel` testIDs.
2. Protection & Services — plain-English states from `ProtectionStatus`/`NetworkStatus`/`EnforcementEvidence`/intel (`buildProtectionRows`). A reachable/enabled service is never shown as a verified block; only "Active and verified" = OS-confirmed enforcement; preview = "Available".
3. Protection Issues & Higgins Checkup — last checkup time/result/warnings + missing permissions + the 4 system-health rows (display only). "Check now" replaced with **Go to Check** → Check tab. Higgins Re-check now also refreshes system health so Support reflects it.
4. App Logs & Diagnostics — View recent activity, Copy Support Summary (expo-clipboard), Export Higgins Diagnostic Report (expo-print + expo-sharing). Redacted: only status/counts/dates, no credentials/tokens/browsing history.
5. Contact Apollo Support — **Email Apollo Support** to support@harmonywellnessgroup.com.au via expo-mail-composer (mailto fallback with correct encoding + oversize guard; Copy Summary fallback when no email app). Never auto-sends, never auto-attaches. Subject `Apollo Support [AP-YYYYMMDD-<128-bit hex>]`; reference minted with expo-crypto CSPRNG (`src/support/supportReference.ts`), reused on reopen, new on "Start a new support request"; identical reference across subject/body/report.

New deps: expo-mail-composer. New modules: src/support/{supportReference,supportInfo,supportSummary,supportEmail}.ts. Tests: tests/support.test.ts (6/6 — protection states, preview truthfulness, higgins merge, shared reference, redaction, reference format). tsc + ESLint clean; firstCheck 9/9, systemHealth 4/4 (incl. updated Go-to-Check assertion), gate7/higgins 67/67; Android bundle HTTP 200. Note: tests/iosSourceReadiness.test.ts fails at load reading app.json (generated only at build time) — pre-existing env issue, unrelated.


## Higgins First Check + Re-check (2026-06)

- **Problem:** Apollo must never assume a newly installed device is clean. Added an onboarding malware/virus/compromise BASELINE assessment ("Higgins First Check") and a manual "Higgins Re-check" in the Check tab, per the owner's detailed spec. Point-in-time, capability-based, local-first — NOT an antivirus engine and NOT a background scanner.
- **Architecture (all frontend):**
  - `src/domain/firstCheck.ts` — pure, unit-tested engine. Per-check states PASS/INFORMATION/CAUTION/SUSPICIOUS/CONFIRMED_THREAT/NOT_AVAILABLE/ERROR; overall CLEAR/ATTENTION/HIGH_RISK/CONFIRMED_THREAT/LIMITED_CHECK/ERROR. Checks: apollo_integrity, device_integrity (root/jailbreak — NOT_AVAILABLE on current build, never upgraded to PASS), application_risk (Android signals only; iOS/web NOT_AVAILABLE), network_config (VPN/profile/cert), os_security (OS version = INFORMATION only). `deriveOverall` + `diffFirstCheck` + Higgins copy. **Heuristics alone can never produce CONFIRMED_THREAT** — only a deterministic `osReportedThreat`.
  - `src/security/firstCheckSignals.ts` — collector reusing existing Diagnostic Core adapters (`AppDeviceSdk.getDeviceSecuritySignals`, `securityAdapter.getProtectionStatus`/`getDeviceProfileFacts`). No new native subsystem; nothing uploaded. Collection failure → honest ERROR report.
  - `src/store/firstCheckStore.ts` — local baseline + history (cap 30), reuses `storage`.
  - `src/components/FirstCheckResult.tsx` — shared result UI (checked / found / couldn't-check), embeds `GateInvestigation` for the AI/Higgins plain-English pass (owner chose on-device signals + AI summary).
  - `app/first-check.tsx` — onboarding screen. Onboarding order is now setup-gates → `/first-check` (runs baseline, saves it) → `/(tabs)/home`. Never shows all-clear before First Check completes; a concern never blocks entry.
  - `app/recheck.tsx` + Check It card ("Higgins Re-check") — manual re-run, diffs against previous baseline, auto-runs the AI pass, saves to history. Not duplicated in Gates.
- **Also (P1):** "Trust this number" / "Trusted — tap to remove" button added to the Call Gate RESULT card (`app/call.tsx`), not just the picker overlay.
- **Verification:** `tsc --noEmit` clean; ESLint clean on all touched files; `tests/firstCheck.test.ts` 9/9 (CLEAR/ATTENTION/HIGH_RISK/CONFIRMED_THREAT/LIMITED/ERROR + NOT_AVAILABLE-never-PASS + re-check diff); gate7/higginsChecks regressions 67/67; Android Metro bundle compiles (HTTP 200). Testing agent NOT used (project rule: not authorised without explicit owner approval; web preview is fail-closed for native). Device-side behaviour of native signals needs an EAS Android build to confirm.


## Expo preview startup crash correction (2026-10-02)

- **Problem:** The boot heartbeat passed `locale` from `deviceMeta()`, but the frontend `device_register` privacy allow-list omitted that backend-supported field. Egress validation throws synchronously, before the previous `.catch()` existed, so startup emitted an unhandled `EgressViolation` that could be reported as a preview crash.
- **Correction:** The egress contract now includes the backend `DeviceRegister.locale` field, remains deny-by-default for unknown fields, and heartbeat construction runs inside its contained Promise chain so a future contract mismatch cannot escape boot.
- **Verification:** TypeScript and ESLint pass; focused privacy/security tests pass 13/13; bounded backend health pytest passes 12/12; `/api/health` is healthy; Android Metro bundle generation succeeds; fresh external preview reaches Home without an error fallback or fresh `EgressViolation` console entry. Independent iteration 77 repeated the cold-load, console, privacy, security-boot, Android bundle and health checks with no startup-crash regression. Backend pytest discovery is now location-independent through `backend/pytest.ini`; the tester's root-directory invocation passes 6/6.
- **Expo Go boundary:** Apollo requires its custom native security module. Expo Go cannot load that module and therefore remains intentionally fail-closed on the existing Safe Start screen; native protection must never be simulated to make Expo Go appear operational.

## Android EAS/CNG build input follow-up (2026-09-24)

- **Problem:** Android APK build reported `script: line 199: expo: command not found`. The complete failed-build log/build ID is unavailable in this workspace; a previous preparer emitted this *same* message non-fatally (`docs/APOLLO_BUILD_RECORD.md`). Do not assign an unverified root cause or claim an APK was built.
- **Source correction:** The locally present, untracked npm `package-lock.json` has been deleted and excluded by `.gitignore` and `.easignore`, preserving Yarn 1 and its updated `yarn.lock`. CI now rejects either tracked CNG native folder or a competing npm lockfile. `frontend/android/gradle/wrapper/gradle-wrapper.jar` remains deleted in the working tree and needs a saved source commit to disappear from Git's tracked index. An existing local generated `ios/` folder is ignored and excluded from EAS; it was not modified.
- **Verification:** `yarn install --frozen-lockfile`, staging EAS pre-install security preflight, Expo SDK 57 config/app ID, TypeScript, bounded backend health pytest, and CNG/build-input checks pass. No EAS cloud run or physical-device acceptance was available. Standard npm/Yarn scripts have the local Expo binary on PATH; project pre-install hooks do not invoke `expo` directly. The external preparer message cannot be fixed by changing npm script spelling alone; a fresh EAS build with its full terminal log is still required to verify resolution.
- **Static deployment scan boundary:** The generic scanner still reports ignored `.env` secrets, the read-only proxy supervisor without `--tunnel`, and deliberate short-lived OAuth CSRF state expiry as blockers. None is evidence of the reported APK CLI failure. Committing the owner key or weakening CSRF cleanup would contradict product security requirements; these were not changed.
- **P0:** Save deletion of the final tracked native JAR and build-input changes to source, then retry an Android APK build and identify the *fatal* failing step (not just the preparer warning). **P1:** Physical-device Android acceptance. **P2:** Decide the future of family/remote push routes.

## P0 in-app Apollo and Higgins health check (2026-09-24)

- **Problem:** Replace production benchmark/acceptance and alert-delivery test controls with one truthful, manual, owner-scoped four-part health check on Support. Keep Android CNG/JAR cleanup as a separate repository task.
- **Architecture:** `/api/health` is strict public DB-independent schema-1 liveness (`service: apollo-v1`); `/api/health/readiness` is bearer-protected and maps database, maintenance, queue, privacy cleanup, encrypted report store and existing owner-configured Gemini provider into bounded codes. `/api/health/higgins-checks` has the documented minimal 202 admission (checkId/state/createdAt/expiresAt) and a terminal response with a top-level cleanup status; it accepts an empty body, device-scoped idempotency key and a 15-minute cooldown. A durable content-free job invokes the existing Higgins Gemini client exactly once with a fixed fictional scenario, validates with the existing schema/redaction, round-trips through the same encrypted Saved Report store, explicitly deletes its separate TTL-backed artifact and verifies absence. Stale jobs are recovered without repeating provider calls. No user content or provider answer is persisted in diagnostic job documents.
- **Mobile:** Support has one four-result health card with the required Working/Needs attention/Could not check labels, observed timestamps, one primary Check now action and technical data behind More details. Both ordinary saved reports and the synthetic fixture share one escaped PDF preparation path; the diagnostic file is disposed after validation. A cached Higgins result is labelled earlier/degraded. Production benchmark and GuardDog acceptance routes, mobile benchmark corpus/code, and Settings test-delivery button are removed; benchmark corpus is now backend test-only.
- **Verification:** Backend full `pytest -q`: 414 passed, 16 skipped. Targeted health suites: 24 passed. Frontend: TypeScript, ESLint and 451 Node tests pass; native singleton guard and CNG source preflight pass. The **one** authorized live backend owner-key Higgins diagnostic completed with encrypted report round-trip and zero retained temporary artifacts; the key value and provider text were never output. Android/iOS device PDF rendering, real UI interaction and native build acceptance remain **PENDING**; use a supported device/build host before claiming them.
- **P0 remaining:** Independently reviewed CLI/source acceptance contract; verify native device-side PDF preparation and user interaction on supported builds. Commit the already-deleted final `frontend/android/gradle/wrapper/gradle-wrapper.jar` separately; it is still tracked in Git until committed.
- **P1/P2 backlog:** Re-evaluate device-side PDF retention on physical iOS/Android and privacy cleanup monitoring. Existing family/remote push routes remain unchanged pending a separate product decision.

## Android Firebase removal / CNG handoff (2026-09-24)

- **Problem:** Remove Apollo-owned Google Services configuration and Expo remote push registration without losing local protection alerts or modifying GuardDog enforcement, evidence, Higgins diagnostics, or signed trust/rules.
- **Architecture:** `app.json` no longer references Google Services; the GuardDog Kotlin serialization config plugin no longer relies on the Google Services Gradle anchor. Local notification permissions, channels, Apollo sounds and evidence-gated on-device alert scheduling remain with `expo-notifications`. The frontend no longer registers Expo push tokens. Backend family-alert/owner push routes remain unchanged pending a separate delivery decision.
- **CNG safety gate:** Before deleting the 47 tracked `frontend/android/` files locally, a clean temporary Android prebuild reproduced 42 files byte-for-byte, omitted only the Firebase JSON file and changed four generated files solely for Google/FCM metadata removal and preserved Kotlin serialization. Autolinking, module manifests, notification sounds, permissions and the frozen GuardDog 91/91 checks passed. `.gitignore` and `.easignore` already exclude `/android`. Evidence: `/tmp/apollo-cng-parity.2N89Fe/parity-audit.json` (temporary; rerun after a workspace reset).
- **Verification:** Final clean Android prebuild and generated-project check pass using nonproduction CI trust fixtures. TypeScript, ESLint, 443/443 Node tests, CNG source preflight and native dependency guard pass. Android `:app:assembleDebug` did **not** compile here (no JDK/Android SDK); Android JS bytecode export did **not** complete (ARM64 host versus bundled Hermes compiler). Neither launch nor local alert delivery/sounds, background behavior, runtime Firebase logs or physical enforcement have been verified on a device.
- **P0 handoff:** The 47 native paths are deleted in the working tree but remain tracked in Git until the deletion is committed. Compile a clean CNG Android project with release-owner trust inputs in a compatible Android/JDK toolchain before claiming build success.
- **P1 owner acceptance:** Validate Android launch, local protection/Higgins alerts, sound/channels, true packet-proof-only Biting and runtime logs on a physical device. Local JS alerts need an active observation path; closed-process VPN-event alert delivery must not be assumed without device/native verification. Decide separately whether existing backend Expo family/owner delivery remains part of the product.

## Apollo brand logo and app icon (2026-09-23)

- User-supplied shield-and-guard-dog artwork now drives the in-app Apollo logo, iOS/legacy Android icon, Android adaptive foreground and web favicon.
- Native variants use platform-safe padding; the iOS icon is opaque and Android adaptive foreground is transparent over Apollo's configured `#F5F7FA` background.
- Original artwork is preserved and variants are reproducible with `frontend/scripts/prepare-apollo-logo.py`.
- Launch splash remains unchanged because the confirmed scope was the in-app logo plus app icon.

## Apollo downloadable media kit (2026-09-23)

- Public gallery and ZIP now expose 28 faithful screen exports plus 12 state GIFs.
- Media is reproducible with `frontend/scripts/generate-apollo-media-kit.py` and served from `frontend/public/apollo-media-kit`.
- The existing dark preference currently uses the Light Sentinel palette, so light/dark export pairs intentionally match source rather than inventing an unsupported theme.

## Gmail production OAuth readiness (2026-09-23)

- Production callback: `https://threat-patrol-1.emergent.host/api/gmail/oauth/callback`; Gmail API scope remains exactly `gmail.readonly`.
- OAuth state is now opaque, hashed, single-use and TTL-limited; redirect destinations are allow-listed and expanded Google scope sets are rejected.
- Unreadable legacy refresh grants are deleted safely and require explicit reconnect; mailbox scans with no connection return a truthful 404.
- P0 external/user action: refresh the hosted backend to the latest source, then have an allow-listed Google test user complete **Connect Gmail read-only**. Restricted-scope verification/custom-domain ownership remains necessary before unrestricted public OAuth access.

## Higgins Apollo transactional email (2026-09-23)

- Migrated guardian invitations/alerts from owner-managed Resend credentials to the platform-managed verified transactional sender.
- Sender identity: `Higgins Apollo`; no Reply-To inbox configured.
- Backend retains stable event idempotency and truthful delivery receipts; caller cannot supply subject or HTML, and all templates pass a structural credential/link safety gate.
- Provider-owned test-sink submission and the authenticated guardian invitation route both returned provider acceptance references.

## FF10 Family Help — configuration-gated source complete (2026-09-23)

### Problem statement
Let one paired family helper watch an owner-consented mobile screen session without control, audio or recording, while the backend owns authorization, lifecycle and time limits and no media/SDP/ICE enters durable product storage.

### Architecture implemented
- FastAPI/MongoDB owns relationship/device authorization, revisions/generations, invitation/consent/active deadlines, stale callback rejection, one-session concurrency, single-use WSS tickets, closed bounded signaling and minimal terminal events.
- A server-only Cloudflare broker requests temporary `iceServers` through the Cloudflare Calls TURN credential API. Provider token/Key ID stay server-only; response fields/hosts are strictly validated; credentials last at most one hour and are refreshed natively before an ICE restart. Generic coturn realm/shared-secret settings are ignored.
- Apollo-owned Expo module uses Android MediaProjection + foreground service and iOS ReplayKit Broadcast Upload; WebRTC frames and helper rendering remain native. First release has no microphone, system audio, recording, remote control or data channel.
- Mobile routes cover overview, helper/scope selection, invitation wait, accept/decline, native consent, owner pause/resume/extend/stop, helper view and neutral pause state.

### Backlog
- **P0 application source:** none identified for configuration-gated FF10.
- **P1 sole activation dependency:** an authorised infrastructure operator places the associated Cloudflare TURN API token directly in server secrets and runs `docs/FF10_TURN_DEPLOYMENT_SPECIFICATION.md` preflight, then performs two-device forced-relay acceptance. Until then Family Help stays unavailable.
- **P2 external evidence:** Apple Xcode compile/signing, physical-device lifecycle, NAT/relay matrix and production capacity/incident drills.

## Phase 2 execution — authorised baseline (2026-09-22)

### Controlling scope
- `Apollo_Consolidated_Architecture_and_Execution_Mandate-3.md` Phase 2 execution cover controls current work.
- Exact pre-change source HEAD: `d1ab4ff22f7476fefd3999e6c292c3ac92f2e30b` on local `main`; no remote/upstream is configured in this workspace.
- M1–M4 remain complete. Execute only P2.1–P2.6, using C19–C25 and V27–V36 as the active register.

### Architecture and delivery order
- **P2.1:** remove SecureCore completely; ship Home, Higgins, Gates, Check It, Patrol navigation with shared top-right Settings.
- **P2.2:** replace manual/automatic Gate labels with independent truthful automatic and on-demand capabilities.
- **P2.3:** separate ordinary Higgins chat from investigations and add typed owner-scoped context access.
- **P2.4:** project meaningful deduplicated Patrol outcomes rather than commands and diagnostics.
- **P2.5:** build the Higgins hub, redacted history, saved reports, learning and recognised-government New scams.
- **P2.6:** integrate one compatible release, complete traceability and produce a fresh Android candidate while isolating genuine signing/toolchain blockers.

### Verification boundary
- TypeScript, ESLint, provider-disabled pytest and Cargo/native source checks only.
- No testing agent, Playwright, scenario suite or live Gemini probe.
- Owner `GEMINI_API_KEY` only; no Emergent-managed LLM key.
- Android package remains `app.apollo.hwg`.

### Implemented Phase 2 release
- P2.1–P2.5 are complete in source: exact root navigation, Check It, truthful Gate capabilities, ordinary Higgins chat, typed owner context, consumer Patrol outcomes and the Higgins hub/history/learning/government-alert surfaces.
- P2.6 integrated source candidate is Apollo `1.1.0`, Android `2`, iOS `2`, desktop `1.1.0`.
- TypeScript, ESLint, Python lint, 53 provider-disabled pytest checks, security/native preflight, Cargo and Apollo-owned Android release Kotlin modules pass.

### Backlog
- No remaining application-source item from Phase 1, Phase 2 or Package 6.
- Signed builds, installer production, notarisation, store work and physical-device acceptance are build-owner responsibilities and are not development backlog items here.

## Phase 2 source remediation — completed locally (2026-09-22)

- Production and app-bundle profiles now default to Apollo-owned GuardDog production authority and fail closed when signed trust is unavailable.
- Retired references are absent from active source/test/config/support/design inputs; navigation and reusable Settings behaviour are stable.
- Gates use one consumer model/card each; ordinary chat has registered read-only context tools; unavailable reasons are canonical; Patrol uses five meaningful states.
- Higgins provides stable current/recent/history/report/learning/New scams entry points. History survives case evidence cleanup as redacted summaries.
- Backend owns 35 curated learning articles and official-source feed/admin lifecycle; consumer learning is no-store and ships no article bodies.
- Validation: TypeScript, ESLint, Python lint, 373 Node tests, 61 provider-disabled pytest tests, staging/production preflight and Cargo pass.
- Final GitHub save remains required before build-owner handoff. No artifact/deployment/device/signing work was performed in this source package.

## Package 6 native source delivery — complete locally (2026-09-22)

- iOS/iPadOS: real Content Blocker, Call Directory, unknown-sender Message Filter and Share Extension targets; App Group queue stores no raw message content.
- Windows: WFP ALE service, dynamic exact-destination filters, WFP drop evidence with app/process attribution, service lifecycle and NSIS packaging source.
- macOS: Network Extension system extension, source-app attribution, bounded enforcement evidence, activation helper, required entitlements and unsigned embedding source.
- Desktop host reports actual installed/active state and canonical missing/permission states; no native source is represented as live protection.
- Validation: TypeScript, ESLint, Python lint, 381 Node tests, 58 provider-disabled backend pytest tests, 9 GuardDog source pytest tests, Cargo, 5 Rust tests, Windows x64 cross-link, Expo extension resolution and both security preflights pass.
- No signed/native artifact or device result is claimed. Final Package 6 GitHub save is the only source-handoff action remaining.

## GuardDog production-default authority — controlling update (2026-09-23)

- The owner's uploaded `Apollo GuardDog Production-Default Activation` instructions are FIRST / CRITICAL and authoritative over earlier GuardDog wording.
- GuardDog must be the Android production-default engine with the existing M2 Website Gate DNS/sinkhole path active under the same process-lifetime Apollo owner; selector-only cutover is insufficient.
- Frozen `frontend/packages/guarddog-*` files remain immutable. Production has no legacy/acceptance/simulated fallback and accepts public roots plus signed artifacts only—never private keys.
- Biting remains restricted to fresh authorised packet-drop evidence. Developer scope is GD-PROD-01 through GD-PROD-08 source/configuration/checks/handoff; signed artifacts and physical-device review remain release-owner scope.
- Authoritative source URL and continuation boundary: `memory/APOLLO_GUARDDOG_PRODUCTION_AUTHORITY.md`.
- GD-PROD-01 through GD-PROD-08 developer source scope is complete: production-only selection, single owner, independent-root signed trust, frozen M2 Website Gate wiring, lifecycle reconciliation, truthful coverage/evidence, bounded checks and handoff manifest.
- External completion remains: owner public trust/feed inputs, release-host signed candidate production, and physical-device enforcement/expiry/revocation/rollback evidence. Detailed handoff: `docs/APOLLO_GUARDDOG_PRODUCTION_HANDOFF.md`.

## Phase 2 remediation and Learn with Higgins — implemented (2026-09-23)

- Authority: `memory/APOLLO_PHASE2_LEARNING_AUTHORITIES.md`.
- C22: canonical device-result absence values now pass the pre-provider serializer; safe retry preserves request/result identity.
- C23/C21: ordinary chat has bounded retention and read-only access to the authoritative capability/Gate registry, existing investigation/report history, Patrol outcomes, learning preferences and recognised-government alerts. It cannot start investigative work.
- C24: immutable server Patrol records own revisions, deduplication and effective display state. Consumer history uses server projections and timelines; Biting still requires fresh validated enforcement evidence.
- C25/Learning: governed backend catalogue, source/feed registries, editorial workflow, permissions, audit, candidate review queue, safe feed transport, filters/preferences and structured mobile reader are implemented. The explicit import path published 43 Australian starter articles in this environment.
- Verification: TypeScript/ESLint, 385 Node checks, Python lint/compile, 77 bounded provider-disabled pytest checks, and local no-provider APIs pass. Scamwatch was fresh in development; ACSC truthfully reported unavailable after a read timeout; no feed candidate auto-published.
- Developer verification and exact boundaries: `docs/APOLLO_PHASE2_LEARNING_IMPLEMENTATION_RECORD.md`.
- P1 external operation: configure least-privilege admin keys, verify each registered government feed from production egress, and conduct editorial acceptance. Live Gemini and physical-device acceptance remain separate.

## C15 / GuardDog production-default activation — source implemented (updated 2026-09-23)

### Problem statement
Create a production-distinct GuardDog authority without promoting the frozen M1 acceptance profile: one process/runtime owner, pinned production roots, signed update trust, rollback/recovery authority, validity/revocation, offline key custody, explicit build selection and truthful cutover evidence.

### Architecture implemented
- **Selection:** production, app-bundle and guarddog-production all select only `guarddog_production`; legacy activation is rejected natively in production, and `guarddog_acceptance` remains forbidden.
- **Trust:** pinned primary/recovery public roots sign strict domain/profile manifests. Manifests introduce ordinary rule keys only; recovery can permanently disable primary authority. Generations, versions and envelopes are rollback/conflict checked.
- **Persistence:** accepted trust/rules are HMAC-bound to Android Keystore state with backup disabled. Missing/replaced integrity state fails closed.
- **Runtime:** one Apollo-owned engine/verifier/registry/version-store/listener/VPN route. The accepted engine is wired into the frozen M2 Website Gate DNS gateway, sinkhole /32 routes, physical-network IPv4 DNS forwarding, allow-only override cache and packet-drop reporter before start.
- **Updates/expiry:** HTTPS signed refresh every six hours plus expiry stop, boot/unlock/package-replace reconciliation and physical-network DNS-change restart; persisted valid authority can bridge temporary network loss but never its deadline.
- **Key custody:** offline Ed25519 signing tools reject private key paths inside `/app`. App/plugin/preflight reject M1 acceptance key material and accept only public roots/signed artifacts.

### Verification and boundaries
- TypeScript compilation and ESLint pass.
- 9 GuardDog production source/configuration pytest checks plus 58 provider-disabled backend lifecycle pytest tests pass.
- TypeScript, ESLint, frozen GuardDog 91/91 hash checks, production preflight, Cargo check, 5 Rust tests and Windows x64 cross-link pass.
- No Playwright, scenario agent, live Gemini call or Emergent-managed key was used.
- Android Kotlin source compilation is performed in this continuation. Physical-device trust/rollback enforcement remains unrun and is not implied by compilation.

### Priorities
- **P0:** C15 production source track complete.
- **P1:** Owner supplies only public roots, signed update artifacts and HTTPS locations; the build/device owners then produce signed candidates and device evidence.
- **P2:** Release evidence packet and long-term rotation/recovery drill records follow device acceptance; production never falls back to legacy.

## Consolidated architecture mandate — M3 implemented (2026-09-22)

### Problem statement
Close the remaining lifecycle semantics: cancellation must report the actual race winner and fence downstream effects; saved reports, speech, family voice, captions and retry UX must have explicit identity, ownership and cleanup.

### Architecture implemented
- **Cancellation:** server outcomes are typed as cancelled/completed/failed/superseded. Accepted turns are detected from the encrypted accepted-commit ledger; the mobile case store refreshes and displays completion if it won. Duplicate cancel is idempotent and stale cancel preserves newer work.
- **Narration:** speech jobs enter an observable active state, verify epoch/work epoch before and after provider calls, and purge partial chunks on cancellation, deletion, expiry or provider/unexpected failure.
- **Saved reports:** persistent historical scope/sources/actions/revision/retention notice, stable list/detail retry controls, and owner-scoped deletion of report plus speech scope/cache.
- **Family voice:** stable recording submission ID, relationship generation, idempotent attachment, pre/post publication link validation, unlink transcript fencing and caption updates conditional on an unrevoked matching generation.

### Verification and boundaries
- TypeScript compilation and ESLint pass.
- 58 investigation/lifecycle pytest tests pass with `GEMINI_API_KEY` explicitly disabled.
- Cargo check passes.
- No Playwright, scenario/testing agent, live Gemini call or Emergent-managed key was used.
- Android Gradle/Kotlin compilation remains intentionally outside the owner-approved verification commands.

### Priorities
- **P0:** M3 source implementation complete.
- **P1:** Continue the C15 production GuardDog source track, then preserve explicit legacy/production cutover separation.
- **P2:** Production-default cutover remains separate.

## Consolidated architecture mandate — M2 implemented (2026-09-22)

### Problem statement
Close the six case/job coordinator findings in M2: durable automatic Text intake, one Gmail pipeline, mixed-document evidence fidelity, restart-safe source/model continuity, honest app/device provenance and first-class Saved Reports.

### Architecture implemented
- **Automatic Text:** encrypted revision-aware Android queue with fixed expiry, serialised read/modify/write, explicit overflow/key failures and WorkManager delivery. Foreground and background consumers use one owner-authenticated idempotent case intake.
- **Gmail:** a single leased manual/monitored intake with durable page cursor and receipt deduplication. Raw email remains request-scoped until encrypted temporary evidence; final Patrol projection is model-free.
- **Evidence:** mixed PDF visual pages are rendered beside text; DOCX expansion is pre-bounded, images are extracted under secret admission, and undecodable drawings remain explicit gaps. Complete provider transcripts are not silently clipped.
- **Coordinator continuity:** immutable fetched-source snapshots back every URL cursor; jobs persist their original Gemini model; a replay-safe non-model projector translates accepted case state into Patrol.
- **App/device facts:** exact package visibility without vendor-prefix trust; requested, granted, special-access and user-reported permission origins remain distinct.
- **Reports:** independent Patrol list/detail UX, historical labeling, stable keyset paging, reopen/speech and owner-scoped report/speech deletion.

### Verification and boundaries
- `tsc --noEmit` and ESLint pass.
- 53 M2-focused backend pytest tests pass with `GEMINI_API_KEY` explicitly disabled.
- `cargo check` passes.
- No Playwright, scenario/testing agent, live Gemini call or Emergent-managed key was used.
- Android Gradle/Kotlin compilation was not run because the owner permitted only TypeScript, ESLint, pytest and Cargo checks. Native changes remain source-verified rather than Android-compiler-verified in this milestone.

### Priorities
- **P0:** M2 source implementation complete; owner/native build verification remains separate.
- **P1:** Continue M3 (`C13`, `C14`) and then subsequent consolidated-mandate milestones without weakening the M1/M2 ownership boundaries.
- **P2:** Production-default cutover remains separate.

## Consolidated architecture mandate — M1 implemented (2026-09-22)

### Problem statement
Apply the consolidated Apollo architecture starting with every M1 finding while preserving the Gemini-only owner-key boundary and avoiding scenario/browser automation. Repair lifecycle ownership, background supervision, Settings contracts, single-investigator behavior, durable Patrol continuity, ambiguous audio cleanup, consumer status language, settings-return recovery and shared protection health.

### Architecture implemented
- **Investigation lifecycle:** fixed 15-minute client deadline reserved before I/O, explicit UUID/event submission identity, generation guards after async boundaries, owner-bound server event→case association, and terminal disposal of transient references/indexes.
- **Backend workers/storage:** lifespan-owned maintenance supervisor with bounded per-component work, independent failure containment, component telemetry/backlog health, and durable `outcome_unknown` family-audio cleanup.
- **One investigator/actions:** App and Account compatibility APIs perform lookup-only non-AI work; the shared case engine is the only Higgins presenter. Settings plan/recheck egress matches Pydantic exactly and binding failures are visible.
- **Protection recovery:** one shared health coordinator/store owns startup, foreground, periodic, Support and post-action checks. Android reports whether system UI opened, was already granted, failed or is unsupported; a durable typed attempt resumes on return/cold boot and deduplicates prompts.
- **Consumer UI:** Home and Protection show component-scoped status and direct actions. Technical build/provider diagnostics are separated under Support. Recurring visibility alarms and routine verification controls were removed.

### Verification and boundaries
- Frontend TypeScript compilation and ESLint pass.
- Focused M1 backend pytest passes with `GEMINI_API_KEY` disabled; no live provider call was used.
- Desktop `cargo check` passes after installing the container's standard Rust/Tauri build prerequisites.
- No Playwright, automated scenario/testing agent or Emergent-managed LLM key was used.
- The full legacy pytest attempt still contains unrelated environment-dependent failures where email, family object storage or voice delivery credentials are absent; no application fallback or mock was added.

### Priorities
- **P0:** M1 source implementation complete; owner verification remains separate.
- **P1:** Continue subsequent consolidated-mandate milestones and unblocked Package 6/7 source work. Keep `app.apollo.hwg` and native EAS profiles free of browser preview harnesses.
- **P2:** Production-default protection cutover remains a separate evidence decision.

## Production deployment build correction — EAS app-bundle pre-install

- Diagnosed failed Android app-bundle build `4dee4d9b-99ba-48db-825d-1f63c22414db`: the generated `app-bundle` profile inherited development-web preview-harness values, and the native security preflight correctly stopped the build before compilation.
- Added a production-safe `app-bundle` EAS profile, explicit production environment fail-closed values, and profile-aware preflight resolution that never inherits `.env` development-web defaults for a native EAS build.
- Added `.easignore` and removed 3.6 GB of ignored generated caches from deployment input. No Docker changes were made.
- Verification: four native profile preflights pass; deliberately unsafe app-bundle preview input remains rejected; security tests 6/6, TypeScript and lint pass; deployment health agent reports PASS.
- The failed build has no artifact. The corrected source requires a fresh Android app-bundle build; success is not claimed until that build finishes.

## Current continuation — 7-package mandate repair and Packages 3–5 completion

### Problem statement
Complete the remaining Apollo investigation lifecycle without reopening supported prior corrections: restore automatic durable recovery/retention, make mobile operations case-owned beyond screen lifetime, deliver recoverable PDF continuation images to Gemini, fix the generated Windows filter command, then complete investigation depth/limits, Gate background behaviour, guided actions, saved reports and cleanup. Use only the owner's `GEMINI_API_KEY`; keep live provider access disabled during bounded verification.

### Architecture now implemented
- **FastAPI/MongoDB:** supervised maintenance independently runs temporary-content cleanup, expiry/deletion retry, tombstone cleanup, job/device-inbox recovery and family-audio cleanup with component heartbeat/failure reporting. Gmail monitoring now creates durable temporary Higgins cases and only projects redacted terminal summaries to Patrol.
- **Expo:** `transferManager.ts` owns create/upload/append execution, retry identity, terminal result retention and expiry by strict operation/case pair. Screens subscribe by explicit operation ID; they no longer attach the global latest operation.
- **Evidence/research:** PDF continuation manifest replay repairs image delivery and parent coverage. Clue overflow has `continue_clues`; public research has an explicit entity cursor; device observations retain structured provenance; full protected Gate handoffs and Gmail link destinations are preserved.
- **Lifecycle UX:** unobservable Settings changes may be recorded only as user-reported confirmation; saved reports are paged/deletable; voice uploads create durable orphan-cleanup ownership before object storage.
- **Desktop/native:** Windows PowerShell generation uses `$apolloTargetHost`; Android Text notification content is protected with Android Keystore AES-GCM and removed only after exact durable submission acknowledgement.

### Verification
- Frontend: `tsc --noEmit` passed; `frontend/src` and `frontend/app` ESLint passed.
- Backend bounded suites: recovery/PDF/ownership-adjacent lifecycle **35/35**, maintenance **3/3**, mailbox shared-engine **1/1**, Gmail **11/11**; `/api/health` returned healthy worker/component status. Provider calls were hard-disabled.
- Desktop: generated-command assertion passed; Windows command Rust unit **1/1**; `cargo check --jobs 2` passed.
- Not used for acceptance: live Gemini, scenario/browser automation, testing agent or managed AI keys.

### Priorities
- **P0:** No outstanding finding from the four-item repair list. Keep health datetime normalization and strict operation/case pairing covered.
- **P1:** Produce the next Android correction candidate after this repair pass, then obtain device feedback for the protected Text queue and screen reattachment. Build iOS when Apple signing/team and device UDIDs are available. Produce Windows/macOS packages on matching signed hosts.
- **P2:** Production-protection implementation remains backlog; production-default cutover is a separate approval/evidence decision. Continue desktop WFP/Network Extension implementation separately from manual Gate availability.

### Artifact truth and external blockers
- Existing APK remains available but does not contain this continuation's frontend/native changes.
- Apple credentials/UDIDs block only signed iOS delivery. Windows/macOS hosts/signing block only trusted desktop installers.
- Owner-managed family storage and separately configured email/push credentials block only those service-backed flows.

## Session 5 (2026-09-21) — builds + source-review corrections

- **Android `device-test` APK BUILT**: EAS build `e32f6068-b349-4de8-ab5d-8c950a6596bf`, commit `fa9bf2f`, APK https://expo.dev/artifacts/eas/-R5J9ohNQ6k-MxXloAh_NuawortWikr6zDUyXPbaRlE.apk
  (details/inspection in `docs/APOLLO_BUILD_RECORD.md`). First build `d54b2c70` failed on a pre-existing Kotlin error (fixed).
  EAS is logged in in this workspace (`emergent-em-user-…`, project `threat-patrol-1`) — `npx eas-cli build --platform android --profile device-test --non-interactive --no-wait` works from `/app/frontend`.
- iOS: blocked only on Apple credentials + device UDIDs (recorded).
- Review corrections done: work_epoch vs content epoch (cancel keeps evidence); device submission claimed→stored→resumed with persisted
  result + sweeper; exclusive recoverable upload finalisation; pending tool batch persisted/answered before Gemini (arg-hashed call ids);
  strict preflight validation + targeted redaction (verbatim text with only secrets [REDACTED], visual description, coverage);
  settings plan bound before opening Settings, attempts recorded before launch, native permission requests observed on return, failed
  rechecks retained with retry button; desktop hosts explicit windows/macos identity + descriptors + failures propagate.
- Product gaps: Patrol "Ask Higgins" continues the Gate's case (event→case index); scanned-PDF pages rasterised (pypdfium2) for Gemini
  vision; family voice-note storage lifecycle (retention/purge/unlink/410); tablet/desktop max-width column.
- NEXT EXACT TASK: (1) owner installs APK on Pixel 10 → report native-module behaviour; (2) iOS credentials then `eas build --platform ios --profile device-test`;
  (3) desktop: real manufacturer/model (WMI/IOKit), SSID, WFP/Network Extension filtering service; (4) Text Gate duplicate-guidance dedupe;
  (5) rerun Android build after any native change (`modules/apollo-security`).

## Current continuation status — 2026-09-21, session 4 (revision-1 package; supersedes the blocks below)

Controlling doc: `memory/Apollo_Complete_Developer_Instructions-1.md` (owner revision: **developer scenario testing STOPPED**; no
testing agent, no Playwright/Gemini scenario suites, no new scenario scripts/reports; finish functionality, bounded checks only —
compile/tsc/lint/focused local tests; deliver installable builds; Windows/macOS are REQUIRED targets; zero runtime mocks).

DONE this session (committed locally; owner must "Save to GitHub"):
- S01 zero-mock runtime: `EXPO_PUBLIC_SECURITY_MODE`/`SECURECORE_MODE` removed; `MockSecurityAdapter*`, `securecore/SecureCore.ts`,
  `securecore/mock/*`, `app/dev-tools.tsx` deleted; SecureCore boot dependency removed (Settings: "Not included"); real
  `WebSecurityAdapter`; platform-split `hostAdapter.ts`/`.web.ts`; development-web-only preview harness in `frontend/tools/preview-device-harness/`
  (label "MOCKED DEVICE INPUT — PREVIEW ONLY", `EXPO_PUBLIC_DEVICE_PREVIEW_HARNESS=enabled` in dev `.env` only); preflight scans sources.
- S02 real permissions/facts: Kotlin/Swift `getProtectionPermissions` read real notification/listener/blocker state with recorded
  request history (`requested`/`lastRequestedAt`/`enabled`/`observedAt`/`unavailableReason`); `getDeviceProfileFacts` (manufacturer/model/OS/
  form factor/locale); broker advertises only implemented capabilities; `DeviceProfile.formFactor`, `DeviceResult.unavailableReason` (backend contracts too).
- S03 Settings: `src/settings/guidance.ts` descriptors (Android intents / iOS paths), `actions.ts` executes the bound descriptor and records
  an `ActionAttempt`, `recheck.ts` takes a fresh observation on return and calls `/settings-plan/{id}/recheck`; backend binds plan to the
  advertised descriptor by target; `research_settings` "exact" requires manufacturer AND OS in the same source.
- S04 push protocol: `routers/push.py` rewritten (Expo token + projectId, registrationId, durable `push_deliveries` with unique
  (owner,event,channel,recipient), per-ticket inspection, receipt reconciliation loop, 202 DeliveryStatus / 409 recipient_unregistered / 503 setup,
  `GET /push/deliveries/{id}`, `GET /push/registration`, sound + `threats` channel fixed); frontend `getExpoPushTokenAsync({projectId})`,
  permission vs registration state, bounded pending retry, Settings shows registration.
- S05 writer-lease/tombstone: `settle_write`, epoch-fenced `emit`, `sweep_tombstones` in the job sweeper.
- S06 Gemini-only image secret preflight (ephemeral admission; secret-bearing originals never stored; redacted description retained; fails closed) — verified live.
- S07 client integrity: generation-guarded `refresh`/callbacks/ask/retry/cancel/attach, orphan-case abandonment, persisted deletion retry,
  `GateInvestigation` bound to an immutable submission object on all nine Gate screens (typing never starts/deletes cases).
- S08 durable per-call tool ledger; accepted-turn-first deadline recovery; atomic `(owner,case,request)` claim with canonical hashing,
  superseded-request 409, recoverable continuation record + sweeper completion.
- S09 Text screenshot original image + prior Apollo check, App typed native SDK observation + server lookups carried onto the case.
- S10 clue inventory: document order, phone priority, explicit omitted counts/offsets to the model; clue reads never examine parents; read marks deferred.
- S11 delivery: `eas.json` `device-test` profile (Android APK + iOS internal); `desktop/` Tauri v2 host scaffold + `DesktopSecurityAdapter`
  (typed commands; filtering explicitly `not_implemented`); docs `APOLLO_PLATFORM_DELIVERY_MATRIX.md`, `APOLLO_RUNTIME_SIMULATION_AUDIT.md`.
Checks: tsc clean, eslint 0 errors, frontend security/adapter/guard tests 49/49, backend engine+persistence 10/10, push tests 24/24, preflight OK.
Builds: NO artifact produced in this sandbox (no EAS/Gradle/Xcode/Windows runner). Operator action: Publish → Android `device-test` profile.

NEXT EXACT TASK: (1) trigger Android `device-test` build via Publish and record build ID/SHA in the delivery matrix; (2) iOS signing inputs;
(3) desktop real manufacturer/model (WMI/IOKit), SSID, WFP/Network Extension filtering service; (4) S09 remaining entry routes
(Home quick checks/share/Patrol onto the case; Text still runs `/message/analyse` first as the deterministic initial observation — keep,
but stop showing contradictory duplicate guidance); (5) email idempotency/ambiguous outcomes + family storage lifecycle (§10A);
(6) R06 upload-finalisation claim; (7) tablet/desktop layouts audit. Scenario execution: owner.

---

## Current continuation status — 2026-09-21, session 3 (supersedes the blocks below)

Controlling docs: `memory/Apollo_Complete_Developer_Instructions.md` + `memory/Apollo_Saved_Source_Review_59725fc.md` (R01–R10).
DONE this session (all committed locally; user must "Save to GitHub"): R01 immutable per-attempt commits + crash repair; R02 epoch-fenced
content writes, TTL backstop at expires_at, cleanup revisit; R03 originals purged when they carry secrets, TXT as document; R04 per-round
checkpoints, interrupted-call marker, retry_wait heartbeat, deadline reconciliation; R05 true page totals, tables/headers, whole-page rule,
deferred examination marks, coverage-aware completion validation; R06 separate upload chunks, atomic digest, idempotent finalisation;
R07 clue registration (links/numbers as child evidence), `register_clue` tool, full research snapshots, stable source IDs; R08 plans bound
to capability/expected value/created_at, fresh-observation recheck; R09 generation-fenced store, sequence continuation, retryable deletion;
R10 action dispatcher (`src/settings/actions.ts`), inert actions as text, case-bound narration, honest completion label.
Gate integration: `GateInvestigation` on all ten Gate screens (initial investigation via shared case; Ask continues same case);
device broker bound to `securityAdapter`; mock adapter platform-split out of native bundles; delivery adapters (Resend/Expo push/S3) implemented,
credential-blocked; legacy failures classified (`docs/APOLLO_LEGACY_TEST_CLASSIFICATION.md`); US runner `tests/run_us_scenarios.py`
(US01/03/05/06/24 complete via screens, US11/US35 via API). Tests: engine 7/7, persistence 3/3.
REMAINING: full US01–US35 matrix (US02/04/07–10/12/14–23/25–29/32–34 through normal screens incl. File upload + Device recheck UI),
`src/settings/{guidance,recheck}.ts` Device-screen UI, native Kotlin requested-vs-granted contract, simulated-observation badge in the view,
image secret preflight (Gemini-only), 6 open legacy-route test defects (see classification), Home quick checks/share targets onto the case.

---

## Previous — 2026-09-21, session 2

Controlling specifications: `memory/Apollo_Complete_Developer_Instructions.md` (Stages A–D, US01–US35) consolidating
`memory/Apollo_Final_Code_Review_and_Developer_Package-2.md`. Gemini only via owner `GEMINI_API_KEY`; no testing agent
without explicit approval; Stage 1D cancelled; frozen `frontend/packages/guarddog-*` untouched.

DELIVERED THIS SESSION (verified live with the owner key, no mocks):
- Shared engine `backend/services/higgins/{contracts,repository,evidence,tools,validation,coordinator,jobs}.py` and
  `backend/routers/investigations.py` (all spec §8 routes). Encrypted owner-scoped collections `investigation_*`,
  lifecycle epoch, lease/fence, staged→single-CAS accepted turn commits, SSE events with `after=` reconnect,
  resume/cancel/delete/expiry sweep, resumable uploads, PDF/DOCX/TXT/PNG/JPEG intake with page-level coverage,
  9 typed tools incl. Search-grounded research, device-observation pause/resume, settings plan + recheck, case speech, saved reports.
- `routers/ask.py` is now a thin adapter over the same engine (one engine). Obsolete keyword-validator/fallback tests removed.
- Frontend `src/investigation/{types,client,caseStore,deviceBroker}.ts`, `src/components/InvestigationView.tsx`;
  `app/(tabs)/ask.tsx` rewritten onto cases; all ten Gate screens' Higgins handoffs carry original evidence (`original_evidence`, incl. Link/Site via `EventActions`).
- Probes: `backend/tests/probe_investigation.py`, `probe_document.py`; regressions `backend/tests/test_investigation_engine.py` (7/7).
  Legacy suite: 279 pass / 23 fail — identical to pre-change baseline failures (voice mp3, push placeholder, gate4, prompt tests).

STATUS: Stage A ✅ (native picker lifecycle unverified). Stage B ✅ core (frontend device broker returns honest `unavailable`;
Gate screens' local state not yet case-driven). Stage C 🟡 (backend settings plan/recheck done; Site/Link/Network/App/Device
handoffs summary-only; native permission semantics, preview isolation, `src/settings/*` not started). Stage D ⬜ (US01–US35 NOT RUN
as a suite; only direct probes). Delivery adapters (email/push/storage) remain 503 stubs — blocked on owner credentials and unimplemented.

NEXT: C18 remaining Gate handoffs with originals (Site/Link screenshot+URL, Network, App, Device); bind native observation
adapters to `deviceBroker`; `src/settings/*` + Device screen recheck UI; AR-09 native contract; AR-11 preview isolation;
extend `tests/run_round1_user_scenarios.py` with US01–US35 + `ScenarioOutcome` schema and run live; delivery adapters.
Docs: `docs/APOLLO_IMPLEMENTATION_MATRIX.md`, `APOLLO_INVESTIGATION_ARCHITECTURE.md`, `APOLLO_CAPACITY_AND_RETENTION.md`,
`APOLLO_SETTINGS_CAPABILITIES.md`, `APOLLO_INTEGRATION_CONFIGURATION.md`.

---

## Current continuation status — 2026-09-21 (supersedes conflicting older handoffs)

Controlling specification: owner-uploaded `Apollo_Final_Code_Review_and_Developer_Package-2.md`.
All AI must use the existing owner GEMINI_API_KEY through direct Google SDK; no managed keys or other AI providers.
The testing agent must not be invoked without explicit user approval. Stage 1D remains CANCELLED.

Implemented: direct Gemini text/vision/transcription/speech adapter; removal of active managed dependencies/config;
encrypted fixed-expiry Ask and speech storage with owner isolation, deletion fencing and cleanup; distinct turn retry
identity, strict provider/application completion, opaque handoff navigation, no canned Higgins substitution or prose
clipping; full-length speech segmentation; picker-copy ownership cleanup; conservative incident correlation;
larger explicitly bounded primary text inputs; immutable regression reporting with NOT_RUN accounting.

Verification: real Gemini text, follow-up replay, protected WAV, transcription, screenshot, 13,863-character input,
encrypted DB content, expiry, live deletion race and mobile preview passed direct checks; local preflight 35/35.
All ten full browser journeys were NOT_RUN in this iteration. No testing agent used. Not full architectural acceptance.

BROKEN/BLOCKED pending direct owner credentials: guardian email, push delivery/registration, family voice object storage.
These legacy relays were disconnected as instructed; direct replacements and historical remote-object cleanup are unfinished.
Gmail OAuth/security-data services and frozen native packages preserved.

P0: finish shared typed InvestigationCase/evidence/coverage models and durable job/tool coordinator; full original-evidence
ingest, progress/resume/cancel, semantic claim/action grounding and image secret-preflight. P1: full Gate migrations,
legitimate/ambiguous/threatening and failure matrix, native-free privacy/capacity validation; restore blocked integrations
using owner configuration. P2/P4: existing backlog, native desktop adapters; physical Stage 1D remains cancelled.

Full architecture, current models, key lifecycle, actual failures/fixes, configuration blockers and AR01–AR16 matrix:
`docs/GEMINI_ONLY_MIGRATION_STATUS.md`. Preserve `INVESTIGATION_KEY_FILE` outside Git; never print key values.
Current direct verification credentials are recorded by file reference in `memory/test_credentials.md`.

---

# Apollo V1 — PRD & Build Log

## Current delivery — ten first-class Gates with File and Device health (iteration 74)

### Problem statement
Make File Gate and Device Gate first-class members of Apollo's ten-Gate overview. File Gate must accept selected or shared downloads and attachments without treating a cloud host as proof of safety. Device Gate must assess existing visible app capabilities, permissions, security configuration and Apollo protection health without claiming continuous scanning or malicious behaviour without evidence. Higgins must explain findings, guide remediation, open relevant settings and support re-checks. Stage 1D physical-device work remains cancelled; the product focus is how Apollo and Higgins handle people's real situations.

### Architecture
- **Mobile:** Expo Router + React Native. `message.tsx`, `text-guard.tsx` and `check.tsx` use the shared `MessageAssessmentResult`, guided screenshot-access hook/sheet and the Apollo context.
- **Backend:** FastAPI routes `/api/message/analyse`, `/api/message/extract` and new `/api/link/investigate` call deterministic checks, bounded reputation/web/caller evidence and Gemini through `services/investigation.py`.
- **Persistence:** MongoDB stores sanitised Patrol summaries/evidence only. Raw submitted assessment content is request-scoped and excluded from Patrol, logs and analytics.
- **Native candidate:** `guarddog-acceptance` remains an Android-only staging profile over one Apollo-owned runtime; production remains `legacy`. Imported `frontend/packages/guarddog-*` source is frozen.

### Implemented
- **Ten first-class Gates:** The main Gates overview now contains Site, Link, Text, Call, Network, Account, Email, File, App and Device. File and Device are selectable overview cards that reuse `/file` and `/device`; both truthfully show **Ready to check** because they are user-triggered checks, not continuous monitors.
- **File Gate:** Accepts selected/shared downloads and attachments from any source, keeps cloud hosting source-neutral, performs bounded local signature/extension/text-sample inspection, explains limits through Higgins, and hands relevant URLs or installed/profile/certificate concerns to Link, App or Device Gate. Email Gate now states that a pasted attachment name is not the file and routes to File Gate with Email attachment context selected.
- **Device Gate:** Re-checks existing visible app capabilities, sensitive permissions, VPN/profile/accessibility/notification/developer settings and Apollo protection health. It records observable snapshot drift, separates capability from malicious behaviour, keeps dormant capabilities reviewable, labels protection gaps without alleging tampering, and reserves suspected-tampering wording for specific high-risk/high-confidence change evidence. Higgins opens relevant Settings and offers an explicit outcome re-check.
- **Iteration 73 frontend closure:** Cleared the current frontend lint gate and removed the final warning. Email Gate now leaves its Gmail status wait after eight seconds, presents a truthful retry state, and displays disabled loading labels/spinners while Gmail OAuth opens or a connected inbox scan runs. App Gate remains unchanged functionally and renders correctly.
- **Credential policy correction:** Generic IMAP connection and every mailbox username/app-password input, route and storage function were removed. Existing `imap_connections` rows were purged. Gmail read-only OAuth remains the only mailbox connection path; Apollo never asks for or stores mailbox usernames or passwords. Text/Ask request boundaries redact passwords, usernames, PINs, recovery codes and one-time codes before external processing or history storage; existing Ask history was purged. See `docs/CREDENTIAL_REMOVAL_RECORD.md`.
- Text, Link and screenshot results now show submitted content, scam/clear/uncertain hierarchy, findings, visible unresolved questions, Higgins' exact response, one primary action, safe sources and the processing boundary.
- Chosen screenshots show a preview, run Gemini extraction and automatically continue into the same full investigation. Photo access is explained before prompting; denied settings access is rechecked when the app becomes active.
- Added dedicated `/api/link/investigate`, client egress allow-list/redaction, safe long-request handling and Patrol-safe supporting references.
- Replaced obsolete cloud-denial and raw-Patrol expectations with current purpose-limited, secret-redaction, SSRF and truthful-enforcement contracts; repaired legacy Biting fixtures without weakening packet-evidence validation.
- Live scam, genuine-looking and ambiguous demonstrations are recorded in `docs/HIGGINS_SCENARIO_EVIDENCE.md`; screenshot completion evidence is in `test_reports/iteration_71_screenshot_retest.md`.
- Stage 1D acceptance profile and frozen source preflight pass. `docs/STAGE1D_CANDIDATE_RECORD.md` preserves the still-missing source/build/APK/Pixel fields instead of claiming acceptance.

### Verification
- Iteration 74: independent testing report `/app/test_reports/iteration_74.json` passed **23/23** focused checks. Main-agent regression passes: frontend **352/352**, backend **301/301**, TypeScript and lint clean. Preview confirms exactly ten Gate cards, File/Device **Ready to check** states, direct overview navigation, cloud-file → App Gate → Device Gate handoff, Device protection-health/Higgins recheck UI, truthful Email preview/attachment limits, and accessible Email-source selection in File Gate. Frozen GuardDog packages were not modified.
- Iteration 73: frontend lint and TypeScript compile clean; Gate 1 **13/13**, Gate 7 **37/37**, Gates Overview **6/6**. Preview verification confirms Email Gate reaches an enabled Gmail connect CTA instead of remaining in “Checking connection…”, the OAuth launch shows a disabled “Opening Google…” state, and App Gate enables its assessment action after app-name input. Independent report: `/app/test_reports/iteration_73.json`.
- Backend current regression: **301 passed** (`python -m pytest -q`), including purpose-limited account/link contracts, secret redaction, SSRF boundaries, content-aware fallback and Stage 1D evidence rules.
- Frontend current regression: **352 passed** (`node --test tests/*.test.ts`), TypeScript compile clean, JavaScript/Python lint clean.
- Browser: scam and genuine-looking Text Guard results rendered; genuine content uses “Assessment only — nothing was blocked.” A real nonblank JPEG completed preview → Gemini extraction → automatic Higgins investigation.
- Testing report: `/app/test_reports/iteration_71.json`; deterministic screenshot retest: `/app/test_reports/iteration_71_screenshot_retest.md`.
- Stage 1D: profile/frozen-source/key-permission preflight passes, but controlled acceptance inputs are incomplete and the documented endpoint returns HTTP 404. Android build, APK hash and Pixel acceptance remain not run.

### Priorities
- **P0:** Complete. Keep all purpose-limited privacy, queue/evidence and Truth-of-State regressions green. No investigation may produce Biting.
- **P1:** Evaluate and improve how Apollo and Higgins handle people’s real situations across Text, Link, Email, Call, Account, App, File and Device checks: useful questions, clear uncertainty, relevant evidence, practical next actions and consistent follow-up. Gmail OAuth human consent remains a separate user-verification item, not the main product workstream.
- **Stopped by user:** Do not pursue the controlled endpoint, acceptance signing, Android candidate build, APK hashing or Pixel acceptance run. Physical acceptance remains **NOT RUN** and must not be implied.
- **P2:** Consider macOS/Windows native enforcement adapters only if separately requested.

## Usability and Higgins handoff correction — completed

### Problem statement
Apollo performs supported checks and protective actions; Higgins interprets bounded findings and guides one truthful next action. Manual Gates inspect available evidence first, preserve unknowns, and never turn user selections into proof of safety or compromise.

### Architecture implemented
- Unique issue handoffs carry bounded Gate/state/provenance/uncertainty/confirmed-action/user-report context. Frontend and FastAPI/Pydantic boundaries reject extra fields and redact secrets/direct identifiers.
- Mongo-backed handoff state provides processing/failed/completed idempotency. Conversation IDs isolate issue follow-ups; frontend states cover queued/submitting/streaming/failed/completed with persistent Retry, short references and per-issue counters.
- Structured handoffs pass through a deterministic final Higgins boundary after Gemini review, guaranteeing explicit provenance, uncertainty, no unsupported capability promise and exactly one supported action.
- Generated investigation actions use a shared validated dispatcher with fixed truthful labels and Gate-specific handlers.
- New recovery actions use `recovery_kinds`; legacy “You told Apollo…” records remain parseable.

### Implemented UX and evidence
- File Gate begins with selected/shared evidence, displays supplied metadata/signature/sample limits, asks source/password only when relevant after inspection, and provides truthful filename-only fallback plus picker Retry.
- Account Gate begins with screenshot/paste/description, extracts claims for correction, asks one relevant follow-up at a time, and preserves uncertainty in offline/cloud-assisted analysis.
- Reports await success and retain Retry on failure. Event resolution says “Mark as handled.” Submitted-copy clearing never claims to delete originals.
- Visibility-loss recommendations route to Device Gate; recommendation sheets dismiss before navigation.
- Verification: final frontend **359/359** and backend **305/305**, TypeScript and JavaScript/Python lint clean. Scenario evidence and screenshot paths: `docs/APOLLO_SCENARIO_VERIFICATION.md`; action audit: `docs/APOLLO_BUTTON_AUDIT.md`; independent report: `test_reports/iteration_74.json` (its initial observability gap was closed by per-issue references/counters plus dedicated dedupe tests).

### Current priorities
- **P0:** None open for this correction.
- **P1:** Physical-phone verification for native pickers/share metadata, Settings return, real app/device signals, large accessibility text and keyboard behavior.
- **P2:** macOS/Windows native enforcement adapters.
- **Cancelled:** Stage 1D packet-blocking/physical acceptance exercise; do not resume.

## Round 1 reusable user-scenario regression suite

- Permanent semantic catalogue: `docs/APOLLO_ROUND1_SCENARIO_CATALOGUE.md`.
- One repeatable command: `./scripts/run-apollo-round1.sh --mode repeatable`.
- Separate bounded live mode: `./scripts/run-apollo-round1.sh --mode live`.
- Coverage: threatening, legitimate and ambiguous situations for all ten Gates; five realistic multi-Gate situations; ten complete browser journeys including popups, trusted actions, offline Retry, automatic Higgins handoff, “I already opened it,” “Help me change that setting,” and simpler-explanation continuity.
- Synthetic inputs and preview-only device observations are allowed and explicitly labelled. All Gate selection, investigation, external lookups and Higgins responses are real; no expected verdict or response is injected. Unavailable services produce **INCOMPLETE**, never a substituted pass.
- The 35/35 local semantic matches are preflight only, not investigation/Higgins acceptance. Browser reports carry the real downstream acceptance status and exact live Higgins responses.
- Readable reports: `test_reports/round1_expected_vs_actual_repeatable.md` and `test_reports/round1_expected_vs_actual_live.md`; machine reports use the matching `.json` names; screenshots are under `test_reports/round1_artifacts/{repeatable,live}`.
- Regression totals after Round 1: frontend **364/364**, backend **305/305** (plus focused Higgins handoff **4/4**), TypeScript and JavaScript/Python lint clean.
- Independent verification: `test_reports/iteration_75.json` (full Round 1 repeatable suite) and `test_reports/iteration_76.json` (fresh onboarding smoke selector/navigation).

## P0 remediation stage — VERIFIED CLOSED (iteration 64)
- User approved completion of the full P0 stage. P0-01 through P0-06 are implemented and individually recorded as **VERIFIED CLOSED** in `docs/STAGE1D_P0_REMEDIATION_BACKLOG.md`; original review identities and archived source remain intact.
- Final punch list closed: durable evidence queue rejects acknowledged stale-version replay over newer pending state; `public_get` performs bounded per-hop HEAD preflight with explicit safe GET fallback; changed evidence identity binding returns 409 before fresh truth validation while new invalid Biting stays 422; `__apollo_test_setup=1` provides a non-persistent development-web-only test entry and is unavailable in production/native.
- Verification: main-agent full relevant backend P0 matrix **81/81**, frontend P0 suites **19/19**, direct preview bypass pass; independent iteration 64 **32/32 backend**, **19/19 frontend + 2/2 preview checks**, no critical/minor issues; GuardDog SHA manifest **91/91 unchanged**.
- Boundaries: this closes software P0 remediation only. Expo/web native-security fallback remains **MOCKED** and is not enforcement evidence. Stage 1D is still NOT STARTED; physical start/stop, genuine packet-drop, A4E device persistence and actual notification delivery remain separate native acceptance work. ChatGPT model integration remains a separate requested task and was not started during P0 closure.
- **P0:** complete. **P1:** finish Stage 1D candidate build/device acceptance, then resolve T1–T5 production certification separately. **P2:** future consumer enhancements only when explicitly requested; ChatGPT integration was cancelled by the user.

### P0-03/P0-05 post-closure hardening — iteration 65
- Historical Patrol retrieval now revalidates and persistently downgrades invalid pre-gate call-screening Biting across Patrol, weekly and admin retrieval paths.
- Identical evidence replay is read-only and returns the current stored event; replacement event evidence and cross-event evidence reuse are atomically rejected through dual Mongo unique bindings, including real concurrent requests.
- Delivery pending capacity is 256 with explicit persisted overflow and no pending eviction; locally retained Patrol events retry when space returns. Receipt history is capped at 1,024 with 30-day TTL pruning persisted to storage.
- Verification: main backend P0 **84/84**, frontend **21/21**, preview PASS, GuardDog **91/91 unchanged**; independent iteration 65 backend **50/50**, frontend **21/21 + 2/2 preview**, live Mongo indexes/races PASS.
- Stage 1D test-candidate work proceeded under explicit authorization. Production T1–T5 certification remains separate.

### Stage 1D acceptance candidate — iteration 66
- Added one Apollo-owned Android runtime over frozen GuardDog core/VPN and excluded the competing frozen Expo bridge from autolinking. The reporter wrapper captures original evidence ID, observation time, protocol number and ports before invoking the engine, then correlates only matching genuine engine event ID/IP; missing values are never inferred.
- Added test-only `guarddog_acceptance` selection, `packet_filter` truth mapping, durable native-evidence acknowledgement ordering, isolated signed-fixture provisioning, internal APK build profile, and `/guarddog-acceptance` consolidated Pixel workflow. Production policy and build profile remain explicitly `legacy`.
- Recovered assets: pinned test public key exists; referenced signed bundle/private signing fixture are absent from the current tree and all reachable git object names. Historical `m1-block-test.guarddog.example` does not resolve and its `203.0.113.7/10` values are TEST-NET, not usable infrastructure.
- Verification: TypeScript PASS; candidate/P0 frontend selected suite **58/58**; backend selected P0 **50/50**; Expo config/prebuild PASS; generated Android includes core/VPN and excludes Expo bridge; default preview harness PASS; GuardDog **91/91 unchanged**. Independent iteration 66 repeated frontend/backend/config/prebuild checks with only two minor findings, both fixed and retested.
- Acceptance trust no longer depends on the historical signer. New key `apollo-stage1d-acceptance-ed25519-001` is injected only into the Apollo-owned candidate verifier; its mode-0600 private key remains outside the repository/APK. Current valid/tampered/expired/unknown-key fixtures pass independent real-clock crypto checks, while production prebuild/native metadata rejects acceptance trust.
- Concrete remaining run blockers: allocate/configure an Apollo-owned dedicated public IPv4 endpoint and exact DNS/TLS baseline, then sign its host-scoped bundle; trigger managed Android profile `guarddog-acceptance` through Publish. Native compilation/build ID and physical Pixel 10 acceptance are **NOT RUN** until those actions produce evidence.
- Iteration 67 independent handoff verification passed crypto **2/2**, source guards **4/4**, and backend P0/Stage1D **50/50**. Main GuardDog manifest remains **91/91** when run from its manifest-relative `frontend/packages` directory.

### Stage 1D post-`bb1a5fa` corrections — iteration 68
- Acceptance evidence is now unique-run proof: generated run/probe IDs, observed native session, deliberate TCP source port, exact host/IP/port and packet observation window are all required; historical or untagged inbox records cannot pass.
- Candidate runtime is one lazy process owner guarded by native build eligibility. Candidate/legacy start-stop operations share one serialized coordinator, and GuardDog start verifies legacy shutdown first.
- Start/stop return only after observed session/TUN/route/reporter transitions or explicit timeout. Protection freshness is based on current native inspection, not lifecycle intention.
- Native and JS boundaries validate supported protocol/source/action/result/confidence values. Unsupported protocol becomes `unknown`/`unverified` with raw metadata preserved. Native durable evidence is capped at 256 and exposes overflow/storage errors without crashing packet processing.
- Historical signer dependency is absent from runtime/provisioner. Production remains legacy and generated default Android metadata is reset to acceptance=false.
- Verification: frontend **60/60**, focused follow-up **11/11**, crypto **2/2**, backend independent **50/50**, candidate prebuild/autolinking PASS, preview isolation PASS, GuardDog **91/91**. Native compilation/JUnit, APK identifiers and Pixel acceptance remain **NOT RUN**.

## D3 policy reconciliation — signed runtime manifests restored; no implementation
- User verified first D1/D3 doc sync at `09bb101d396c35ea4e6795c2a4794825961cf15e`, then correctly identified conflict with Stage 0 §§9–10. **The prior APK-pinned ordinary bundle-key / APK-only rotation proposal is WITHDRAWN.** Stage 0 is unchanged and remains the governing policy mirror; its authoritative engine-owner record is in the other project.
- Added `docs/STAGE1D_D3_SIGNED_MANIFEST_RECONCILIATION.md`, answering the four concrete questions. Pinned primary/recovery ROOTS authenticate runtime signed trust manifests; manifests authorize/revoke everyday bundle keys with validity, overlap and monotonic trust state. Roots do not sign ordinary bundles. A fetched key is never trusted just because a backend supplies it. Recovery/version ordering requires certified engine-owner protocol; no ad-hoc override implemented here.
- Verified manifest updates use the SAME native owner/registry and a durable staged/committed generation with admission quiescence, invalidation/revalidation of BOTH M1/M2 accepted authority, and observed restart/recovery. `.trust/.retire` only affect future lookups; clear-authorization/binding calls leave private accepted bundles that can re-arm. Rejecting an update does not erase old caches. Requested certified T1–T5 interfaces explicitly cover these gaps.
- **Three separate outcomes:** known expiry requires defined cutoff/invalidation; a newly VERIFIED revocation invalidates affected authority without fallback to the revoked cache; offline without new revocation knowledge keeps valid LKG known-bad rules and fails open for unknown traffic, with stale/degraded disclosure. Backend outage alone never kills ordinary access. No unsigned expiry grace or instantaneous offline revocation promise. Proposed shutdown targets must be ratified/measured; timeout/contradiction remains unresolved.
- Frozen SDK offers registry mutation, Ed25519/JCS helpers, bundle validation/version primitives and some lifecycle/clear operations—not a complete primary/recovery manifest controller, trust journal or coordinated accepted-authority transition. Engine owner may certify a composition reusing existing primitives, adding hooks only where needed. Apollo main must not reconstruct that engine trust logic from prose or edit the 91 frozen files.
- **Historical D3 disposition:** policy conflict corrected; D3 production approval remains OPEN pending certified interfaces, inputs and evidence. D1 topology remains proposed/unapproved; D2/D4–D6 unchanged, Stage 1D NOT STARTED, CE-01/cutover unapproved, Stage 1C.1 launch PASS. At the time of this design record the six P0s were open; the iteration 64 closure above supersedes that status and unblocks—but does not pass—the separate native delivery/call acceptance rows.
- Earlier D1/D3 §4/current plan/Stage1C/device template now reference the reconciliation instead of presenting APK-only key rotation as current policy. Validation passed: all four questions and separate validity cases recorded; old current-policy assertions withdrawn; Stage 0, public contracts, runtime/dependencies/CI and P0 tracker unchanged; original review hash and GuardDog 91/91 intact; all six P0s and D1–D6 remain OPEN. New D3 documentation follows the verified `09bb101` snapshot and is not automatically assumed synced. No native trust/expiry/device test was performed; proposed timing targets are not measured guarantees.

## Focused D1/D3 concrete design — production bridge verdict, no implementation
- User requested engine ownership and trust construction together, not a general plan revision. Source baseline `956db060ec6905877371eeaeb703286f0b9c8f81`. Added `docs/STAGE1D_D1_D3_OWNERSHIP_TRUST_DESIGN.md`; only D1/D3 links/disposition updated in the main plan.
- **Existing frozen-bridge production route is NOT feasible through its public API:** private engine/verifier created with `TrustedKeyRegistry.m1Default()`, no registry/verifier/owner injection. A second owner would overwrite global references while active readers retain their captured reporter. Current Apollo module has no GuardDog constructor; no competing-owner device bug is claimed as already reproduced.
- **Conditional alternative for approval:** exclude `guarddog-expo-module` from Android registration/compilation while preserving its source; new process-lifetime `ApolloGuardDogRuntime` in Apollo's native module owns one core engine, injected public registry/verifier, durable version store and subscriptions. Direct public core/VPN constructors support this; CLI-only exclusion query kept Apollo and removed the vendor bridge without editing config. This is a topology/scope change, NOT proof both modules can safely coexist. If both must remain, defer production until an approved certified bridge exposes ownership/trust interfaces.
- Initial build-pinned ordinary-key rotation proposal is **withdrawn** by the D3 reconciliation above. Native test/prod isolation remains necessary, but production must use pinned primary/recovery roots plus runtime signed manifests, not mandatory APK updates for routine keys. Frozen core's public test literal may remain as unused code; active production trust must exclude it.
- **Production validity limit:** expiry/admitted-authority updates need explicit certified semantics and measured shutdown behavior. Post-drop suppression cannot prevent the drop. Offline revocation discovery delay is already accepted policy; instantaneous offline revocation is not a requirement. This is a D3 interface/evidence limitation, not an invented P0-07.
- D1/D3 design is provided for disposition; **D1–D6 remain OPEN, Stage 1D NOT STARTED, CE-01/cutover unapproved**. At this historical design point the six original P0s were open; iteration 64 later verified them closed. Native/Patrol acceptance remains split and physical-device delivery/call negatives remain required. Stage 1C.1 user launch PASS unchanged. No source/config/runtime changes, native build or device test occurred in the D1/D3 design task.
- The previous eight-document handoff was verified at `956db060`, and the first focused D1/D3 design was user-verified at `09bb101`. Their pending-sync notes are superseded. The later D3 reconciliation above is new workspace content; Stage 1C §§18–19 record the progression.

## Stage 1D revised plan / original review intake complete — implementation NOT STARTED (2026-09-20)
- User supplied `Apollo_Review_2026-09-20.md`, reviewing `da60c0372650dead26caeb25c458f8ca7cebd6a2`. Full original archived unchanged at `docs/reviews/Apollo_Review_2026-09-20.md`; SHA-256 `e2704cf1ee89850d8ca39fa50b136ce09575ff4e45e8cfafeb986288c6de2788`. Original historical launch-pending wording does not override subsequent **Stage 1C.1 fresh Pixel 10 launch PASS**.
- **Historical intake state:** P0-INTAKE was resolved while all six findings were still open. P0-01 backend internal-address/redirect connections; P0-02 misleading freshness/recovery; P0-03 call rejection to biting; P0-04 privacy disclosure/processing conflict including automatic messages; P0-05 privacy policy rejects evidence upload/no reliable delivery; P0-06 unread/limited files get unsafe reassurance. No fix was attempted in that plan-only task; the iteration 64 closure above is the current authority.
- `docs/APOLLO_STAGE1D_PLAN_REVIEW.md` revision 2 incorporates the user's six directions. **D1–D6 remain OPEN pending detailed design/approval:** prove one owner even with both modules loaded; truthful selective-filter status; explicitly separate test trust from production trust; original event identity with replay/dedup/retention/privacy rules; unsupported block/unblock returns unsuccessful with no implicit allow-policy bypass; bounded fresh start/stop observations with timeout/conflict UNRESOLVED and recovery separate.
- `docs/STAGE1D_CONTRACT_EXTENSION_PROPOSAL.md` CE-01 proposes one `packet_filter` enum addition plus exhaustive label/tests, **separately reviewed and NOT implemented/approved**. Current contracts and all frozen GuardDog source remain unchanged. If no truthful contract is approved, defer incompatible integration; do not label it dns_filter/none/simulated.
- Device template requires source SHA + APK build ID/hash on each new run, exact trust scope/contract revision, dual-module owner evidence and separate results. **A4N native intentional packet blocking may pass independently; A4E full Patrol/backend/eligible notification acceptance is BLOCKED by P0-05 until fixed/verified.** P0-04 constrains the narrow payload; call rejection is a mandatory negative blocked by P0-03; consumer freshness/recovery acceptance is blocked by P0-02.
- **P0:** separately plan and verify the six remedies; backend exposure risk is not postponed by mobile stage work. **P1:** resolve D1–D6 and get implementation approval; no runtime changes or production-default cutover approved now. **P2:** source review's P1/P2 consumer/Higgins/other-platform recommendations remain preserved/deferred, not closed.
- Revision 2's eight handoff files were subsequently verified byte-for-byte on GitHub main `956db060ec6905877371eeaeb703286f0b9c8f81`, superseding earlier `da60c03`/pending-sync observations. Stage 1C §§16–17 record that handoff. Original review matches its upload hash; six P0s remain OPEN, intake alone resolved; native/pipeline dependencies unchanged. The later focused D1/D3 document above is new work and is not claimed to have been included in that earlier sync.

## Current acceptance — fresh Pixel 10 launch PASSED (user-verified, 2026-09-20)
- User reported **“App is running as expected”**, then answered **“Yes”** when asked explicitly if this was the freshly built APK running on their Pixel 10. **Stage 1C.1 physical-device launch gate is passed**; the prior post-splash blocker is closed on that user evidence. No independent device test by the agent is claimed.
- Exact APK/build ID/hash, Android version, APK-to-source mapping, explicit repeat/reboot test, native start/stop, packet blocking and push delivery were not supplied or demonstrated; do not imply those passed.
- **Stage 1D remains NOT STARTED, awaiting separate approval**, rather than blocked on initial launch. **P0:** retain the passed launch record and preserve GuardDog. **P1:** approved runtime/adapter integration, then native start/stop and packet-block tests. **P2:** later Higgins/consumer/iOS/desktop integration remains deferred.
- Canonical acceptance record: `docs/APOLLO_STAGE1C_BUILD_INTEGRATION.md` §15. Saved dependency-guard implementation SHA is **`6d71e8f4a48a8a0e22d5a74b4d6e395e7cc62094`** (verified from Git history); supersedes the prior report's pending-save caveat. GuardDog hashes 91/91 unchanged. Recording this acceptance changes documentation only.

## Native dependency duplication guard — implemented and independently verified
- User requested a read-only post-merge/native-build safeguard after the SVG launch crash. `frontend/scripts/native-dependency-guard.cjs` + `scripts/native-dependencies/{policy,scan}.cjs` scan nested/scoped/hoisted installed packages and Expo search roots, failing on multiple native physical copies (even same-version copies); symlinks to one copy are not duplicates. Prints all versions/paths; never changes dependencies.
- Explicit coverage: SVG, Reanimated, Screens, Gesture Handler, Safe Area Context, WebView, Worklets, React Native, Keyboard Controller, AsyncStorage, Expo and Expo Modules Core. Native metadata automatically includes other Expo/scoped/third-party native modules.
- Wiring: `.github/workflows/native-dependencies.yml` PR/push post-install job; existing `yarn security:preflight`; Android/iOS `withNativeDependencyGuard` prebuild plugin. EAS's early pre-install lifecycle logs DEFERRED for dependencies only; post-install managed prebuild is mandatory. No package manifest/lockfile changes; existing SVG 15.15.4 pin preserved.
- One-time audit: **888 packages inspected / 50 native packages / zero duplicates / zero errors**. Focused tests **44/44**, changed-code lint, resolved Expo config and actual combined preflight pass. Independently verified in `test_reports/iteration_61.json`, including workflow wiring, preview load, SVG pin preservation and GuardDog hashes **91/91 unchanged**. Full details/inventory: `docs/NATIVE_DEPENDENCY_GUARD.md`; Stage 1C §14 links it. No hosted CI or physical/native build success claimed here. No package/lockfile changes.
- **P0:** initial fresh-APK Pixel 10 launch is now user-verified above. **P1:** Stage 1D awaits separate approval; start/stop and packet blocking remain separate. **P2:** Higgins/consumer/other-platform wiring deferred. Stop/report any duplicates before changing versions; GuardDog remains frozen.

## Support's SVG crash fix — provenance (subsequent Pixel confirmation recorded above)
- **Exact post-splash cause:** duplicate `react-native-svg` copies registered `RNSVGCircle` twice. Support ticket **257445**, commit **`01a30ae72accc3c366492f0217d7fec3cdce866a`** (2026-09-19 18:10:55 UTC), records: `Invariant Violation: Tried to register two views with the same name RNSVGCircle`.
- **Dependency chain:** app uses SVG `15.15.4`; `@nandorojo/heroicons@0.3.0` requested `^13.1.0`, resolving separately to `13.14.1`. Support added `resolutions.react-native-svg = 15.15.4` and regenerated `frontend/yarn.lock` to retain one copy. Only these two dependency files changed in that fix.
- **Verification:** Support reports successful deploys/Android builds and emulator launch to Home. On 2026-09-20, local commit/patch inspection, `yarn why` and Node resolution from both consumers confirm the single `15.15.4` copy; GuardDog manifest 91/91 matches. No new emulator/physical-device run was performed for this documentation update.
- **P0:** User has confirmed that the freshly built APK runs as expected on Pixel 10. Exact build ID/commit/APK hash/Android version and repeat/reboot results remain unspecified, not fabricated. **P1:** Stage 1D has not begun and awaits approval; native start/stop and packet-block evidence remain separate. **P2:** Higgins/consumer integration and later iOS/desktop engine adapters remain deferred.
- **Canonical incident record:** `docs/APOLLO_STAGE1C_BUILD_INTEGRATION.md` §13 contains the exact exception, commit/ticket, fix, evidence boundaries, and recurrence checklist. Earlier “non-blocking” SVG notes and SecureCore root-cause attribution below are historical, not the resolved cause of this crash. Do not repeat the retracted native-init timing hypothesis.
- Documentation-only update; no application code or GuardDog changes. Support's statement that the blocked GitHub push did not expose keys is recorded with attribution, not as a new security audit.

## Investigation before Support's fix was identified — historical, superseded by §13
- User reports: **"App installed and still stopping"** after the Firebase replacement. Follow-up confirms the Android **"Apollo keeps stopping"** dialog (not SafeStart) and apparent continued background presence. Background presence is not evidence of live protection: surviving notifications/recent-task entries or service/process restarts remain possibilities, not established causes. Physical-device launch is NOT verified; prior SafeStart/policy work did not establish resolution. Stage 1D remains blocked.
- Supplied production logs show successful Uvicorn startup and repeated `/health` 200 responses, plus one `/` 404. They contain no Android crash stack or MongoDB startup error. Sandbox `/api/health` was also verified to return healthy JSON; that is not proof of production device behavior.
- Deployment scan's transient OAuth TTL and secret `.gitignore` findings were retracted after source verification. Remaining scan flag about Expo `--tunnel` is a development-preview setting, not an evidenced APK/backend connectivity blocker; independent troubleshooting confirmed this. No infrastructure, auth, or secret-tracking changes were made.
- An initial troubleshooting hypothesis blaming module-scope native access was retracted after inspecting Expo 57's synchronous native-module initialization. Do NOT lazify the selectors as a guess: deferred validation could bypass the layout's existing boot-error snapshot. No native root cause has been established.
- Android autolinking resolves ApolloSecurity, GuardDogExpoModule and required Expo modules. Firebase/app identifiers match. Device confirmed by user: **Google Pixel 10**; Android version not provided. No `adb`, JDK, device logcat, or current APK/build ID is available here. The user confirmed Android's crash dialog, not SafeStart. Pixel on-device bug-report instructions were supplied, but the follow-up marked every step skipped and attached no report; do NOT treat skipped steps as completed or assume crash data. Next required evidence: Android crash log from launch through failure. The exact installed APK can also help verify packaged configuration, but cannot on its own prove the crash cause or resolution. No application code changed during this investigation.

## Firebase configuration replacement — historical configuration-only verification
- User supplied `f60xq9zf_google-services.json`; replaced `frontend/google-services.json` with its configuration for Firebase project `apollo-243ad` and Android package `app.apollo.hwg`. This supersedes the older `fit-beyond-50` configuration and its unrelated clients. `app.json` already points to this file with the correct package and bundle identifiers; no application code, security policy, or certified GuardDog source changed.
- Focused validation passed: full supplied JSON object matches the saved file; Android/iOS identifiers match; exactly one Firebase client matches the Android package; Firebase project number/app ID are consistent; `npx expo config --json` resolves the correct package, file, and notifications plugin; security/boot tests 15/15; GuardDog SHA-256 provenance manifest 91/91. Restarted Expo and verified onboarding renders in the external preview. No full regression run for this config-only change; no APK generated or physical-device/push sign-off claimed.
- **P0:** A fresh native Android build and physical-device launch past splash are still required. SafeStart is a fail-closed error screen, not proof of a successful native launch. This configuration update does not prove native launch or push delivery.
- **P1:** Stage 1D runtime/adapter wiring remains blocked until explicit successful physical-device launch evidence. Then verify native start/stop and real packet blocking before claiming enforcement.
- **P2:** Higgins/consumer UI integration and later iOS/desktop engine adapters remain deferred.
- Firebase project changed: Android push-sending service-account credentials must belong to `apollo-243ad`. The uploaded client config is not a service-account credential; existing server-side push configuration was not changed or validated here.

## Original problem statement
Privacy-first mobile security app (iOS/Android, Expo + FastAPI + MongoDB) that detects, explains and — only where verified — blocks dangerous links, suspicious websites, unsafe connections and known threats. Four exact user-facing states: Patrolling / Growling / Barking / Biting. Apollo's Patrol shows what happened. Capability-aware, truthful UI; on-device-first; minimal indicators to backend; native module bridge (Swift/Kotlin) from day one; HuCentAI SecureCore mock SDK contract. The legacy internal key `resting` is storage-only and must never be shown to users.

## User choices
- Ask Apollo: Gemini 3 Flash (user's own Google key, via emergentintegrations)
- Patrol: anonymous device ID + backend sync of event summaries (no accounts)
- Reputation: Google Safe Browsing (user key — currently rejected 401 by Google; surfaced truthfully as "Unavailable") + Apollo managed blocklist
- Design: dark "sentinel" palette (Sentinel Navy #0B1220, Charcoal, Slate, state colours green/amber/orange/red), Outfit + Geist fonts
- Native shell: TypeScript adapters + Swift/Kotlin Expo Module stubs + HuCentAI SecureCore mock SDK

## Architecture
- backend/server.py — FastAPI: /api/health, /api/devices/register, /api/intel/status, /api/intel/check (HMAC digest cache, blocklist + Safe Browsing), /api/patrol/events (upsert/list/patch/soft-delete), /api/trust, /api/ask/stream (SSE) + /api/ask/history
- frontend/src/domain — types, stateMachine (fast escalation, strict recovery: cooldown + fresh verification), risk (local deterministic URL checks), decision (local + intel → state), privacy (egress allow-list enforced in code), capability
- frontend/src/security — SecurityPlatformAdapter + Mock/IOS/Android adapters, fail-closed selector (EXPO_PUBLIC_SECURITY_MODE); securecore/ (HuCentAISecureCore contract, MockSecureCore + 21 scenarios, NativeSecureCore bridge, errors, safe logger, fail-closed selector EXPO_PUBLIC_SECURECORE_MODE)
- frontend/modules/apollo-security — local Expo Module: Swift + Kotlin stubs (truthful capabilities, blocks return verified:false)
- frontend/app — onboarding, (tabs)/{home,guard,patrol,ask,settings}, check (modal), patrol/[id], dev-tools (mock only)
- Docs: /app/SECURECORE_INTEGRATION.md

## Implemented (2026-06)
- Phase 1–5 MVP: domain layer, state machine, Patrol, capability model, privacy guardrails; native shell + truthful status UI; Check-a-link with local + intel; four states w/ thresholds; Patrol timeline + detail + Trust This (growling only, exact link) + revoke; verified block → Biting (mock adapter simulated, labelled); cautious de-escalation (2-min cooldown, verify-now freshness 10 min); Ask Apollo streaming explanation-only.
- Testing iteration 1: backend 13/13 after 422 fix; frontend flows verified (barking→biting→contained→growling→verify→resting; growling→trust→settings).
- Iteration 2 (2026-06): Share Intake (expo-share-intent config plugin for iOS Share Extension + Android ACTION_SEND; `/check?url=&source=` deep link auto-run; clipboard link banner on Home, native only). Threat Benchmark (shared corpus `src/benchmark/corpus.json` 60/60; in-app `/benchmark` screen scoring detection/FP vs gates; backend `POST /api/intel/check-batch`; pytest `tests/test_benchmark.py` → `/app/test_reports/benchmark_report.json`). Site Guard native: Android DNS-only `VpnService` filter (Kotlin) + module wiring; iOS Safari Content Blocker extension + `plugins/withApolloSiteGuard.js` config plugin + EAS appExtensions config; `SITE_GUARD_NATIVE.md`. Australian privacy disclosure screen in onboarding + Settings. Testing iteration 2: all pass.
- Iteration 3 (2026-06): Connection Guard (NetworkStatus wifiSecurity/captivePortal/vpnActive; Android WifiInfo.currentSecurityType + NET_CAPABILITY_CAPTIVE_PORTAL; iOS NEHotspotNetwork limited; `domain/connection.ts` → growling connection events, deduped). Weekly Patrol Digest (`domain/digest.ts`, Home card, `/digest`). Benchmark History (local, bar charts, `/benchmark`). Family Sharing (`/family`; backend `/api/family/*`: guardian email via Emergent Resend w/ confirm link + 5/day cap, pairing codes, shared_events fan-out on barking/biting). Testing iteration 3: 30/30 backend, all frontend flows pass.

- Iteration 4–6 (2026-06): Production security hardening (`src/security/securityConfig.ts` validator; `EXPO_PUBLIC_APP_ENV`; `.env.production` pins native; `scripts/security-preflight.mjs` as EAS `eas-build-pre-install`; `tests/securityConfig.test.ts` 8/8 via `yarn test:security`; docs in SECURECORE_INTEGRATION.md §7). Guardian Reply (`POST /api/family/shared-events/{id}/ack`, `GET /api/family/acks`; UI in /family). Wi‑Fi Memory (NetworkStatus.ssid; trusted SSIDs local; Guard trust/forget). Export Patrol (expo-print PDF + expo-sharing; Patrol header button). Biting → green "Threat contained" confirmation after containment. Brand logo/app icon/adaptive icon/splash/favicon from user asset (`assets/images/logo.png`, `ApolloLogo` component in Home header, onboarding, hero). Testing iterations 4–5 all pass.
- Iteration 7 (2026-06): New Doberman logo/app icon applied to icon, adaptive-icon, splash, favicon, logo.png. **Alert notifications** via Emergent-managed push relay: backend `POST /api/register-push` + `send_push()`; pushes to (a) owner when a barking/biting event is synced with `background: true` (native Site Guard, app closed), (b) paired guardian devices on fan-out, (c) protected owner when a guardian acks. Frontend: `src/push/notifications.ts` (lazy-loads expo-notifications — null in Expo Go/web to avoid SDK 53+ crash), `_layout.tsx` handler/channel/tap handlers/weekly nudge, Settings "Alert notifications" card, registration on device identity and after setup. `EMERGENT_PUSH_KEY=placeholder` in backend/.env (set by deploy pipeline). Guardian Reply UI verified end-to-end (iteration 6 tests 14/14).
- Iteration 8 (2026-06): Shield Doberman logo applied to all icon assets (ApolloLogo now contentFit=contain). Push sounds: `assets/sounds/apollo_bark.wav` (threats channel, MAX) + `apollo_chime.wav` (family channel, HIGH) + `growling` channel (DEFAULT); backend payloads set channel_id/sound. Family alert tap → `/family/alert/[id]` (Call/Message via tel:/sms:, phone from owner at pairing `phone` or watcher override `POST /api/family/links/phone`, ack buttons). Quiet hours (`PUT/GET /api/devices/{id}/settings`, growling background pushes + in-app growling toasts held; barking/biting always through; Settings card with TimeStepper). Battery saver (slower tick, hero animations off) + "Minimise Apollo" (Android BackHandler.exitApp; iOS/web guidance toast) on Settings and Home. Hero animations per state (patrolling breath+look-around, growl rumble, bark bounce, bite lunge). "Resting" renamed to "Patrolling" in UI (STATE_NAME; internal key unchanged). Guard fix: capability→permission sheets merged into one Modal. Google Safe Browsing key updated → status ok. Iteration 7 tests: backend 15/15, frontend pass.
- Test Alert Button (2026-06): Settings → Alert notifications → "Send me a test bark" (shown when push permission granted on a native build) → `POST /api/push/test {device_id}` relays a sample barking alert on the threats channel with the bark sound. Returns 500 with friendly detail when the relay isn't configured (dev placeholder key).
- In-App Alert Preview (2026-06): Settings → "Preview an alert" opens `AlertPreviewSheet` (mock notification card, Threat/Family tabs, plays bundled bark/chime via expo-audio; plugin microphonePermission=false).
- Gate 2 — Text & Messaging (2026-06): six-state model (sniffing/resting=Patrolling/ears_up/growling/barking/biting=Guarding; STATE_NAME/LABEL/MEANING in types.ts; theme colours sniffing/ears_up). On-device rule engine `src/domain/messageAnalysis.ts` (M01–M15) + backend `POST /api/message/analyse` (URL reputation for message links + Gemini second-opinion explanation JSON, never overrides verdict) + `POST /api/message/extract` (screenshot → text via Gemini vision). Screen `app/message.tsx` (paste/screenshot, result, links hand-off to /check, Verify Sender sheet, Tell me more → Ask, recovery, Mark as safe). Threat Scent `src/domain/threatScent.ts` (30-min window, brand+host keys incl. brand-in-hostname, 2 gates → barking; Home 'Connected events' cards). Share intake routes text → /message. Message Guard capability; `MessagingSdk` contract stubs. `yarn test:gate2` 20/20.
- Gate 3 Phase A — Website & Browser (2026-06): `POST /api/intel/check {expand:true}` follows redirects (≤5 hops) → redirect_chain/final_url, judges final destination; `POST /api/feedback` (Report mistake / override). `src/domain/brand.ts` Brand & Impersonation engine (OFFICIAL_DOMAINS list, homograph deobfuscation, verifyWebsite). decision.ts: brand mismatch → barking (login context/homograph) or growling; uncertain → ears_up ("I don't know this website well yet"); redirect chain in Why. check.tsx: calm "Apollo is guarding — I blocked a dangerous website." copy, redirect/brand pills, Verify website, Technical details, Continue anyway (override recorded + feedback), Report mistake, shared `RecoveryFlow` (clicked/password/card/code/download/app/called). `WebSdk` contract stubs. `yarn test:gate3` 18/18. Patrolling GIF (`assets/images/apollo-patrolling.gif`, watermark cropped, transparent) in Home hero. tsconfig: allowImportingTsExtensions for node:test runtime imports.
- Gate 3 Phase B (2026-06, DONE): `POST /api/page/extract` (Gemini vision → security-signal JSON, image not stored) + `src/domain/pageAnalysis.ts` rule engine (W08 fake virus, W09 fake support, W14 remote access, W10 fake shop, W11 payment, W12 wallet drainer, W18 fake CAPTCHA, W02/W03 fake logins, W17, W20). check.tsx 'Add a screenshot of the page' → check-page-card; merges/escalates existing link event via `recordPageAnalysis` or creates a website event. `yarn test:gate3page` 15/15. Backlog: W16 notification spam, downloads/app-install hand-offs (Gates 6/7), Gate 4 phone calls.
- Android push: `frontend/google-services.json` (Firebase project fit-beyond-50) wired via `expo.android.googleServicesFile`; app identity changed to `app.hwg.apollo` (iOS bundle ID + Android package + content blocker `app.hwg.apollo.contentblocker` + app group `group.app.hwg.apollo.apollo`) to match Firebase. Push only works on Publish → native builds (not Expo Go / web).

## Known gaps / notes
- Safe Browsing key returns 401 (API not enabled on the key's Google Cloud project or key restricted to Generative Language API). Enable "Safe Browsing API" for that project or create a separate key; backend picks it up from SAFE_BROWSING_API_KEY.
- Native code (share extension, DNS filter, Safari content blocker, Wi‑Fi security) only runs in EAS dev/prod builds (Publish → build); Expo Go/web use labelled mocks.
- PUBLIC_API_BASE in backend/.env must be the production https host after deploy so guardian confirm links work.

## Backlog
- P0: Real Safe Browsing key; EAS dev build validation of ApolloSecurity module, DNS filter, Safari content blocker, share extension
- P1: Connection Guard (Wi‑Fi safety), store permission copy review
- P2: Benchmark history/export; iOS Network Extension for non-Safari coverage
- Gate 7 — Apps & Device (2026-06, iteration 14): `src/domain/appAnalysis.ts` App & Device Engine (A01–A20; context-aware score: source + unexpected-for-purpose permissions + call/scent timing + brand/update impersonation + SDK network; off-store impersonators get no purpose credit) + `deviceAnalysis.ts` (Protected/Review/Action/Recovery, D01–D11, truthful cannot-see list). Screens `app/app-check.tsx` (Check This App: name/dev, source/purpose chips, permission multi-select with long-press plain-language explainer, context switches, Access/Network/Reputation cards, Open Settings via `utils/deviceSettings.ts` Android intents / iOS openSettings+path toast, Stay With Me, Keep/Report) and `app/device.tsx` (Check My Device: status, findings with Open Settings, self-report switches, Save to Patrol). Backend `POST /api/app/analyse` (remote-tool/security-vendor/brand-impersonation hints, SDK hosts → intel, Gemini second opinion never overriding). Categories `app`/`device`; recovery kinds remote/accessibility/profile/banking_during_access; handoffs File→App (keeps scent), Call→App. `AppDeviceSdk` contract stubs. Tests: `yarn test:gate7` 36/36, `tests/test_gate7_app.py` 9/9.
- Gate 8 — Network & Accounts (2026-06, iteration 15): `src/domain/networkAnalysis.ts` (N00–N12: public≠malicious, lookalike SSID, open Wi‑Fi ears_up, captive portal → Gate 3, VPN trusted/unexpected, DNS change, SDK blocked → Guarding calm, C2 → bark + Gate 7) + `accountAnalysis.ts` (AC01–AC20: unexpected MFA → BARK "Don't approve this login", MFA fatigue, fake reset/alert off official domain → BARK + web handoff, genuine alerts ears_up, expected activity resting, code/password entered → Stay With Me, locked out, recovery changed; takeover risk). Screens `app/network.tsx` (Network Guard dashboard: protection status from capabilities, current network, 24h activity + Check This Network) and `app/account.tsx` (Account Guard dashboard of open account events + Check Account Alert + breach exposure card). Backend `POST /api/account/analyse` (URL intel + per-provider official-domain match + password-scrub validator + Gemini), `POST /api/account/breach` (HIBP when `HIBP_API_KEY` set, else truthful not_configured). Category `account`; recovery kinds mfa_approved/locked_out; handoffs Message→Account, Call(code/password)→Account. `connection.ts` open Wi‑Fi background event now ears_up (N04). Hero shows `assets/images/apollo-barking.gif` for barking/biting. Tests: `yarn test:gate8` 34/34, `tests/test_gate8_account.py` 8/8.
- Backlog: HIBP key for live breach checks; Gate 1 (Email) PRD; native Swift/Kotlin SDK implementations behind the documented contracts; stale assertions cleanup in tests/test_apollo_backend.py; web bytes path in file.tsx.
- Gate 1 — Email (2026-06, iteration 17/18): `src/domain/emailAnalysis.ts` (parseEmail headers/body/attachments; E01–E13: official sending-domain check per brand, off-domain login links, risky attachments, changed bank details/BEC, code/identity asks, reply-to mismatch) + `app/email.tsx` Check an Email (From/Subject/Body or pasted forwarded email; links → /check, attachments → /file, account alerts → /account with scent, Verify sender, RecoveryFlow). Category `email`; reuses `POST /api/message/analyse`. Guard tab "Network & Accounts" section: Network Guard card (connection_guard status + summary → /network) and Account Guard card (open account events → /account). Home "Check an email". `yarn test:gate1` 13/13.
- Fixes: Site Guard permission now persisted by MockSecurityAdapter (`apollo.mock.permissions`, iteration 16); account.tsx recentLinked includes `email` (iteration 18). Hero GIFs: patrolling / growling (`apollo-growling.gif` — currently identical to barking, user to supply distinct file) / barking+guarding.
- Share Into Apollo (iteration 19/20): `src/share/classifyShare.ts` routes shared payloads (file → /file, image → /message screenshot, email headers/body → /email, login/MFA/reset text → /account, bare link → /check, else /message) + alternatives; `app/share.tsx` landing ("Looks like …", Check as …, Not that?); `ShareIntakeListener` → /share; app.json share-intent accepts text/images/files (native build only; web uses /share?text=|url=). message.tsx accepts `imageUri`, file.tsx accepts `uri/name/mime/size`. Home "Share to Apollo" capability now "available" on native.
- Incident Timeline (iteration 19/20): `src/domain/incidentPlan.ts` (ordered timeline, highest state, recovery kinds inferred from recorded "You told Apollo" entries + scenarios, one deduplicated Stay With Me plan) + `app/patrol/scent/[id].tsx` (tickable steps, Ask, mark whole incident handled → resolves all linked events). Home Threat Scent card tappable; event detail "View incident timeline". `RECOVERY_STEPS` moved to `src/domain/recovery.ts`. Store: `eventsRef` makes back-to-back upserts safe; `refresh(minVisibleMs)` — Verify now holds Sniffing ≥900ms. Hero GIFs: sniffing / patrolling / growling (distinct 43-frame file) / barking+guarding. `yarn test:share` 11/11.
- Family Incident Sharing (iteration 21): protected user taps "Ask my family for help" on an incident timeline → `POST /api/family/incidents/share` fans out headline/timeline/steps/ticks (never message text) to paired guardians + push; ticks/handled mirrored via `PATCH /api/family/incidents/{scent_id}/progress` (tick state persisted locally at `apollo.incident.<id>`). Guardian: Family → "Incidents shared with you" → `app/family/incident/[id].tsx` (read-only timeline, live progress, Call). Weekly Digest: "Connected incidents" card (`buildDigestIncidents`: handled vs open, stopped vs still-open events, tap → timeline). Palette locked to spec: sniffing #9EABB8, ears_up #D9A441, growling #E47A3F, barking/biting #D9534F (+ tints, export colours). Tests: `test_family_incidents.py` 3/3, `yarn test:share` 12/12.
- Cleanup (2026-06): `tests/test_apollo_backend.py` assertions made Safe-Browsing-state agnostic (clean/full when key ok, unknown/partial otherwise) and rerun-safe (cached flag, blocklist >= 4) — 14/14. Incident-share push idempotency key uses `ts.isoformat()`.
- Hero GIF fixes (2026-06): sniffing/growling/barking GIFs re-encoded with transparent backdrop (`scripts/gif-transparent.py`, edge flood-fill so shield highlights stay). Code-driven dog shake/bounce/lunge removed for all GIF states (growling rumble, sniffing ticks/tilt, barking bounce, biting lunge) — GIFs carry the motion; ring + glow pulses remain. Resting breath and ears_up (static logo) unchanged.
- Family Reassurance Note (iteration 22): guardian → `POST /api/family/incidents/{scent_id}/notes` (kinds here/calling/on_way/together/custom ≤140; `from_name` remembered as link `guardian_label`; push to protected device → `/patrol/scent/<id>`), `GET …/notes` (protected sees all, guardian own). Guardian screen "Send a reassurance note" card (chips, optional custom line, name); protected timeline "From your family" card (polls 15s, warns never to give codes/passwords even to family). Tests: `test_family_notes.py` 2/2; E2E `/app/tests/test_family_notes_e2e.py` full pass.
- Deployment health check (2026-06): blocker fixed — reputation_cache TTL index removed (plain index; expiry checked at read time; existing TTL index dropped). Integration base URLs now env-driven (`EMERGENT_INTEGRATIONS_BASE_URL`). Root .gitignore no longer excludes .env files. Status: pass with one warning — Android push needs `frontend/google-services.json` from Firebase (user to supply).
- Family Weekly Check-In + Guardian Call-Back (iteration 23): `GET /api/family/weekly?device_id=<guardian>` — count-only 7-day rollup per watched person (total, by_state, alerts/open/handled, blocked, active_days, shared incidents, last_seen_at, phone; never headlines). Family screen "Weekly check-in" cards (`src/domain/familyWeekly.ts`: calm/handled/needs-a-call/no-news sentences, last-active line, Call button); pair card copy discloses it to the protected user. Reassurance notes carry an optional guardian `phone` (scrubbed, remembered on link) → protected timeline shows "Call <name> back". Tests: `test_family_weekly.py` 3/3, `yarn test:family` 7/7, E2E `/app/tests/test_family_weekly_e2e.py` full pass.
- Sunday Check-In notification (iteration 24): backend loop (`weekly_checkin_loop`, every 15 min) pushes one gentle summary per guardian per ISO week inside their local Sunday 17:00–20:59 (device `tz_offset_minutes` now sent on register; falls back to quiet-hours offset), respects quiet hours, dedupes via `weekly_checkin_sends`, skips opted-out devices. `weekly_sentence()` mirrors frontend wording. Endpoints: `GET/PUT /api/family/weekly/notify` (pref + last_sent), `POST /api/family/weekly/send-now {preview_only}` (text preview on web; real push on native). Family screen weekly card: Sunday toggle, "Preview the notification", native-only "Send it to me now". Tests: `test_family_weekly_push.py` 5/5. Push delivery itself needs a native build.
- Check-In Reply (iteration 25): guardian taps "All good, spoke to Mum" / "Messaged them" on the weekly card → `POST /api/family/weekly/checkin` (one per guardian/person/week, upsert; push to protected device "Sam checked in"), `GET /api/family/weekly/checkins` (protected: received, guardian: sent). Guardian sees "Checked in · … · Sun" pill; protected user sees "Sam checked in — All good, spoke to you" in Family → Family responses. Tests: `test_family_checkin.py` 2/2; self-tested in web.
- Higgins, owner attribution, Tuesday nudge (iteration 26): **Owner**: Apollo is a brand of Harmony Wellness Group (privacy disclosure intro, Settings About card + footer, guardian email footer). **Higgins** = Apollo's handler (proper old English gentleman, butler-like; never "sir/madam") and the voice of the app: `HIGGINS_VOICE` persona prefix on all Gemini prompts; "Ask Apollo" → "Ask Higgins" (tab "Higgins"); STATE_MEANING, RECOVERY_STEPS, weekly/nudge sentences and push titles in Higgins voice. **Spoken audio**: `POST /api/voice/speak` → OpenAI TTS `tts-1`, voice `fable`, speed 0.95 via EMERGENT_LLM_KEY, cached in `voice_cache`, served `GET /api/voice/<key>.mp3`; frontend `src/voice/higgins.ts` (single expo-audio player, playsInSilentMode) + `HigginsSpeakButton`: Home hero, each Ask reply, check result (compact), Settings "Hear a sample"; Settings toggle "Read alerts aloud automatically" (`apollo.voice.auto`) auto-reads barking/guarding check results. Disclosure lists TTS as overseas processing. **Tuesday nudge**: `missed_checkin_tick` (Tue 17–20 local, once/week, opt-out shared with Sunday toggle) names people not checked in since Sunday; preview via `send-now kind=nudge` ("Preview Tuesday's"). Tests: test_voice 2/2, test_family_nudge 2/2, weekly push 5/5; E2E iteration 26 full pass. (on_event → lifespan migration done in the backend split.)
- Higgins Greets You (iteration 27): `src/domain/higginsGreeting.ts` (time-of-day opener + state line, deterministic per day; `yarn test:higgins` 6/6) + `HigginsGreeting` card under the Home hero — shown on the first open of each local day (`apollo.higgins.greeted`), matches Apollo's state (incl. visibility lost → Guard), Hear Higgins button, spoken automatically when the Settings auto-read toggle is on, dismiss with X. Self-tested in web (show → dismiss → hidden after reload).
- Higgins Reads Patrol (iteration 28): `src/domain/higginsNarration.ts` (`narrateEvent`: state → what → why with ordinals → what to do → handled/contained; `narrateIncident`: summary → events in order with times → plan intro → "Step N[, already done]" → closing; `yarn test:narration` 3/3). Voice module gained a queue (`speakHigginsSteps`, `useHigginsReader`): plays chunks back-to-back via the player's finish status, prefetches the next mp3, Stop cancels. `HigginsReadAloud` component (button + "Reading 2 of 4 — What happened") on event detail (`event-read-*`) and incident timeline (`incident-read-*`). Self-tested in web: auto-advance verified.
- Security Hardening Gate — step 1 truth of state (iteration 29): `ProtectionStatus` now {requested, operational, enforcementMethod, coverage, coverageScope, lastVerified, degradedReason} (+ `running` alias = operational). Android: `requested`/`since` persisted in SharedPreferences, `operational` = `ApolloDnsVpnService.isRunning` read live, start waits ≤2 s for establish(), degraded reasons (VPN permission / other VPN); pure `DnsPacket.kt` extracted + JUnit `DnsPacketTest.kt`. iOS: `requested` persisted in App Group, operational = extension enabled (observed) ∧ rules written, status/start/stop async after Safari callbacks, stop writes empty rules; pure `SiteGuardTruth.swift` + XCTest. Mock: never operational, `blockDestination` never verified (preview can't show biting). Guard master card: "Apollo is guarding / guarding what he can / off duty" + Requested/Enforcement/Verified pills + coverage + degraded reason (`src/domain/protectionTruth.ts`, `yarn test:truth` 5/5). Home/Network gates use `requested`; "Guarding in the background" card only when operational. Docs: SITE_GUARD_NATIVE.md "Truth of state" (coverage definitions, device QA list, sign-off rule). Native tests cannot run in this sandbox (no JDK/Xcode). Next: step 2 device auth (server-issued id + 256-bit token, hashed, rotation/revocation, no legacy binding) + CORS; then native tests on device; then split server.py.
- Security Hardening Gate — step 2 device authentication (iteration 30, IMPLEMENTED, E2E sweep pending): `POST /api/devices/register` (public) now issues a SERVER-generated device_id + 256-bit token (only SHA-256 stored, 365-day expiry; returned once); `GET /devices/me`, `POST /devices/heartbeat`, `POST /devices/token/rotate` (atomic), `POST /devices/revoke` (204). Router-wide `enforce_device_auth` dependency: everything except PUBLIC_PATHS (/health, /intel/status, /devices/register) and prefixes (/family/confirm/, /voice/) needs `Authorization: Bearer` (401 + WWW-Authenticate) and any `device_id`/`user_id` in path/query/JSON body must equal the token's device (403). No legacy binding: pre-token installs get a fresh identity. CORS: only `CORS_ORIGINS` env (empty; web preview is same-origin). Frontend: `src/auth/deviceIdentity.ts` (SecureStore native; AsyncStorage on web = preview-only, documented), API client attaches bearer & fails closed without identity; 401 → identity reset → toast → re-register new identity; SSE stream also authenticated. ApolloContext boot/completeSetup register/heartbeat via server identity (SecureCore mock identity no longer used for API). Tests: `tests/test_device_auth.py` 8/8 (raw, no shim); `tests/conftest.py` auth shim maps legacy ids→real registered devices for the older suites (documented); full backend suite 143/145 (2 known flakes: Gemini second-opinion timing, shared-events 2.5 s fan-out wait). Frontend smoke: register→heartbeat→all calls bearer-authenticated, no 4xx. TODO next: testing_agent E2E sweep (note: web identity key is `apollo.device.identity.v2`, tests pairing via API must use each context's token), device truth QA, failure-mode tests, backend split.
- Hardening Gate step 2 — E2E sign-off (iterations 30/31): two-device Family/Guardian sweep under device auth PASSED (create/join, incident share + note + check-in, cross-device 403s, 401 + WWW-Authenticate, revocation no-restore, second guardian, public paths, SSE authenticated). Bug found+fixed: reload after 401 silently re-registered → now `apollo.device.identity.reset.v1` marker persists the explicit reset state; boot never auto-registers while it is set; Home `identity-reset-card` → user taps "Register this phone again". Email confirm tokens single-use + 72 h expiry. `test_device_auth.py` 12/12 incl. lifecycle. Known gap flagged by tester: there is no "unlink a paired device" endpoint/UI (only guardian email removal) — candidate for the next session. **STATUS: Hardening Gate Step 2 — Device Authentication: COMPLETE.** Next: Device Truth QA (native builds) → Failure Mode Testing → Backend split into authenticated routers.
- Hardening Gate step 3 — failure modes (iteration 32): failure contract "unreachable ≠ unprotected; unknown ≠ safe". Frontend: `src/domain/serviceHealth.ts` (pure reducer + banner/stale copy + 401/403/5xx classification), `src/domain/intelContract.ts` (`parseIntelResult` rejects malformed intel → unavailable), `src/api/backendHealth.ts` (live reachability from every call + `/health` probes; recovery only on fresh success; 30 s/120 s re-probe while down + on foreground; on recovery: refetch + late registration), API client time budgets (20 s / 60 s long paths) + offline/timeout/malformed ApiError kinds, 403 never resets identity, boot never blocked by a hung service (15 s bounded register, fire-and-forget heartbeat). UI: `ServiceBanner` (Home/Guard/Family) with the agreed wording, Guard `masterCopy(p, online)` mixed states ("guarding what he can · DNS active · Online checks unavailable"), check.tsx intel unavailable/partial pills, `StaleNote` on Family/incident/notes, offline-specific copy on family incident/alert screens. Backend: SB wrong-shape guard, redirect expansion bounded 12 s. Tests: `yarn test:failure` 15/15, `tests/test_failure_modes.py` 17/17. Self-tested outage → banner → auto-recovery in web.
- External admin console (iteration 32): `X-Admin-Key` shared secret (`APOLLO_ADMIN_KEY` in backend/.env, constant-time compare, separate router, never mixed with device auth) → `/api/admin/{ping,stats,blocklist,feedback,devices,devices/{id},devices/{id}/revoke}`; blocklist edits flush the reputation cache; CORS allows the header (console origin must be added to `CORS_ORIGINS`). `tests/test_admin.py` 10/10. Test infra: conftest shim map shared across xdist workers.
- Hardening Gate step 4 — backend split (iteration 33, DONE, zero behaviour change): `backend/server.py` is now the 68-line entry point (FastAPI `lifespan` replaces `on_event`; indexes + blocklist seed + weekly loop task; router mounting; CORS). Code lives in `core/{config,db,models,auth}.py`, `services/{intel,email}.py`, `routers/{health,devices,intel,patrol,ask,family,family_weekly,voice,push,analysis,admin}.py`. Every `/api` router is mounted behind `enforce_device_auth`; `/api/admin` behind `require_admin_key`. Verified: identical route table (68 routes, same paths/methods/handlers), dependency wiring per route, full pytest 173/174 (1 pre-existing xdist log-tail race), testing-agent frontend regression PASS (iteration 33). Tests that import backend code now target `routers.family_weekly`, `services.intel`, `core.db`.
- Hardening Gate step 5 — native security tests (iteration 33, CODE DONE, DEVICE SIGN-OFF PENDING): Android `SiteGuardTruth.kt` extracted (pure truth derivation + `verifiedBlock`; module `statusJson()`/`blockDestination` delegate to it) + `SiteGuardTruthTest.kt` (8 JUnit tests incl. full packet→NXDOMAIN path, offline known-bad). iOS `SiteGuardTruthTests.swift` +5 tests (extension enabled but off duty, every degraded state explains itself, pure derivation, valid content-blocker JSON, case-insensitive dedupe — `rules(for:)` now dedupes). `SITE_GUARD_NATIVE.md` gained run commands and an 11-row physical-device verification matrix (permission denied/revoked, second VPN, reboot, backend down + filter on, offline unknown, background block, biting only with verified enforcement, recovery, admin revoke). Native tests cannot run in this sandbox (no JDK/Xcode) — they run in the Publish build pipeline / a dev machine; Expo Go and web preview are never sign-off evidence.
- Unlink Device (iteration 34): `GET /api/family/links` now returns `watchers` (link_id, guardian_label, since — never the guardian's device id) and `link_id` on each `i_watch` row; `DELETE /api/family/links/{link_id}?device_id=` (204) lets EITHER side end a pairing (soft delete + `unlinked_by`; strangers → 404, mismatched id → 403). All fan-outs/pushes/weekly rollups already filter `deleted_at: None`, so the removed phone stops receiving alerts immediately; re-pairing with a new code creates a fresh link. Family screen: "Who receives your alerts" rows with **Remove** (`family-watcher-remove-<link_id>`) and **Stop** on each watched person (`family-watch-stop-<pid>`), confirm dialog (Alert / web confirm). Tests: `tests/test_family_unlink.py` 3/3.
- Phase A — Android Apps & Device real signals (iteration 34, native build only): `AppDeviceCatalog.kt` (pure: 17-app remote-access RISK_CATALOG, store/browser/messenger → installSource mapping, accessibility/notification-listener setting parser, permission → plain-name map, `VISIBLE_PACKAGES`) + `AppDeviceSignals.kt` (real reads: Settings.Secure accessibility + notification listeners, ConnectivityManager VPN transport, DevicePolicyManager active admins, developer options, PackageManager lookups for catalog packages incl. `getInstallSourceInfo`, first-install time, requested permissions). Module now implements the AppDeviceSdk contract (`getAppDeviceCapabilities`, `getInstalledAppAssessment`, `getDeviceSecuritySignals`; install/security event feeds stay `[]`). Manifest `<queries>` lists exactly the 46 catalog packages — **no QUERY_ALL_PACKAGES, no AccessibilityService** (asserted by `AppDeviceCatalogTest.kt`, 5 JUnit tests). Fields Android cannot expose stay null (unknown sources per-app, overlay apps, user CA certs) and surface under "cannot see". app-check.tsx merges observed install source/permissions/remote capability into the on-device engine (`sdkPermissionsToApp`). Web/Expo Go keep the mock → verify on a Publish Android build.
- Watcher Names (iteration 35): `POST /family/link` accepts `guardian_name` (from the guardian's "Your name" field) → stored as `guardian_label`; `PUT /family/links/{link_id}/name` (guardian only) renames later; `i_watch[].my_label` exposes the current label. Family screen: watcher rows show the real name ("Sarah"), guardian rows show 'They see you as “…”' with a one-tap 'Use “<new name>” instead' rename. Empty name keeps the neutral "A family member". Egress allow-list (`src/domain/privacy.ts` family set) gained `guardian_name` — REMINDER: any new client-posted field must be added there or the request is blocked on-device. Tests: `test_family_unlink.py` 5/5; two-context E2E 10/10 (iteration 35).
- iOS Device Signals (iteration 35, native build only): `ios/DeviceSignalsTruth.swift` (pure) + module `getAppDeviceCapabilities` / `getDeviceSecuritySignals` / stubs. VPN on/off from tunnel interfaces (utun/ipsec/ppp/tap/tun via NWPathMonitor + scoped proxy keys) with `vpnProviderKnown` always null (Apple never names the provider); management profile reported "present" only when the app itself received a managed configuration, otherwise "unknown" — never "none". All other fields null → "cannot see". `deviceAnalysis.ts` D04b: observed VPN with unknown provider is an *info* fact ("Apollo can see that it's on but not who runs it"), Apollo's own Android filter produces no finding; iOS "cannot see" copy explains management can be confirmed but never ruled out. `DeviceSignalsTruthTests.swift` 5 tests; `yarn test:gate7` 37/37.
- Guardian Voice Note (iteration 36): guardian records ≤ 30 s on a shared incident (`VoiceNoteRecorder`, expo-audio; permission contract: explain → ask → respect canAskAgain → "Open Settings"; auto-stop at 30 s; review → Send/Discard). Upload `POST /family/incidents/{scent_id}/voice` (multipart, ≤ 1 MB, audio/* incl. webm on web; form device_id bound to bearer; 403 if unpaired) → bytes in **Emergent Object Storage** (`services/storage.py`, path `apollo-v1/family-voice/{guardian}/{note_id}.{ext}`), row in `incident_notes` kind "voice" (audio_path never returned). Playback: `GET /family/voice/{note_id}/ticket` (either side) → 10-min HMAC-signed public URL `/api/family/voice-play/{note_id}?exp&sig` (forged/expired/other-note → 403) so web `<audio>` and native play alike (`VoicePlayButton`, shared player, one at a time). Mum sees "Hear Sarah · 0:07" in "From your family"; guardian sees "Listen back". Push "Sarah left you a voice note". app.json: NSMicrophoneUsageDescription + RECORD_AUDIO. Egress allow-list += duration_s. Tests `test_family_voice.py` 3/3 (real storage round-trip).
- Admin Audit Trail (iteration 36): append-only `admin_audit` rows for blocklist.add / blocklist.remove / device.revoke with actor (`X-Admin-Actor` header, default "console"), IP, target, detail, time; failed actions log nothing. `GET /api/admin/audit?limit&action&actor&target`; `/api/admin/stats.audit` = total, last_7d, by_action_7d, recent[10]. `test_admin.py` 12/12.
- Voice Note Transcript (iteration 37): every voice note is captioned asynchronously with OpenAI Whisper (`whisper-1`, Emergent LLM key via `emergentintegrations.llm.openai.OpenAISpeechToText`) in `services/transcribe.py`; the upload returns immediately with `transcript_status: "pending"`, a background task writes `transcript` (≤ 500 chars) + `transcript_language` + `transcript_status ready|unavailable` (empty/failed transcription → "unavailable", never stuck pending). Notes API exposes these; `VoiceCaption` shows “…” under the play button on Mum's incident and the guardian's "Sent" list ("Caption coming…" while pending, guardian screen polls every 5 s until ready). Verified with real speech (TTS → upload → caption contains the spoken words). Tests `test_family_voice.py` 5/5.
- Light Sentinel palette (iteration 38): `src/theme.ts` is now a single light theme applied to both system schemes — background #F5F7FA, cards #FFFFFF, secondary surface #EAF0F6, navy text #0B1220, secondary text #52606D, borders #D7E0EA, deep navy accent/CTA #162235 (brand/brandPrimary), states: sniffing #52606D, resting #4FAF83, ears_up Apollo amber #F4B942, growling #E8943A, barking/biting #D9534F, unknown #7A8794; light-surface tints; scrim/glass adjusted. app.json userInterfaceStyle light + #F5F7FA backgrounds; StatusBar dark; exportPatrol HTML colours aligned. No literal colours elsewhere (verified by grep).
- Higgins Reads Captions (iteration 38): `VoiceCaption` gained deviceId/speaker → "Can't play it? Let Higgins read it" (Volume icon) which speaks "<Guardian> says: <caption>" through the existing `useHiggins` TTS (toggle to stop); playback errors now point to it. Wired on Mum's incident (`incident-family-note-caption-<i>-higgins`) and the guardian's Sent list (`family-note-caption-<i>-higgins`).
- Palette refinements (iteration 39, per user): background now soft sky blue #E6F0FA (secondary surface #D9E7F5, borders #C9D9EA); navigation bar is app navy #162235 with Apollo-amber active icons (#F4B942) and muted #9FB0C3 inactive (`nav`/`onNav`/`onNavMuted` tokens). Contrast fix from the iteration-38 sweep: new text-safe state tokens (`restingText #1E7A50`, `ears_upText #7A5200`, `growlingText #9A4A0B`, `barkingText #B3261E`, `sniffingText`, `unknownText`) used by `toneText()` for Pill labels and every state-coloured text; dots/borders/icons keep the bright hues; tint alphas raised. Web theme-color/background set in app.json.
- Higgins names & tracks checks (iteration 40): system prompt now lists Apollo's six checks by exact name and requires a machine-readable trailer `CHECKS: link|message|app|device|account|network` when advising a check. `src/domain/higginsChecks.ts` (`parseChecks`, `isDone`, `progressLine`; `yarn test:higgins-checks` 5/5) strips the trailer from the shown/spoken text; `HigginsChecks` renders "Higgins suggests" link chips (`higgins-check-<id>`) under the reply that route to /check, /message, /app-check, /device, /account, /network; completion is tracked on-device (`src/store/checkCompletion.ts`, `apollo.checks.completed.v1`) — each check screen calls `markCheckDone()` when it produces a result (link/message in ApolloContext; app/account/device/network screens) — and a chip turns green "Done" only if completed after Higgins asked, with a "1 of 2 done / All 2 done — thank you." progress line.
- Buttons (iteration 40, per user): secondary buttons are now white with a navy outline and navy label (no longer near the sky-blue background); ghost text navy; danger uses the text-safe red (#B3261E). Contrast fixes from iteration 39: onboarding wordmark → restingText; restingText darkened to #1B6B47.
- Higgins guidance upgrade (iteration 41, per user): the system prompt now lists each check with its purpose and WHERE TO FIND IT (Home → …, Guard tab → Open … Guard) and ties advice to Apollo's state (Growling → run the confirming check; Barking → act first, then Account Guard if codes/details were shared and Check my device if someone connected remotely; Biting → reassure, Account Guard only if something was typed). Verified reply: "…use Check my device, found on the Home screen… Account Guard, also on the Home screen… CHECKS: device, account". Chips now show the path under the label ("Home → Check a message"). HigginsSpeakButton restyled to the white/navy secondary face. Note: link/message completion is marked inside ApolloContext.checkLink/checkMessage (used by /check and /message), app/device/account/network in their screens.
- Home has ONE "Hear Higgins" (iteration 42, per user): removed the hero's speak button (`hero-hear-higgins`); the Higgins card's button (`higgins-greeting-hear`) now reads the greeting followed by Apollo's status line from the hero.
- Higgins Follow-Up (iteration 43): suggestions Higgins makes in Ask are recorded on-device (`apollo.higgins.suggestions.v1`, idempotent per message). A day later (`FOLLOW_UP_AFTER_MS` 24 h), Home shows one gentle `higgins-followup` card — "Yesterday I suggested Check my device and Account Guard. No rush at all — they're still waiting whenever you have a quiet moment." — with the same link chips (only checks still not done since he asked; a check appears once, from its latest suggestion) and a "Remind me tomorrow" snooze (24 h). Pure logic `pendingFollowUps`/`followUpLine` in `higginsChecks.ts` (`yarn test:higgins-checks` 9/9). Device check now counts as done when the device screen has assessed signals (not only on Save). Storage stores parse JSON values themselves — both stores accept string or object.
- Hear Higgins placement (iteration 43, per user): the single button lives inside the Apollo state card (`hero-hear-higgins`, reads state title + meaning + reason); the Higgins greeting card has no button.
- "Run a check" always names the checks (iteration 44, per user): `recommendedChecks()`/`checksSpoken()` in `higginsChecks.ts` — **mock standard list** (`RECOMMENDED_CHECKS_ARE_MOCK`) until native enforcement can report which protections failed verification: stale verification → Check my device, Network Guard, Account Guard; post-incident cooldown → by the resolved event's category. The Home hero renders them as tappable `HigginsChecks` chips ("The checks to run", `hero-checks`, `higgins-check-<id>`, Done tracking from start of today, not recorded for follow-up) plus a truthful note (`hero-checks-note`); Hear Higgins reads the list with where to find each. State reasons no longer say a bare "Run a check." `yarn test:higgins-checks` 12/12; iteration 44 E2E pass. TODO when enforcement lands: replace the table with real verification results.

- Light Sentinel Navy/Gold theme + Ask Higgins rename + Truth-of-State hardening (prior session, undocumented until now): Navy/Gold "Light Sentinel" visual language rolled out across Home, Guard, Patrol, Ask, Settings; Quick Checks on Home redesigned into one control strip; `/api/ask/history` Pydantic response-model crash fixed; Settings gained a Version/Build label (logo removed from Home header); iOS Swift `ApolloSecurityModule` capabilities contract now strictly returns `[]` for evidence per the documented platform contract; server-side Biting invariant (`_derive_verified_block()` in `routers/patrol.py`/`core/models.py`) rejects any `verified_block=True` not backed by real `enforcement_evidence` — a rule match, requested block or manual tap can never become "biting" on its own; `docs/android-consolidation-plan.md` + non-wired `src/security/future/GuardDogSecurityAdapter.ts` stub created for a future Android native-consolidation migration (M2), left unimplemented per user instruction; Android native DNS/VPN enforcement (`ApolloDnsVpnService`) left untouched — this track stays on hold until the user confirms a physical-device APK test passes.
- RDAP Domain Lookup for Check a Link (2026-06): keyless registrar/registration-date/registrant-org lookup — `backend/services/rdap.py` (IANA `dns.json` bootstrap, right-to-left longest-suffix TLD match → authoritative registry `GET {base}domain/{domain}`, jCard/vCard + `events[eventAction=registration]` parsing), Mongo-cached 48h (`domain_info_cache`, unique index on `domain` + plain `expires_at` index checked at read time, mirrors `reputation_cache` pattern). `POST /api/intel/check` fires the RDAP lookup as a background `asyncio.create_task` at request start (using the original submitted host) so it runs fully in parallel with the existing Safe-Browsing/blocklist verdict (incl. the `expand=true` redirect-following path) and is awaited with a bounded 6 s timeout at the end — best-effort by design: any RDAP failure/timeout/unknown-TLD degrades to `domain_info.available=false`, never blocking, delaying past a few seconds, or affecting the malicious/clean verdict. Domains registered <30 days ago are flagged `newly_registered=true` ("elevated scam risk"). `core/models.py` gained `DomainInfo`/`DomainInfoCache`; `IntelCheckResponse.domain_info` is optional and additive. Frontend: `check.tsx` result card shows a "Domain info" line (`formatDomainInfoLine` in new `src/domain/domainInfo.ts`) + a growling-tone "Newly registered — elevated scam risk" pill when flagged, or a muted "unavailable" hint when the lookup failed; Technical Details sheet shows the full breakdown (registrar/registered date/age/registrant org/RDAP server). `intelContract.ts`'s `parseDomainInfo` is defensive — a malformed `domain_info` is dropped silently, never rejects the whole intel result (RDAP is presentational, not a security verdict). Backend: `backend/tests/test_rdap_domain_info.py` (5 tests) + full pre-existing intel suite (25 tests) all pass, zero regression. Testing agent verified end-to-end on both backend (google.com/apple.com/microsoft.com real registrar data, cache reuse <200ms, bad-TLD best-effort <1s) and frontend (Domain info section, unavailable hint, Technical Details line) with no regressions elsewhere in Check a Link or the rest of the app.
- Gmail read-only connection — Gate 1 add-on, Phase 1 of 3 (2026-06): optional, manual-scan-only Gmail inbox connection for "Check an Email" (coexists with the pre-existing paste-email flow; user's planned sequence is Gmail → Outlook/Microsoft 365 → generic IMAP, each as its own phase). Architecture: server-side OAuth 2.0 Authorization Code flow against a **Web-application** Google Cloud OAuth client (`gmail.readonly` scope only — never send/delete/modify/label). `backend/services/gmail.py` — manual httpx-based token exchange/refresh (no google-auth-oauthlib dependency added), Fernet-encrypted refresh token stored in Mongo `gmail_connections` (device_id unique index), MIME-part text extraction (`text/plain` preferred, crude tag-strip fallback for `text/html`, capped ~4000 chars) via the Gmail API (`messages.list` + `messages.get`, last 30 days, capped 15/scan). `backend/routers/gmail.py`: `GET /gmail/connect` (authenticated, mints a single-use 10-min `state` in `gmail_oauth_states` — real Mongo TTL index via `expireAfterSeconds=0`, unlike the reputation/domain caches which check expiry at read time on purpose) → `GET /gmail/oauth/callback` (the ONE new public path in `core/auth.py` PUBLIC_PATHS — Google's redirect carries no bearer token; trust comes solely from the single-use state, never from caller input) → redirects back to whatever `app_redirect` the app itself supplied via `Linking.createURL('/email')` (validated against an `apollo/exp/https/http` scheme allow-list to prevent open-redirect abuse) with `gmail=connected|denied|error`. `GET /gmail/status`, `DELETE /gmail/connection` (disconnect), `POST /gmail/scan` (device_id-only body) round out the router. **Privacy contract: message content from `scan_inbox()` is returned to the caller for that one request only and is NEVER written to Mongo** — only the encrypted OAuth refresh token persists, and only until the user disconnects; this matches the "checked and discarded" pattern already used for the page-crawl and screenshot flows. Frontend: `ApolloContext.tsx` gained `scanGmailInbox()` (fetches via `/gmail/scan`, runs each message through the SAME on-device `analyseEmail()` engine as the paste flow, files Patrol events for anything non-resting — zero duplicated rule logic); `email.tsx` gained a "Connect Gmail (optional)" card above the paste form (`expo-web-browser` + `expo-linking`, no `expo-auth-session` needed) with connect/status/scan/disconnect states, per user's choices: manual scan only for now (settings toggle for automatic background scanning is a planned follow-up, needs a native build — background scanning cannot run in Expo Go), read-only Patrol alerts only for now (a settings toggle to allow archive/delete from within Apollo is also a planned follow-up). Egress allow-list (`gmail_scan`: device_id only) + updated `PRIVACY_POLICY_SUMMARY`. Real Google OAuth credentials configured (GOOGLE_CLIENT_ID/SECRET in backend/.env, user-created Web-application client; GMAIL_TOKEN_ENCRYPTION_KEY generated locally) — see `/app/memory/test_credentials.md`. Tests: `backend/tests/test_gate_gmail.py` (11/11: status/connect/open-redirect-protection/bogus-callback-state/scan-without-connection/idempotent-disconnect) + full regression 230/230 (pre-existing unrelated flakes excluded). **The real Google consent-screen login cannot be completed by an automated test agent (bot-login blocked by Google) — that step is unverified end-to-end and needs the user to manually connect a real Gmail account and confirm "Scan my inbox now" surfaces expected Patrol events.** Native OAuth (iOS/Android) needs a development/standalone build to test — the web preview's browser-popup flow is what's usable/testable right now.
- NEXT (approved by user, sequenced after Gmail): Outlook/Microsoft 365 connection (Phase 2, Microsoft Graph OAuth) and generic IMAP connection (Phase 3, app-password based) for the same "Check an Email" inbox-scan capability — followed by settings toggles for automatic periodic background scanning and in-app archive/delete of flagged emails (both currently manual-only / read-only per user's initial choice, explicitly deferred).
- "Let Apollo read the page" — Gate 3 Phase C (2026-06): second, manual/opt-in button on Check a Link (coexists with the pre-existing screenshot flow), fetches the target page's live HTML server-side instead of a screenshot. `backend/services/webcrawl.py` — SSRF-safe fetch: only http/https, resolves + rejects private/loopback/link-local/reserved/multicast/unspecified IPs before every hop (redirects followed manually, max 3), caps response size (~1.5MB) and time (~14s), no JS execution, strips `<script>/<style>`, extracts title/visible text/input-field types (password/email/tel only)/button labels/outbound link hosts. **Fetched content is never persisted or cached anywhere — checked in memory and discarded**, unlike the RDAP registrar cache. `POST /api/page/crawl` (routers/analysis.py) sends the extracted text (never raw HTML) to Gemini for the exact same `PageSignals` JSON contract as the existing screenshot `/page/extract` endpoint, plus a purely-descriptive `higgins_note` field (never a verdict — the on-device `analysePage()` engine stays sole decision-maker, exactly like every other Gemini "second opinion" in the app). Frontend `check.tsx`: new "Let Apollo read the page" button reuses the existing `check-page-card` UI end-to-end (zero duplicated rule logic) plus a new "Higgins's take" section for the note; friendly errors surface in the existing `check-page-error` card for SSRF-blocked/invalid/unreachable targets. Egress allow-list (`page_crawl`: device_id, url only) + updated `PRIVACY_POLICY_SUMMARY` disclosure line. Tests: `backend/tests/test_gate3_page_crawl.py` (9/9, real fetches of example.com/developers.strava.com, SSRF-blocks of 127.0.0.1/localhost/169.254.169.254 all <15s). Testing agent flagged `CORS_ORIGINS` was empty in backend/.env, blocking the web-preview testing tool's cross-origin calls (localhost:3000 page bundle calling the public preview HTTPS backend URL) — added the preview domain + localhost dev ports to `CORS_ORIGINS`; harmless for real usage (native apps ignore CORS; real end users hit frontend+backend through the same public origin, so no cross-origin request occurs there either way).
- Gmail read-only connection shipped (see Gate 1 add-on entry above, tested 11/11 + full regression). "Email Guard" requested next (2026-06): a richer, automatic pre-click assessment layer, requested to sit alongside the paste flow AND the Gmail auto-scan (retrofit both together). Scope agreed: (1) auto-run full link assessment (redirect-chain expansion + Safe Browsing/blocklist + RDAP domain-info, no manual "Check" tap needed) on every URL found in a checked/scanned email or message; (2) NEW capability — displayed-link-text vs real-destination-href mismatch detection (the classic "says paypal.com, goes to evil.ru" pattern), requiring the raw HTML anchor structure (available from the Gmail API's `text/html` MIME part; best-effort regex fallback for plain-text paste, which rarely carries this signal). Hard rule carried over from the existing Truth-of-State invariant: heuristics/URL-reputation findings here may only ever raise state to `growling` or `barking` — they must NEVER produce `biting` (that stays reserved for verified native block evidence elsewhere in the app). Explanations must be specific and human ("Display name says PayPal, but the sender domain is unrelated", "This link redirects through three domains and ends at a known malicious host"), not a generic red banner. **SHIPPED (2026-06)**: `services/intel.py` gained `assess_indicator()` — a pure extraction of the previous `/intel/check` body (redirect-chain expansion + Safe Browsing/blocklist + parallel/best-effort RDAP), now shared by both `/intel/check` (unchanged behavior, verified via full regression) and the enriched `/message/analyse` (runs it concurrently — `asyncio.gather` — for every URL in a checked/scanned message). `MessageUrlResult` extended with `redirect_chain`/`final_url`/`domain_info`. `services/gmail.py`'s `_extract_text()` became `_extract_content()`, additionally pulling `(text, href)` anchor pairs from the `text/html` MIME part via BeautifulSoup — `routers/gmail.py`'s `ScanMessage` gained a `links` field carrying them through to the frontend. New shared frontend module `src/domain/linkGuard.ts`: `evaluateLinkGuardFindings()` (redirect-chain-length + RDAP newly-registered + malicious-verdict → growling/barking with specific why-lines; the Truth-of-State invariant is enforced **by construction** — its internal `escalate()` helper only ever receives the literals `"growling"`/`"barking"`, so it's structurally impossible for this path to produce `"biting"`), `detectAnchorMismatch()` (compares a claimed domain-shaped token in the link's visible text against the real href's host), `extractAnchorsFromPlainText()` (best-effort markdown/`text (url)` pattern recovery for paste flow, which otherwise has no anchor structure at all). Wired into `ApolloContext.tsx`'s `checkMessage()` (paste-message/email flow) and `scanGmailInbox()` (now also calls the enriched `/message/analyse` per scanned message, which it didn't before, plus merges the real Gmail anchor pairs) and into `email.tsx`'s paste-flow `run()`. Tests: `backend/tests/test_email_guard.py` (10/10 — enriched `/message/analyse`, unchanged `/intel/check` behavior post-refactor, `_extract_content()`'s anchor-mismatch extraction on a synthetic paypal.com-text/evil-href HTML payload) + full regression 254/257 (3 pre-existing documented flakes, all passed individually on retry). Frontend verified end-to-end: paste-email escalating to barking with brand-mismatch why-lines, SMS paste escalating to growling, Check-a-Link unaffected, zero regressions anywhere.
- Full protection-stack roadmap captured 2026-06 (Websites → Email → Calls → Text, all sharing one evidence-backed reputation engine and feeding Patrol; **the same Truth-of-State rule applies to all four**: `resting`/`growling`/`barking` may come from heuristics/AI, `biting` must always require deterministic known-bad threat intel, an explicit user rule, or equivalently strong verified evidence — never a heuristic/AI judgment call alone):
  - **Website Guard** — shipped (Check a Link + RDAP + "Let Apollo read the page").
  - **Email Guard** — shipped, see above (automatic pre-click link assessment + link-mismatch detection, applied to paste flow, Gmail scan, and IMAP scan).
  - **Outlook (Microsoft Graph OAuth)** — SKIPPED per user decision (2026-06): generic IMAP (below) already covers Outlook.com/Office365 via IMAP + app password without needing a separate Azure AD app registration, so the dedicated OAuth integration wasn't built.
  - **Generic IMAP connection** — SHIPPED (2026-06), Gate 1 add-on Phase 3: connect ANY email provider (Gmail app password, Outlook, Yahoo, iCloud, custom domains) via host/port/username/app-password entered directly in the app — no OAuth app to register, unlike Gmail. `backend/services/imapmail.py`: read-only IMAP only (`SELECT INBOX` with `readonly=True`, `BODY.PEEK[]` — never `STORE`/`COPY`/`MOVE`/`EXPUNGE`), TLS via `ssl.create_default_context()`, Fernet-encrypted app-password storage (`IMAP_CREDENTIAL_KEY` — deliberately a SEPARATE key from Gmail's `GMAIL_TOKEN_ENCRYPTION_KEY`, different credential type/blast radius) in Mongo `imap_connections`, capped message count (15)/bytes (2MB)/text length (4000 chars)/timeout (20s). `imaplib` (synchronous) wrapped in `asyncio.to_thread()` throughout so it never blocks the event loop. `_parse_message()` uses Python's built-in `email` module (RFC822 parsing) + BeautifulSoup for `text/html` anchor extraction — same `(text, href)` pairs feeding Email Guard's link-mismatch check as the Gmail path. `backend/routers/imapmail.py`: `GET /imap/providers` (Gmail/Outlook/Yahoo/iCloud presets), `POST /imap/connections` (validates via one real `test_connection` call before saving), `GET /imap/status`, `DELETE /imap/connection`, `POST /imap/scan` (device_id-only body, same "checked and discarded, never stored" privacy contract as Gmail). Frontend: `ApolloContext.tsx`'s `scanGmailInbox`/`scanImapInbox` now share one `_scanInboxMessages()` helper (DRY — both run the same on-device engine + Email Guard assessment + Patrol filing). `email.tsx` gained a second "Connect another inbox (optional)" card below the Gmail card, with a bottom-sheet connect form (provider preset chips, host/port/username/app-password, `secureTextEntry`). Egress allow-list (`imap_connect`: device_id/host/port/ssl/username/app_password; `imap_scan`: device_id only) + updated `PRIVACY_POLICY_SUMMARY`. Tests: `backend/tests/test_gate_imap.py` (9/9: providers list, status before connection, invalid-host rejection, unreachable-host graceful failure, scan-without-connection 404, idempotent disconnect, synthetic-message anchor-mismatch extraction) + full regression 263/266 (3 pre-existing flakes, all passed individually on retry) + frontend verified (card rendering, sheet + preset auto-fill, error-on-invalid-host with sheet staying open, zero regression in Gmail card/paste flow/rest of app). **No real IMAP mailbox has been connected/scanned end-to-end yet** — no test mailbox was available to either this session or the testing agent; error paths are fully verified, but a real connect-then-scan needs a human with real app-password credentials for any provider.
  - **Call Guard** — SHIPPED (2026-06). Android: real `RoleManager.ROLE_CALL_SCREENING` request flow + `ApolloCallScreeningService.kt` (CallScreeningService) — checks an incoming number against three on-device sets (personal `block`, personal `allow`, and `autoRisky` — numbers THIS device previously found high-risk via a lookup, per-device only, no cross-user sharing in this build); a match in block/autoRisky is REJECTED before it ever rings (`respondToCall(disallow=true, reject=true)`), which is the verified enforcement action itself, recorded via `EnforcementEvidence.verifiedCallBlock` (new `call_screening` mechanism, reuses `destinationDomain` for the caller's E.164 number — documented shortcut, no new field added across the Kotlin/Swift/Python/TS layers for a v1) and synced through the SAME generic `getEnforcementEvidence()`/`syncEnforcementEvidence` pipeline Site Guard already uses (extended, not replaced, to branch on mechanism for call-specific Patrol copy + `local_indicator` instead of `indicator_host` for the number — matching Check This Call's existing choice to never sync a raw phone number to the backend). Everything else rings completely normally — Apollo never delays/silences a call on a guess — and unknown numbers are queued (bounded, deduped) for a background reputation lookup done by the app, never inside the ~5s screening window. iOS: real `CXCallDirectoryExtension` ("ApolloCallDirectory", new Xcode extension target via `plugins/withApolloCallGuard.js`, mirroring the EXACT proven pattern of the existing Safari content-blocker extension — same shared App Group, same target-creation approach) reads a `block`/`allow`/`autoRisky` JSON file the main app writes and adds ascending-sorted blocking entries; `CXCallDirectoryManager.getEnabledStatusForExtension`/`reloadExtension` used for real (not guessed) status + instant reload after any list change. Apple's newer "Live Caller ID Lookup" (PIR/relay, `IdentityLookup` framework, real API names confirmed via research) is scaffolded in `LiveCallerIDLookupHandler.swift` but explicitly NOT wired into any build target — needs its own extension target, Apple-granted entitlement, AND a from-scratch PIR backend server (a multi-week build on its own), clearly flagged as future work rather than claimed as working. **Caller number reputation**: integrated IPQualityScore (`services/phonerisk.py`, `POST /api/call/risk-check`, backend-proxied — key never reaches the client) — note the correct live API takes the key as a URL path segment (`/api/json/phone/{key}/{number}`), NOT the `IPQS-KEY` header the initial integration playbook suggested; fixed after a live-call verification. Response is Truth-of-State-honest: `decision` ("allow"/"review"/"avoid" — deliberately never "block") is heuristic/probabilistic and may only reach "growling"/"barking" in the app; ONLY a native CallScreeningService/CXCallDirectory rejection may ever produce a verified "biting" event. Cached 24h in Mongo `phone_risk_cache` by E.164 number (not hashed — this is the caller's number, already visible in the person's own call log, same privacy tier as a domain). New DEDICATED screen `app/call-guard.tsx`: automatic-screening status card (Android: role request button; iOS: honest Settings-deep-link explainer; web/other: "needs a native build"), "Recently flagged calls" (call-category Patrol events), "Check this number" quick action (phone-pad input + optional 2-letter country, shows fraud score/line type/carrier, "Add to block list"/"Always allow" actions), personal block/allow list management — "Check this call" (`app/call.tsx`) stays completely unchanged, per explicit instruction, as the mid-call-under-pressure path. Guard tab gained a "Calls" section → Call Guard card, matching the Network/Account/Text Guard card pattern. **Scope simplification flagged to the user**: the originally-discussed "community-wide synced scam-number list across all Apollo users" was intentionally NOT built this session (per-device `autoRisky` only) — reduces privacy/legal surface and native complexity for a v1; noted as a natural fast-follow. Tests: backend regression 261/269 (8 pre-existing, unrelated failures in guardian-invite/weekly-checkin email flows — not touched by this work) + 12/12 new Call Guard tests (7 risk-check + 5 pre-existing call-patrol tests) all passing, using IPQS's own documented test number live (no mocking, matching this repo's existing convention). Frontend verified end-to-end on web: "Check this number" reaching "High risk" (fraud score 100/100) on a live IPQS lookup, instant Patrol logging, "Add to block list" flow, honest capability messaging on web/iOS. **Native CallScreeningService (Android) and CXCallDirectoryExtension (iOS) cannot be tested in Expo Go/web preview — both need a development/production build on a real device to verify end-to-end (including generating a genuine iOS extension target via EAS/Xcode).**
  - **Flaky backend test fix (2026-06)**: the recurring `test_family.py`/`test_device_auth.py` (and other guardian-invite/weekly-checkin) failures were caused by `services/email.py`'s `send_email()` making a real, live HTTP call to the Emergent email relay for every test that adds a guardian — under full-suite/xdist concurrency this reliably tripped the relay's 429 concurrency rate limit. Fix: `send_email()` now short-circuits for the Resend test-safe sentinel address `delivered@resend.dev` — confirmed via grep to be the ONLY email address used anywhere in `tests/*.py` — returning a synthetic id without ever touching the network; real recipient addresses go through the exact same safety checks + semaphore + retry/backoff as before (zero behaviour change for actual users). Verified: `test_family.py` 12/12 + `test_device_auth.py` 16/16 clean on two separate full runs; full suite 273/273 on the second run (one unrelated, pre-existing Gemini "second opinion" timeout seen once under `-n2` load, not reproducible in isolation — untouched, out of scope).
  - **Flaky Gemini "second opinion" timeout fix (2026-06)**: that unrelated flake (test_gate2_message.py's explanation occasionally coming back None) was itself a second, separate concurrency issue — `gemini_second_opinion`/`gemini_app_opinion`/`gemini_account_opinion` (gate2/7/8) each wrapped their Gemini call in a bare `asyncio.wait_for(..., timeout=20)` with zero retry, so one slow response under concurrent load (several requests hitting the Gemini relay at once during a full-suite/xdist run) silently degraded to `explanation=None`. Fix: all three collapsed onto one shared `_gemini_second_opinion_call()` helper in `routers/analysis.py` that retries once on ANY failure (including the timeout) before falling back to `None` — same "retry only if it can actually help" philosophy as the email fix, and still never overrides the on-device verdict either way. DRY bonus: 3 near-identical call/parse/truncate blocks collapsed into 1. Verified: full backend suite run 3× post-fix — 273/273, 272/273 (the 1 = a different, already-documented pre-existing `test_iter7` log-tail race under xdist, confirmed passes alone, unrelated to Gemini), 273/273 — zero recurrence of the gate2/7/8 timeout across all three runs; `test_gate2_message.py`+`test_gate7_app.py`+`test_gate8_account.py` also run standalone, 25/25 clean.
  - **Project split clarified + Stage 0 protection-integration plan (2026-06, doc-only)**: this `/app` workspace is now explicitly the **Apollo main** project (active consumer product development). `m2-native-acceptance` and the proven `com.guarddog.*` native engine belong to a **different** Emergent project/session and are not present here and were not recreated. Working rule: consumer-app changes → Apollo main (here); native-engine changes/re-certification → m2-native-acceptance (not here). Wrote `docs/APOLLO_PROTECTION_STAGE0.md` (Stage 0, documentation only, zero code changes) covering: production signing authority (today: no local keystore/eas.json — signing is via the Emergent-managed Publish pipeline under `app.hwg.apollo`; the frozen GuardDog APK SHA-256 is a certification hash only, never treated as this app's signing key), Apollo-facing adapter ownership (`SecurityPlatformAdapter.ts` contract frozen; `frontend/modules/apollo-security`/`com.hucentai.apollosecurity` stays the Apollo-facing adapter layer, GuardDog becomes the engine underneath it, never called directly by product code), the import path for `com.guarddog.*` (human-mediated transfer of a pinned snapshot at commit `e5d11be912c76775c5a8b27b53218211484ca8bd` onto a dedicated consolidation branch — never a merge of `m2-native-acceptance`, never a rewrite from description), the production-vs-certification boundary, the Higgins truth/diagnostic interface (today's plain-language-only explainer + the future "Higgins Checkup"'s data contract, fixed now as read-only over `ProtectionStatus`/`PlatformCapabilityProfile`/`EnforcementEvidence` via `SecurityPlatformAdapter` only, so it stays engine-agnostic), 5-stage migration plan with rollback boundaries (Stage 5 — deleting the legacy `ApolloDnsVpnService.kt` — is the only non-free rollback point), explicit do-not-touch areas, and 5 open decisions requiring sign-off before any Stage 1 work begins (transfer mechanism, vendor-vs-dependency, new Gradle namespace, signing-identity confirmation, re-certification ownership). Builds directly on the pre-existing `docs/android-consolidation-plan.md` + `docs/android-physical-device-acceptance.md` (already-written decision records covering the Android-specific half of this) rather than duplicating them. **No migration/implementation started — stopped after Stage 0 per explicit instruction, awaiting review.**
  - **Cross-project relay clarified (2026-06)**: user asked me to relay a key/trust-architecture correction to "the m2 team." Confirmed via platform support: Emergent agent sessions are fully isolated per project — there is no mechanism for one project's session to act inside or send instructions to another. The user must open the `m2-native-acceptance` project's own chat directly for that. Similarly, "Save to GitHub" is a manual UI button the user clicks themselves (requires GitHub connected + paid plan) — not an agent-invocable action; no git remote is configured in this workspace and no push tool exists. Added §9 "Key & trust architecture for rule-bundle signing and revocation" (build-time pinned bootstrap trust — primary + recovery root keys — verifying a runtime-updatable signed Trusted Key Manifest with active/revoked key IDs, expiry, monotonic version, rotation overlap, rollback protection; a fetched key is never trusted merely because the backend supplied it; revocation latency for offline devices documented honestly as an unavoidable limitation; root-compromise recovery needs a controlled app update unless the recovery root was pre-pinned) and §10 "Corrected offline/backend-unreachable semantics" (last-known-good signed trust set + rule bundle kept; locally-known-bad still blocked; unsigned/unknown-key/rolled-back/unverifiable bundles never accepted; but unknown/unverified traffic while offline now correctly FAILS OPEN rather than breaking ordinary connectivity; degraded/stale state surfaced via the existing `ProtectionStatus.degradedReason`/`lastVerified` fields for Higgins to explain later — no new field needed) to `docs/APOLLO_PROTECTION_STAGE0.md`. Explicitly flagged as informational-only in this repo — the durable copy must be corrected by the user directly in the m2 project's own decision document, which this session cannot access or edit.
  - **Stage 1A — Production Engine Source Transfer Planning (2026-06, doc-only)**: user confirmed m2-native-acceptance's Stage 0 trust/revocation correction is closed there (commit `df26765`); only remaining actions are the user personally clicking "Save to GitHub" in both projects. Wrote `docs/APOLLO_STAGE1A_TRANSFER_PLAN.md` (planning only — zero code imported, zero GuardDog code written/recreated, `ApolloDnsVpnService.kt`/consumer UI/Higgins/`SecurityPlatformAdapter.ts` all untouched). Empirically tested (not assumed) what's actually available from this sandbox: outbound HTTPS/git access to github.com works (`curl`/`git ls-remote` against a public repo both succeeded); a locally-run `git bundle create` → `git clone` round-trip reproduced the exact same commit hash, confirming a single-commit git bundle preserves full content-addressed integrity; `get_assets_tool` confirmed working for receiving user-attached files (checked — 14 pre-existing unrelated attachments present, no GuardDog source attached yet). Recommended primary transfer method: **git bundle of the single pinned commit** `e5d11be912c76775c5a8b27b53218211484ca8bd` (needs no shared repo/token/live network at fetch time, cannot carry in anything beyond the pinned ref); secondary: pinned-SHA GitHub fetch (needs repo URL + a minimally-scoped read-only token if private — neither known/available to this session); fallback only: archive + manifest (weakest — no git-native integrity). Provenance procedure: `git rev-parse` of the imported ref must equal the pinned SHA exactly (primary proof); CI run `35171369548` + APK SHA-256 `905d66a9ab5d9f70c22c4a2fce897cdf668d975908546e583b404db01f774335` recorded as certification pointer only — explicitly NOT expected to be reproducible once rebuilt inside Apollo main's own signing identity (consistent with Stage 0 §1.2); a file-level SHA-256 manifest of the approved paths generated as a durable audit record. Scope discipline: allow-list `packages/guarddog-android-sdk`, `packages/guarddog-expo-module`, production `com.guarddog.*` native code only; explicit deny-list for certification-only code (test/acceptance harnesses, CI workflow config, m2-only fixtures) — final allow-list confirmed by manual review only after the pinned tree is actually visible, never a blind whole-repo copy. Landing location (forward-looking, not executed): a new `packages/`/`vendor/guarddog/` path, never mixed into `frontend/modules/apollo-security`. **Stopped after producing the plan per explicit instruction — no transfer executed; awaiting user's choice of method + the actual file/credentials to proceed to Stage 1B.**
  - **Repo discovered live (2026-06)**: user shared the m2 project's actual GitHub URL, `https://github.com/zelnix/Apollo` (public, no token needed). Read-only inspection (scratch `/tmp` clone, nothing copied into this workspace at the time) confirmed: it's genuinely the other project (`frontend/app.json` → "Apollo Native Gates" / `com.emergent.guarddogm.k6cugf`); pinned commit `e5d11be912c76775c5a8b27b53218211484ca8bd` is the exact tip of `main` and an ancestor of `m2-native-acceptance` (3 commits behind: `e5d11be`→`f0aecd5`→`df26765`→tip `df7a4fd`, `df26765`'s message matched exactly what the user reported); `docs/APOLLO_INTEGRATION_STAGE0_DECISIONS.md` and native `TrustedKeyRegistry.kt`/`RuleBundleVerifier.kt`/`BundleVersionStore.kt` are real; `packages/` at the pinned commit has 4 dirs, not 2: `guarddog-android-sdk`, `guarddog-expo-module` (approved) plus previously-unnamed `guarddog-contracts` and `guarddog-ios-sdk` (flagged as open scope questions). Updated `docs/APOLLO_STAGE1A_TRANSFER_PLAN.md` to promote live pinned-SHA GitHub fetch to the primary method (bundle demoted to fallback).
  - **Stage 1B — Production Engine Source Transfer, EXECUTED (2026-06)**: user resolved the two open scope questions: include `guarddog-contracts` *only if* it's a real build/runtime dependency of the approved packages (verify from build config, don't assume); defer `guarddog-ios-sdk` entirely (separate future iOS stage). Verified from actual Gradle/npm config (not assumed): `guarddog-android-sdk` depends only on external libs + its own internal `vpn→core` edge; `guarddog-expo-module`'s `android/build.gradle` depends on `project(':guarddog-core')`/`project(':guarddog-vpn')` only. **Zero** Gradle/npm dependency edge onto `guarddog-contracts` from either — the only hits were 2 doc-comment "Mirrors ..." lines plus a `sync-to-app.mjs` script that copies into *the other project's own* frontend, not into either approved package. Per the user's own conditional rule, `guarddog-contracts` is therefore **excluded**. Also found and excluded one certification-only file nested inside the otherwise-approved `guarddog-expo-module`: `android/src/androidTest/.../AndroidBlockingProofE2ETest.kt`, self-labelled "Physical-device acceptance (Phase 5)" requiring special instrumentation args — a certification harness, not a unit test, so excluded even though colocated inside an approved package. Re-verified source commit == `e5d11be912c76775c5a8b27b53218211484ca8bd` via a fresh scratch clone, then staged 91 files (72 `guarddog-android-sdk` + 19 `guarddog-expo-module`) into a **new top-level `packages/` directory** in this repo (chosen over `vendor/guarddog/` per instruction to preserve the source's own monorepo layout) — every file individually byte-verified via SHA-256 against the pinned commit's git blobs, zero mismatches; manifest stored at `docs/APOLLO_STAGE1B_SHA256_MANIFEST.txt`. `packages/guarddog-ios-sdk` was never cloned/touched. Wrote `docs/APOLLO_STAGE1B_TRANSFER_MANIFEST.md` (source→destination→action→reason table for every path, dependency-closure evidence, existing-tree conflict check [zero — `packages/` didn't exist before], and forward-looking Stage-2 build-system notes: this is an Expo *managed* workflow app with no checked-in `android/` project, so `:guarddog-core`/`:guarddog-vpn` will need a new Expo config plugin — matching the existing `./plugins/withApolloSiteGuard` pattern — to register into the generated `settings.gradle` at prebuild time, not a static edit; positive signal: this app is already on Expo SDK `57.0.19`, an exact match to what `guarddog-expo-module` was built against). **Nothing wired up**: `SecurityPlatformAdapter.ts`, `frontend/modules/apollo-security`, `ApolloDnsVpnService.kt`, consumer UI, Higgins, and `frontend/package.json` all confirmed untouched (`git diff --stat` empty on all of them). Source is staged and provenance-verified only — explicitly not ready for production integration; that's a distinct, later, separately-approved stage.
  - **Stage 1C — Production Build Integration, EXECUTED (2026-06)**: goal — wire the Stage 1B staged, certified GuardDog Android engine into Apollo's native build config with zero behavior/UX/Higgins change, Android-only. New `frontend/plugins/withGuardDogEngine.js` config plugin: (1) `withSourceCheck` fails prebuild fast with a clear error if the Stage 1B staged source ever goes missing; (2) `withSettingsGradle` appends `include(':guarddog-core')`/`include(':guarddog-vpn')` with `projectDir` pointed straight at the untouched `packages/guarddog-android-sdk/*` source (raw Gradle library modules, not Expo modules, so not autolinked); (3) `withProjectBuildGradle` adds `gradlePluginPortal()` + one classpath entry (`org.jetbrains.kotlin.plugin.serialization:...:2.1.20`) to Apollo's own generated root `build.gradle` — the one Gradle plugin id `guarddog-core`/`guarddog-vpn` need that wasn't already provided. Registered in `app.json`'s `plugins` array. Separately, `frontend/package.json` gained `"expo":{"autolinking":{"searchPaths":["../packages"]}}` — verified empirically (via `npx expo-modules-autolinking resolve`) to be the correct, documented way to make autolinking discover `guarddog-expo-module` living outside `frontend/` (unlike `apollo-security`, which is auto-discovered because it's inside `frontend/modules/`); confirmed it resolves exactly once, with zero effect on `apollo-security`'s own discovery. `guarddog-vpn`'s own `AndroidManifest.xml` already declares its `VpnService` + required permissions — no manual manifest edit needed, Android's own Gradle manifest merger picks it up automatically once `:guarddog-vpn` is a real dependency. Empirically confirmed (not assumed) React Native 0.86.3's own version catalog (`node_modules/react-native/gradle/libs.versions.toml`) already pins `agp=8.12.0`/`kotlin=2.1.20` — an exact match to what `guarddog-core`/`guarddog-vpn` require — so `com.android.library`/`org.jetbrains.kotlin.android` needed zero addition, only the one missing serialization plugin id. Verified via two independent clean `expo prebuild --platform android` runs (Node-only, no JDK needed — confirmed this sandbox has **no Java/Gradle/Android SDK at all**): identical output both times, `:guarddog-core`/`:guarddog-vpn`/`guarddog-expo-module` each appear exactly once, generated `android/` deleted afterward (not checked in, fully reproducible on demand). **Honest limitation, stated explicitly in the report:** actual Gradle build/Kotlin compilation could NOT be executed in this sandbox — everything verified is structural/version-string-based, not an executed compile; a real native build via the Emergent pipeline is required before this can be called proven. Re-verified all 91 Stage 1B files still byte-identical via the SHA-256 manifest — zero mismatches, nothing under `packages/` touched. Ran regression-level frontend tests (per the user's credit-efficient testing policy, not a full `testing_agent` pass): `test:adapter-contract` 7/7, `test:security` 8/8, `test:platform` 11/11, `test:truth` 5/5, `test:evidence-sync` 4/4, `expo-doctor` (4 pre-existing unrelated failures, none new), `eslint` clean; web preview restarted, confirmed still logs `SecureCore initialized {"implementation":"mock"}` (Expo Go/web still honestly not pretending native VPN enforcement exists). **Flagged, not executed, awaiting user decision:** `guarddog-core`/`guarddog-vpn` require `minSdk=26`; this app's current effective minSdk is 24 (RN's default, no `expo-build-properties` override) — a real AGP manifest-merge constraint requiring the app's own minSdk to rise (drops Android 7.x support app-wide), reported per the "stop and report, don't guess-fix" instruction rather than silently applied — this is a change to Apollo's own build config, not certified GuardDog source, and doesn't affect certified behavior either way. Wrote `docs/APOLLO_STAGE1C_BUILD_INTEGRATION.md` with the full report. Consumer UI, Higgins, `SecurityPlatformAdapter.ts`, Patrol, threat-event semantics, `guarddog-contracts`, `guarddog-ios-sdk` — all confirmed untouched. **Stopped here per instruction — not proceeding to Stage 1D (production adapter/native-runtime wiring), live VPN activation, Higgins integration, UI changes, or physical-device proof.**
  - **minSdk 24→26 approved + Stage 1C.1 native-build gate attempted (2026-06)**: user approved raising Android minSdk to 26 at the Apollo Production/config-plugin level (not by patching certified GuardDog source). Implemented via `npx expo install expo-build-properties` (57.0.20) + `["expo-build-properties",{"android":{"minSdkVersion":26}}]` in `app.json` — the standard reproducible Expo mechanism, no manual `android/` edits. `targetSdk` unaffected (stays at RN's pinned 36). Verified via clean `expo prebuild`: generated `android/gradle.properties` now has `android.minSdkVersion=26` exactly; `:guarddog-core`/`:guarddog-vpn`/`guarddog-expo-module` still each resolve exactly once; re-ran all 5 regression suites (35/35 pass), `eslint`/`expo-doctor` unchanged (same 4 pre-existing unrelated flags); re-verified all 91 Stage 1B certified files still byte-identical via the SHA-256 manifest (zero mismatches). Recorded the product-support consequence explicitly (drops Android 7.x/7.1) and the future runtime test the user flagged (must prove `ForegroundServiceTypeNotAllowedException` doesn't fire on a real device — a successful manifest merge does not prove systemExempted foreground-service eligibility). **Stage 1C.1 (real native build gate) could NOT be executed**: this sandbox has no JDK/Android SDK/Gradle at all, and no tool available to this agent triggers Emergent's actual native build pipeline (Gradle config, Kotlin compilation, manifest merge, APK build all require the user-triggered Emergent Publish flow). Stated this plainly in `docs/APOLLO_STAGE1C_BUILD_INTEGRATION.md` §11 rather than approximating a result — every check possible without a real compiler was done and is clean, but the mandatory compile-gate items remain unverified pending an actual build. Stage 1D (runtime/adapter integration) explicitly not begun.


  - **Text Guard** — SHIPPED (2026-06), decision resolved: Android uses opt-in **NotificationListenerService** (NOT default-SMS-app role, NOT READ_SMS ever). New Kotlin `ApolloSmsListenerService.kt` (NotificationListenerService subclass) restricted to the device's default SMS package + the two catalogued messaging apps (Google Messages/Samsung Messages) — WhatsApp/Telegram/Messenger deliberately excluded (user asked for SMS, not every chat app). Captures sender+text metadata into a capped (20-item) SharedPreferences queue on `onNotificationPosted` (group/summary notifications skipped, per-notification-key dedup up to 200 keys), fires a best-effort LOCAL heuristic notification ("Apollo noticed a message worth checking" — URL or obvious scam-keyword regex, never a verdict) so the person hears something even before reopening the app, then defers the REAL, authoritative check to the app. `ApolloSecurityModule.kt` gained `getMessagingCapabilities` (live `Settings.Secure` "enabled_notification_listeners" read — never cached), `getRecentMessageSecurityEvents` (drains/clears the queue — mailbox semantics, no double-processing), `openSmsListenerSettings` (deep-links to `Settings.ACTION_NOTIFICATION_LISTENER_SETTINGS`). AndroidManifest gained the `<service>` declaration (`BIND_NOTIFICATION_LISTENER_SERVICE`). iOS: honestly reports `smsFiltering: "unsupported"` — Apple gives third-party apps NO mechanism to observe Messages notifications at all (no NotificationListenerService equivalent); `TextGuardFilterExtension.swift` is a clearly-labelled, NOT-wired-into-any-build-target scaffold for a future `ILMessageFilterExtension` (needs its own Xcode extension target + `com.apple.developer.message-filter` entitlement — deliberately not attempted as "working" this session). Frontend: `ApolloContext.tsx` gained an Android-only poll `useEffect` (45s interval + AppState-active trigger, `lowPower`-aware) that drains the native queue and runs each captured item through the EXACT SAME `checkMessage()` used for pasted text (zero duplicated rule logic — same on-device engine + Email/Text Guard link-mismatch assessment + Patrol filing), showing a toast for anything non-resting. New DEDICATED screen `app/text-guard.tsx` (per user's explicit choice, not a retrofit of the existing `/message` screen): "Automatic scanning" status card (Android: live capability + "Turn on notification access" button when off; iOS/web: honest "Apple doesn't let apps read your Messages automatically" copy, no misleading button), "Recently flagged from your messages" (message-category Patrol events), "Paste a message" fallback (same `checkMessage()` call), links hand-off to `/check`, Verify Sender sheet, RecoveryFlow, Mark as safe. Guard tab gained a "Messages" section → Text Guard card (status pill from open message-category events, `Open Text Guard` button), matching the existing Network/Account Guard card pattern exactly. No new backend endpoints — reuses `POST /api/message/analyse` entirely. Tests: full backend regression 265/266 (1 pre-existing transient pytest-xdist flake, passed individually), frontend verified end-to-end on web (paste flow reaching Barking on a synthetic bank-phishing text, live Patrol update, Guard tab card, honest iOS/web capability messaging, zero regressions in /message, /check, /patrol). **Native NotificationListenerService capture (Kotlin) cannot be tested in Expo Go/web preview — needs a development build on a physical Android device/emulator to verify capture → local heuristic nudge → app-open drain → Patrol.**


## Stage 1C.1 — Step 7 config gate diagnostic (this session)
- Ran `npx expo config --json` plain, with `EAS_NO_VCS=1`, with `EXPO_DEBUG=1 EAS_NO_VCS=1`, and from a pristine `git archive HEAD` checkout (no `.env`): all exit 0, valid JSON, no stderr exceptions.
- Node v24.19.0, expo 57.0.19, @expo/cli 57.0.21, commit a2c8ee0 (clean tree).
- Failure is NOT reproducible locally → requires Emergent stderr for build aa24dd73-eab7-4d0f-8b83-4734adb870b8.
- Record: /app/docs/STAGE_1C1_STEP7_CONFIG_DIAGNOSTIC.md. No code changes made. Stage 1D NOT started.

## Stage 1C.1 → 1D gate order (confirmed by user, binding)
1. **Diagnose & Apply Exact Cloud Fix** — obtain Emergent's real Step 7 (`eas-update` → `expo config --json`) stderr; fix ONLY the exact exception; GuardDog source untouched unless the error directly implicates it. No speculative changes.
2. **Rerun Publish** — confirm Step 7 clears and pipeline reaches native Android Gradle/Kotlin build (this is the actual Stage 1C.1 test).
3. **Runtime Wiring (Stage 1D)** — only after native build succeeds; wire certified GuardDog engine into SecurityPlatformAdapter; preserve Truth-of-State rules.
4. **Physical Device Proof** — install APK on real Android device; prove VPN start/stop; prove a real packet observed and intentionally blocked; verify enforcement evidence generated; only then allow THREAT_BLOCKED / "Apollo is biting."
Current position: waiting on step 1 input (Step 7 stderr for build aa24dd73-eab7-4d0f-8b83-4734adb870b8). Do NOT start step 3.

## Stage 1C.1 Step 7 — RESOLVED (this session)
- Root cause (reproduced deterministically): Emergent removes projectId → `eas project:init` re-links → writes plugin-evaluated `extra` back to app.json via deepmerge (array CONCAT) → `appExtensions` doubled → expo-share-intent throws "more than one appExtensions for ShareExtension (2)" → exit 1. **GuardDog exonerated** (fresh install, no-git, Node 18/20/22/24, packages/ absent — all pass).
- Fix (user-approved): `frontend/plugins/withEasAppExtensionsDedupe.js` (dedupe appExtensions by targetName, first occurrence kept) registered FIRST in app.json plugins. Nothing else changed.
- Verified: config/introspect exit 0; 3 write-back rounds clean; Android prebuild exit 0; GuardDog includes ×1 each, autolinking 1 project; SHA manifest 91/91; 35/35 regression tests.
- Next: user reruns Publish → success criterion = Step 7 passes and pipeline reaches native Android build. Stage 1D NOT started.

## Deployment health probe fix (this session)
- Deployed backend log showed platform liveness probe `GET /health` (root, unauthenticated) → 404 → container restart loop. Added `@app.get("/health", include_in_schema=False)` returning `{"status":"ok"}` in server.py (no DB/auth). `/api/health` and all auth gating unchanged. Verified 200 locally; auth still 401 on protected routes; 71 backend tests (auth/admin/api-regression/failure-modes/health-touching) green.
- Status board: Step 7 eas-update PASS ✅ · backend deployment reached ✅ · health probe FIXED 🔧 · Stage 1C.1 Android Gradle/Kotlin build NOT YET PROVEN ⏳ (need log lines: gradlew/assemble/compileKotlin/guarddog-core/guarddog-vpn/APK/AAB) · Stage 1D NOT STARTED.
- Redeploy after /health fix: platform probe now 200 OK on all calls (127.0.0.1 + 10.22.x). Backend deployment HEALTHY ✅. Android Gradle/Kotlin build evidence still NOT seen (backend container log does not contain it) — user must trigger the Android build from the deployment panel and paste that log.

## Stage 1C.1 — first EAS Android build reached PREBUILD, failed on package location; FIXED (this session)
- EAS build f2359ee5 failed in PREBUILD: withGuardDogEngine source check — /home/expo/workingdir/packages missing. Cause: eas-cli (no VCS) archives only frontend/; repo-root packages/ sibling never uploaded.
- Fix (user-approved): `git mv packages frontend/packages` (91 renames, byte-identical). Updated withGuardDogEngine.js (REQUIRED_PATHS 'packages/...', PACKAGES_DIR_FROM_ANDROID '../packages') and package.json searchPaths ['./packages']. Docs updated (1B manifest note, 1C §11b).
- Verified: SHA 91/91 from new location; config+introspect exit 0; archive simulation ships 91/91; prebuild inside simulated worker archive (no sibling packages) exit 0; core×1 vpn×1 expo-module autolinks ×1; 35/35 tests.
- Deployment-agent .gitignore ".env" findings = false positives for this pipeline (workspace upload includes .env); deliberately NOT changed (secret hygiene).
- Historical build-warning backlog: expo-asset peer dep missing (expo-audio), duplicate react-native-svg (@nandorojo/heroicons). **Correction:** duplicate SVG was later proven to be the post-splash runtime blocker and fixed by Support in `01a30ae`; it is not an outstanding harmless warning. See Stage 1C §13. No claim about the other warning is made by that fix.
- Status: Step 7 ✅ · backend deploy/health ✅ · EAS Android build reached ✅ · PREBUILD fixed 🔧 · Gradle/Kotlin NOT YET REACHED · Stage 1C.1 IN PROGRESS · Stage 1D NOT STARTED. Next: user generates fresh APK; need Gradle log.
- User re-pasted the SAME EAS log (build f2359ee5, code version 676c6260, unzip shows root-level source/packages) — predates relocation commit 0efef7a. No new fix needed. A fresh Publish (new code snapshot) + Android build is required; new unzip log must show `source/frontend/packages/...`.
- EAS build eb022c0b: PREBUILD ✅ (relocation confirmed), RUN_GRADLEW ❌ "project ':apollo-security' does not specify compileSdk" — Apollo-owned modules/apollo-security legacy ExpoModulesCorePlugin path. Fixed by migrating to expo-module-gradle-plugin (same as certified module). Certified source untouched (SHA 91/91). Next: fresh Publish + Android build; watch for :guarddog-core/:guarddog-vpn compile.
- Stage 1C.1 iteration 3 (2026-06): EAS build `737fa306` proved the certified GuardDog engine (`guarddog-core`, `guarddog-vpn`, `guarddog-expo-module`) and `apollo-security` all compile natively inside Apollo. Remaining failure `:app:processReleaseResources` (AAPT: `<package android:name>` must be a valid Java package name) traced to nine `SYSTEM_PREFIXES` strings (`com.google.` …) wrongly listed in `modules/apollo-security/android/src/main/AndroidManifest.xml` `<queries>`; removed them, added `INSTALLERS` to `AppDeviceCatalog.VISIBLE_PACKAGES` so the JUnit manifest-contract test still matches (37 entries). GuardDog SHA-256 manifest verified intact. Non-blocking: `google-services.json` has a stale `life.fb50.app` client beside `app.hwg.apollo`. Awaiting next Publish → Build; if `bundleRelease` succeeds Stage 1C.1 is closed and Stage 1D (runtime wiring) may begin.
- Stage 1C.1 device run #1 (historical): Android app closed after splash. An invalid native SecureCore configuration was reproduced with the pure validator, but **was not verified as the cause of the installed APK crash**; Support later identified the exact `RNSVGCircle` duplicate-registration exception (Stage 1C §13). User-approved policy/SafeStart work remains separate: production still requires native Apollo Security Adapter; native SecureCore is required only while `NATIVE_SECURECORE_DEPENDENT_FEATURES` is non-empty; `.env.production` selects SecureCore mock / security adapter native. Settings labels SecureCore "NOT ACTIVE (MOCK)". Selectors record configuration errors via `securityBoot.ts`; `_layout.tsx` renders SafeStart without app providers/navigation when blocked. This is a configuration-error boundary, **not protection against all OS/process crashes**. Earlier tests: security 9/9, boot 6/6 and web SafeStart/onboarding checks. App identity changed to `app.apollo.hwg` (including iOS extension/app-group identifiers); the stale Firebase file noted at that time was subsequently replaced with the matching `apollo-243ad` config. These earlier changes did not deduplicate SVG. Stage 1D still requires a successful physical-device launch of the fresh Support-fixed APK.

## 2026-09-21 product status (review `9cfb377` supersession)
- **Problem statement:** Apollo must provide one durable, evidence-backed Higgins investigation across every Gate,
  preserve original evidence until authoritative publication, recover safely from process/lease races, and ship
  honest Android/iOS/desktop candidates while using only the owner's `GEMINI_API_KEY`.
- **Architecture:** Expo mobile client and Tauri desktop shell; FastAPI/MongoDB Higgins coordinator with encrypted
  temporary evidence, durable jobs/events/device requests, fenced leases, conditional checkpoints and 15-minute
  scope expiry. EAS creates native Android/iOS candidates; Tauri creates desktop targets.
- **Implemented now (P0):** durable device request identity and consume-before-ack; one-root atomic evidence manifest
  publication; File Gate navigation-safe cache ownership; stable Device case; one shared Text/Email investigator;
  complete opaque multi-item share envelope; Patrol event→case continuation.
- **Delivery:** Android EAS build `18706c6e-cf91-418e-9536-94b1cf592f93` (fingerprint
  `31a0394db69ca674b79ef91a3d0cf3c2b0e2e083`) finished successfully against the healthy compatible backend; APK
  SHA-256 `50e51aff03ee69ed859386b734365a205fe9040fc240c5af896e7a3342503e91`. Linux Tauri
  release binary SHA-256 is `f3d79697729e558c3351b4c6b44b4c2a739966e2a7ba0b1074bd216e5e794a2a`.
- **P1 backlog:** Packages 3–5 limits/background/guided-action lifecycle; Android physical acceptance; signed iOS
  build after Apple credentials; target-host Windows/macOS packages.
- **P2 backlog:** Package 7 production GuardDog/configuration closure and credential-gated integrations.
- **Verification policy:** no testing agent, Playwright, scenarios or live Gemini probes. Current bounded checks:
  backend 42 focused Higgins tests + 2 Call Guard tests, frontend TypeScript/ESLint, Share suite 13/13, Rust
  `cargo check`, Linux Tauri release compile, backend health HTTP 200.

## 2026-09-22 deployment readiness
- Deployment-agent final health check: **PASS**.
- Startup is non-destructive: no collection drop and no automatic bulk legacy-content migration. Explicit migration
  tooling is fenced, operator-only and regression-tested (18/18 focused recovery/migration tests).
- Expo managed preview now starts with `--tunnel`; `@expo/ngrok` 4.1.3 is installed and Metro reports the tunnel ready.
- Backend `/health` and `/api/health` return HTTP 200; Python lint, TypeScript and ESLint are clean.

## 2026-09-22 correction status from reviewed commit `4c03315`
- **Package 1 P0:** immutable upload/session replay, fenced root publication, abandoned-attempt-only cleanup,
  consumed-observation reconciliation, pending-ledger observation restoration and active-job/work-epoch cancellation
  are implemented and bounded-tested.
- **Package 2 P0:** main Text Gate now starts shared Higgins; Text/Email project one accepted current assessment; File
  transfer ownership begins before I/O and survives navigation; Device appends timestamped rechecks/user reports to
  one case and binds later Patrol events.
- **Package 3 P1:** bounded later-page PDF extraction is implemented as addressable evidence without conflating parser
  extraction with semantic reading. Remaining limit/observation audits stay active.
- **Package 6 P1:** desktop manufacturer/model/form factor, real notification permission, administrator-approved exact
  domain hosts/DNS filtering, block/unblock/status and native-before-fixture host selection are implemented. Packet
  inspection/app attribution remain explicitly unsupported; target-host acceptance remains.
- **Repository hygiene:** 8,240 tracked files under `desktop/src-tauri/target/` were removed from the index and the
  directory is ignored; generated artifacts remain local/outside source tracking.
- **Corrected source identity:** digest `01e4723d48cd34c3129701adebd2947249cb174f94d2ae21a699d30567ea0110`;
  existing Android build `18706c6e...` predates these corrections and is not relabelled.

## 2026-09-22 final deployment health
- Deployment Agent status: **PASS**, zero blockers.
- Readiness-remediated working source SHA-256:
  `b70cdffb4ca7441313c928ec9acc4a946ab7c1b310de55707c6353bc9bdabb10`; preceding saved commit
  `63d60d861104902cfaed0970f9010899ded1f2b3`.
- API process startup performs idempotent initialization only; no retention/investigation/family-audio deletion loop is
  tied to startup or restart.
- Explicit maintenance entry point: `python -m scripts.run_retention_sweep`, reserved for an operator-controlled
  maintenance schedule.
- Repository-wide `.env` ignores were removed for deployment automation; injected local values remain excluded through
  workspace-local Git configuration and were not exposed.
- Verified: backend lint/compile, 25 focused tests, startup cleanup static check, and both health endpoints.

## 2026-09-22 seven-defect correction package
- Package 1/2 P0 now includes control-document evidence publication manifests, checkpoint-revision device-result merge,
  complete application-owned transfer/observation retries, authoritative client cancellation, all Text presenters, and
  bounded exact-host desktop filtering with privileged readback verification.
- Package 3 PDF continuation now preserves later-page links and scanned-page visuals and replays only committed slices.
- Bounded tests prohibit provider calls at both pytest fixture and Higgins provider entry-point boundaries.
- Pre-build source digest: `fe41defb4f0fd0bc6fa85cd0dfb9d9db5412a75445c6be88c4f7d65d694770da`.
- Verification: 56 focused backend tests, TypeScript/ESLint, and 3 Rust native tests pass.
- **Fresh Android candidate:** EAS `047bc183-37e9-447b-b0f8-48012f591550`, source
  `7fd6f9a61d292bdab17700152f7e47e457afc411`, fingerprint
  `565f42d9b04dd39c836360eeccd12c4e442b800f`, APK SHA-256
  `c15804e04597e09628575cc58734bd97fc10c2cbe1f89dd4c1ddae239e102e97`.

## 2026-09-23 review closure
- Closed Gmail disconnected-state, locale-aware Australian callback extraction and `temporary_copy_policy` metadata defects.
- Reconciled the preserved historical 24-failure JUnit artifact; the missing 24th node was
  `TestPatrolEventsGate2::test_upsert_and_list_message_event` (`claimed_brand` contract drift).
- Current provider-disabled backend JUnit is clean: **386 passed, 19 credentialed integrations skipped, 0 failed**.
- Credentialed Gemini/voice/screenshot/public-page/email coverage is explicitly separated behind
  `APOLLO_RUN_CREDENTIALED_INTEGRATION=1`; no managed LLM key or live owner key was used.
- Verification passes: TypeScript, repository ESLint, GuardDog production source **9/9**, frozen manifest **91/91**,
  Android GuardDog/Family Assist Kotlin compilation and desktop `cargo check`.
- Identity: base commit `dac83b072bba9a541dde431b78b8668659625e27`; closure source digest
  `e7ca068ff6a902d4d347760fb7b8dab259f3ea1d081875930590b66961d87c3e`; package remains `app.apollo.hwg`.
- Detailed evidence: `docs/APOLLO_REVIEW_CLOSURE_RECORD.md`.

## Update — Android VPN consent gate in completeSetup (ApolloContext.tsx)
- `completeSetup` now scopes the VPN-consent flow to `Platform.OS === "android"`.
- Flow: read `vpn_config` → if not granted, call `requestProtectionPermission("vpn_config")`
  (→ native `requestGuardDogProductionProtectionPermission`); on `system_ui_opened` poll until
  the user returns; on `launch_failed`/`unsupported` throw.
- A FRESH `getProtectionPermissions()` check is the only gate permitting `startProtection()`
  (→ native `startGuardDogProduction`). Setup/protection are NOT marked complete unless the
  fresh check confirms `vpn_config === "granted"`.
- Native-only: must be validated on an Android dev build (not Expo Go / web preview).

## Update — Declining Android VPN consent no longer disables Apollo (reduced coverage)
- `completeSetup` (ApolloContext.tsx): records protection intent (`apollo.protection.on=true`),
  then `ensureAndroidVpnConsent()` (new, non-throwing helper). On Android it requests `vpn_config`,
  waits for the system consent screen, and detects return promptly via AppState→active (≈4s window)
  with a 120s ceiling. `startGuardDogProduction` (startProtection) is called ONLY when a fresh read
  confirms consent granted. If declined, setup still completes — Apollo is not disabled as a whole.
- `gates.ts`: Site Gate shows `permission_needed` from stored intent (`desiredSiteOn`) even though
  native `requested` only flips true after a successful start. Overview summary reads
  "Protection active — reduced coverage" when Site Gate awaits VPN and other Gates run. Primary
  action label becomes "Grant VPN permission" (id stays `restore_site`).
- `healthCoordinator.ts`: passes `desiredSiteOn` (from `apollo.protection.on`) into the gates overview.
  Existing `decideSiteRecovery` auto-starts once consent lands; declined stays `ask_permission` (no crash).
- `guard.tsx`: Gates summary title mirrors the reduced-coverage wording.
- Tests: tests/gatesOverview.test.ts (+4 cases, 12/12 pass). Native-only flow — validate on an Android dev build.

## Update — Graceful permission handling across all permission/connection Gates
- New `src/domain/gatePermissions.ts`: shared copy/config (what/why/enableLabel/pendingLabel) + ~3-day
  snooze keys for Site, Text, Call, Email; `gateAppliesToPlatform`.
- New `src/domain/gmailConnect.ts`: extracted read-only Gmail OAuth (`connectGmailOAuth`), reused by
  email.tsx and the setup walkthrough.
- New `app/setup-gates.tsx`: after the privacy disclosure, Apollo walks through each applicable Gate
  needing permission/connection one at a time (Enable / Not now), launches the system/OAuth flow,
  verifies the REAL state on return (waitForForeground), and never blocks setup. Declines snooze ~3 days.
  Registered in app/_layout.tsx; privacy-disclosure now routes here after completeSetup.
- `completeSetup` (ApolloContext): no longer requests Android VPN inline (walkthrough owns it); records
  intent and starts protection only on non-Android. Setup never fails on a missing permission.
- `GateNudge` (generalizes old SiteGateNudge; SiteGateNudge.tsx now re-exports it): Home reminder for
  ANY pending Gate (Site/Text/Call/Email), one at a time, respecting the per-gate ~3-day snooze.
- gates.ts + guard.tsx: "Protection active — reduced coverage" now shows whenever ANY permission/
  connection Gate is pending while others run (generalized from Site-only).
- Truthful per-Gate states already existed (Text/Call permission_needed, Email setup_needed) with
  enable-later actions; pendingLabel copy provides "Permission required" / "Not connected" wording.
- Tests: tests/gatesOverview.test.ts 13/13 pass (added non-Site reduced-coverage case).
- NATIVE-ONLY: VPN/notification/call-role flows can't run in Expo Go or the web preview (web fails
  closed). Validate the walkthrough end-to-end on an Android dev build.

## Fix — Android VPN consent now waits for the user's real response (device bug)
- Root cause: VPN consent was fire-and-forget (startActivity) + JS polling with a 4s "shrink on first
  active" window. A transient AppState=active (or the consent screen not backgrounding fast enough)
  ended the wait BEFORE the user tapped Allow → Site Gate reported "needs VPN permission" even when
  the user intended to grant.
- Native (ApolloSecurityModule.kt): `requestGuardDogProductionProtectionPermission("vpn_config")` now
  accepts a Promise and launches the consent intent via `activity.startActivityForResult(VPN_REQUEST_CODE)`
  (no FLAG_ACTIVITY_NEW_TASK). A new `OnActivityResult` handler resolves the Promise ONLY when the user
  responds, returning requestState "granted"/"denied" (VpnService.prepare==null = granted). Also returns
  "launch_failed" when no current Activity. Added `Promise` import + `vpnConsentPromise` + VPN_REQUEST_CODE.
- JS (ApolloContext.ensureAndroidVpnConsent): treats native "granted"/"already_granted" as true and
  "denied"/"launch_failed"/"unsupported"/"cancelled" as false. Legacy "system_ui_opened" fallback now
  waits for a genuine background→active return (no premature bail) then settles.
- setup-gates.tsx & CoverageCard.tsx `waitForForeground` (text/call settings): only start the short
  grace window after a real background→active return; 8s no-show safety only if the screen never opened.
- Type: added "granted"/"denied"/"cancelled" to ProtectionPermission.requestState.
- Stage1B SHA256 manifest unaffected (covers guarddog-android-sdk/ only, not modules/apollo-security/).
- REQUIRES A NATIVE ANDROID REBUILD to take effect (native module changed).

## Fix — Call Gate role request now shows the dialog & waits for response (device bug)
- Root cause (same class as VPN): Android call-screening role was launched with startActivity +
  FLAG_ACTIVITY_NEW_TASK, which does NOT show RoleManager's role dialog and can't deliver a result.
- Native (ApolloSecurityModule.kt): `requestCallScreeningRole` is now Promise-based and launches
  `createRequestRoleIntent(ROLE_CALL_SCREENING)` via `startActivityForResult(CALL_ROLE_REQUEST_CODE)`
  (no NEW_TASK). OnActivityResult resolves `{opened:true, held:<isRoleHeld>}` after the user responds.
  Returns `{opened:false, held}` when unavailable/already-held/no-activity.
- JS: callSdk type adds `held?`. call-guard/setup-gates/CoverageCard use `r.held` as authoritative
  (fall back to waitForForeground for legacy builds). call-guard shows "Call screening is on" on held.
- iOS unchanged and already consistent: opens Settings + verifies CXCallDirectory state on return.
- Cross-platform note: all graceful-permission/reduced-coverage/nudge/coverage-card/setup-walkthrough
  behavior is platform-agnostic JS; the native for-result fix is Android-only because the bug was.
- REQUIRES A NATIVE ANDROID REBUILD (native module changed).

## Feature — Multiple Gmail accounts (Email Gate)
- Also fixed: Google "Error 403 access_denied" is a Cloud Console setting (OAuth consent screen in
  Testing mode) — user adds Gmail addresses as Test Users (or publishes/ verifies the app). Not a code bug.
- Backend gmail_connections now stores ONE ROW PER (device_id, email). server.py drops the legacy
  unique index on device_id, backfills email="", and creates a compound unique (device_id, email) index.
- services/gmail.py: save_connection(device_id, refresh, email) + fetch_profile_email; get_connections();
  get_connection(device_id, email?); disconnect(device_id, email?) (one or all); _access_token_for(device_id, email?);
  scan_inbox aggregates the first page of EVERY connected account (items tagged with `account`);
  scan_inbox_page/download_attachment accept optional email.
- routers/gmail.py: callback fetches the account email and saves per-account; /gmail/status returns
  `accounts: [{email, monitoring_enabled, monitor_state,...}]` (plus back-compat single fields);
  /gmail/monitoring is device-wide (update_many — monitor all together); DELETE /gmail/connection
  accepts optional ?email to remove one account, omitted = all.
- services/mailbox_monitor.py: scan_gmail_through_shared_pipeline(device_id, mode, email?) leases &
  scans per (device,email); the enabled-mailbox loop passes each account's email.
- Frontend app/email.tsx: lists connected accounts with per-account Disconnect, "Connect another
  account", "Disconnect all", and device-wide monitoring/scan across all accounts.
- Validated service-layer multi-account (store 2, per-account + all disconnect) PASS. HTTP endpoints are
  device-credential protected; OAuth connect needs the Google test-user/verification fix + a device to
  test end-to-end. Native build not required (JS+backend only).

## Bug fix — Network Gate: no option to set as Home (2026-06)
- Report: "Network gate not active. There also is no option to set as home network." (screenshot showed
  N02 "Wi-Fi you haven't classified" result card whose recommendation says "Pick a context above" — but
  the home/work/public context chips only rendered in the pre-check view, never in the result view).
- Fix (app/network.tsx): the "Where are you?" context chips are now ALWAYS visible (moved above the
  result/actions block). Tapping a chip calls pickContext(), which re-runs analysis live reusing the same
  Patrol event id (no event spam). Classifying as Home/Work/Trusted yields N01 "resting" and quietly
  resolves the earlier active N02 network item via upsertEvent(status:"resolved").
- "Protection off / Unknown" on the dashboard is the connection/VPN protection state (reduced-coverage when
  VPN consent declined) — a native-build + permission matter, not a code bug. "Check this network" works
  regardless of that state.
- NOTE: Network Gate is native-only; web preview is hard-gated ("GuardDog production authority can be
  selected only in a production build"), so this must be verified on the user's Android build.

## Bug fix (part 2) — Network Gate should be ON and monitoring independent of the VPN (2026-06)
- User pushback: "I should be on and monitoring especially when network changes." The Network Gate showed
  "Protection off / Unknown" because it was reading the Website-Gate VPN status, and the Android production
  runtime never reports a `connection_guard` capability (only `site_guard`).
- Root cause: (a) ApolloContext.refresh() only raised Connection-Guard events when the VPN was running
  (`status.running` gate on line ~284); (b) network.tsx dashboard headline/pill derived from the VPN
  `protection` object + absent connection_guard capability; (c) gates.ts marked Network "running" only when
  `vpnActive`, else "not_activated".
- Fixes:
  - ApolloContext.tsx: removed the `status.running` gate — assessConnection() runs on the OS network snapshot
    (needs no VPN) and raises one deduped event per distinct unsafe condition (open/WEP Wi-Fi, captive portal)
    on every foreground/periodic/network-change refresh.
  - app/network.tsx: dashboard now reflects the Network Gate's own live monitoring — "Monitoring this
    connection" / Active when there is a current connected reading; honest detail: re-checks on every app
    open and network change; reads connection type, Wi-Fi security, captive-portal flags only.
  - src/domain/gates.ts: Network Gate = "running" (Watching) whenever connected + inspectable (or VPN on).
    Honest limitation when VPN off: "Apollo checks the connection on every app open and network change. Turn
    on Site Gate for continuous background watching." permission_needed only when platform withholds net info.
- Truthfulness preserved: foreground watching is real; continuous *background* observation still needs Site
  Gate's VPN and is disclosed, never claimed otherwise.
- Tests: tests/gatesOverview.test.ts +3 cases (16/16 pass). tsc + eslint clean on all three files.
- Native-only screen; verify on the user's Android production build (web preview is hard-gated).

## Bug fix — Account Gate wrongly showed "Status unavailable" (2026-06)
- Report: Account Gate card read "Status unavailable" / "Breach lookup is currently unavailable" even
  though its core "Check an account alert" action works fully.
- Root cause: gates.ts set accountAuto.state = "temporarily_unavailable" whenever
  accountBreachConfigured !== true (backend /account/status → breach_lookup_configured = bool(HIBP_API_KEY),
  and HIBP_API_KEY is unset). presentation() maps temporarily_unavailable → "Status unavailable" (tone
  unavailable), making a working, on-demand gate look broken.
- Fix (gates.ts): the optional live breach-list lookup (HIBP) no longer gates the whole Account Gate.
  When configured → event_driven "running" ("Watching"). When NOT configured → automatic = undefined so it
  falls through to onDemand "ready" → "Ready when you need it" (neutral), with currentHelp: "You can check a
  login, breach or recovery alert anytime. Live breach-list lookup isn't set up, but alert analysis still works."
- Tests: updated the two Account-Gate cases in tests/gatesOverview.test.ts to assert "Ready when you need it"
  (16/16 pass). eslint + tsc clean.
- To actually enable the live breach lookup, the user must provide a HIBP_API_KEY in backend/.env.

## Bug fix — Device Gate false "Action required / high-risk" + unhelpful findings (2026-06)
- Report (multiple screenshots): Device Gate barked "Barking / Action required / 1 high-risk item" for a
  benign device-admin ("Device management profile — High risk"), listed benign Google/Samsung system apps
  under notification access, and findings didn't explain consequences or a concrete action. User: "This is
  legitimate... does not explain consequences and action to take."
- Root causes:
  1. Native AppDeviceSignals.kt set managementProfile = admins.isNotEmpty() ? "present" : "none" — ANY active
     device-admin (Find My Device, Samsung Find My Mobile, Play Protect) became "present", which
     deviceAnalysis.ts D02 flagged severity:"high" → barking. False positive on virtually every consumer phone.
  2. notification/accessibility lists only filtered Apollo's own package, so OS/OEM components (gms,
     gearhead, ringplugin, launcher, smartmirroring) showed as noise.
- Fixes:
  - Native AppDeviceSignals.kt: classify managementProfile = "managed" (device-owner/profile-owner via
    DevicePolicyManager.isDeviceOwnerApp/isProfileOwnerApp), else "device_admin" (ordinary admin), else
    "none"/"unknown". Added managementAdmins[] (friendly labels via KNOWN_ADMINS + PackageManager).
  - Native AppDeviceCatalog.kt: thirdPartyServices(setting, own, pm?) now drops first-party system packages
    (FLAG_SYSTEM when visible, else vendor-prefix fallback: com.google.android./com.android./com.samsung./
    com.sec./OEM prefixes). Added KNOWN_ADMINS map. (Aligns the existing JVM test.)
  - deviceAnalysis.ts: DeviceSignals.managementProfile union now "none"|"device_admin"|"managed"|"present"|
    "unknown" + optional managementAdmins. "managed"/"present" (incl. iOS) → high when unexpected, info when
    expected. Ordinary "device_admin" → benign INFO finding D02b that NAMES the apps and explains the
    consequence ("can lock your screen, reset your passcode or erase the phone — powerful but normal…") and a
    concrete action ("open Device admin apps, tap it to see what it controls, then turn it off"). User can
    still escalate via the "unexpected profile" self-report → high.
- Tests: tests/gate7.test.ts +3 cases (44 pass); gatesOverview 16 pass; fileDeviceGateUi pass; tsc+eslint clean.
- Native-only: verify on the user's Android production build after redeploy + rebuild.

## UX Refinement Package UX-01…UX-16 (2026-06) — presentation/wording/hierarchy only
No architecture, infrastructure, security behaviour, routes, Gate types or product scope changed.
- UX-01 Gate wording: gates.ts presentation() now maps running→ enforcement:"Protection on" / monitoring:"Watching" / event_driven:"Ready automatically" (new user-facing label added to GateStatusLabel union; no new capability type). Home GateRow replaced the blanket "Auto" badge with compact capability-derived labels: On / Watching / Ready / Needs you / Off / Checking / Unavailable.
- UX-02 Home hierarchy: ApolloHero now shows a prominent primary action Button (testID hero-primary-action) when state is a warning and a corrective route exists; Hear Higgins stays below as secondary. Calm states keep Hear Higgins prominence.
- UX-03 dedup: Home suppresses GateNudge when the hero is already naming attention Gates (heroNamingAttention); CoverageCard + Gates Protection list remain as secondary coverage below the hero; HigginsFollowUp unchanged (distinct follow-up).
- UX-04 background copy: "Guarding in the background — minimise to save battery." → "Apollo continues protecting in the background." Minimise control retained as secondary ghost button.
- UX-05 Check It intro: "These checks start only when you tap one." → "These are checks you start yourself. Apollo may also protect or watch automatically where supported."
- UX-06 Patrol summary: new patrolConsumerSummary() + ListHeaderComponent at top of Patrol: "Nothing needs you right now" / "N thing(s) need you" / "Apollo is checking N concern(s)". Header "{n} outcomes" pill kept as secondary.
- UX-07 Patrol empty: removed engineering explanation. Now "No Patrol activity yet." (all) / "Nothing here currently needs your attention." (filtered).
- UX-08 Filters: unchanged (All activity / Needs you / Warnings / Threats stopped / Resolved).
- UX-09 Patrol cards: PatrolItem adds a "Needs you" pill (from matchesPatrolFilter) and shows primaryAction.label as the footer hint when present — existing fields only.
- UX-10 Higgins hub reorder: Ask Higgins → Current investigations → Recent activity → reference grid [New scams, Learn, Saved reports] → History.
- UX-11 "Ordinary chat" removed from user-facing: header pill "Ask Higgins", hub card "Ask Higgins", "Return to ordinary chat"→"Back to chat", empty/disclaimer/error copy reworded. Internal investigationMode var unchanged.
- UX-12 technical wording: "Retry server deletion"→"Try deleting again"; "Investigation answer complete within its stated scope"→"Higgins has finished this investigation." Scope/uncertainty still shown in supporting disclaimer + investigation details.
- UX-13 roles: no Higgins copy claims Apollo actions — no change needed.
- UX-14 vocabulary: plain-English result strings retained; Growling/Barking only used as Apollo character language in educational Q&A, never as instructions — no change needed.
- UX-15 Biting: hero still reuses barking GIF but accessibility label already "Apollo biting after a confirmed block" and biting only resolves with verified_block — animation never presented as proof; unchanged.
- UX-16 reduced motion: ApolloHero now reads AccessibilityInfo reduce-motion and routes it through the existing animate-disable path (motionOn) — no new a11y subsystem. (Previously only manual battery-saver lowPower existed.)
- Tests: gatesOverview 19, phase2Patrol 4 (incl. new patrolConsumerSummary + link-gate "Ready automatically" + account label change). Full gate/higgins suites pass; eslint + tsc clean.
- NOTE: web preview is hard-gated (GuardDog production authority only in a production build) so UI cannot be smoke-tested here; verify on a production build.

## Feature — App Gate: pick from a list of installed apps (2026-06)
- Request: "When checking an app should be able to pick from a list of installed apps."
- Implementation (Android only; iOS can't enumerate apps, falls back to manual entry):
  - AndroidManifest (apollo-security): added a <queries><intent> MAIN/LAUNCHER block so Apollo can list
    launchable user apps WITHOUT QUERY_ALL_PACKAGES (keeps the app's no-broad-visibility stance).
  - Native AppDeviceSignals.installedLaunchableAppsJson(): queryIntentActivities(MAIN/LAUNCHER) → sorted
    [{packageId, appName}], excludes Apollo itself. Registered AsyncFunction("listInstalledApps").
  - appDeviceSdk.listInstalledApps() + InstalledAppRef type; nativeBridge method added.
  - app-check.tsx: "Pick from installed apps" button (Android) opens a searchable Sheet (app-picker-sheet)
    listing installed apps; selecting one fills the name AND stores the packageId, which is passed to
    getInstalledAppAssessment(pickedPackage) so Apollo reads real install source + permissions for the
    chosen app (the launcher <queries> now makes getPackageInfo resolve). Manual typing still works and
    clears any picked package. Scope copy updated for Android.
- tsc + eslint clean. Pre-existing adapterContract.test.ts failures (getCapabilities / AndroidSecurityAdapter
  / dns:udp-53) are unrelated and were present before this change (verified by stash).
- Native-only: requires a production Android build; web preview is hard-gated and Expo Go returns an empty
  list (handled with a "needs a production Android build" message in the picker).
- PENDING (from the prior message, not yet actioned): recognise Apollo's own VPN so the Network Gate doesn't
  ask the user to "confirm you recognise the VPN service"; recognise Apollo-caused device changes; add a
  security/privacy/protection setting-change log with date-time attributing Apollo-caused changes.

## Feature — Call/Text pickers + SMS/email data-handling rule (2026-06)
User decisions: Call Gate number from recent calls (READ_CALL_LOG), number-first; Text Gate pick via Share
AND inbox (READ_SMS); same privacy rule for email. User accepts the Play-restricted permissions.
- Native (apollo-security): new PhonePickers.kt reads CallLog.Calls (recent, de-duped) and Telephony.Sms.Inbox
  (incoming only) on demand, returning [] when the permission isn't held (never throws). Module adds
  hasRuntimePermission/requestRuntimePermission (maps call_log→READ_CALL_LOG, sms→READ_SMS via
  Activity.requestPermissions) + listRecentCalls/listRecentSms. Manifest: added READ_CALL_LOG, READ_SMS.
- JS: src/security/phonePickers.ts (PhonePickers SDK, isSupported=android+native). New shared
  src/components/PhonePickerSheet.tsx implements the permission contract (contextual explain → request →
  poll grant → Open Settings on denial) and a searchable list; Android-only, else "needs production build".
- Call Gate (app/call.tsx): number-first "Who called?" card with "Pick a recent caller" → fills number.
- Text Gate (app/message.tsx): "Pick a text from your inbox" (incoming only) + Share-from-Messages already
  supported via shareIntake. Privacy copy rewritten to the rule: reads incoming only, assesses once,
  discards raw, keeps only if flagged until dismissed.
- Email Gate (app/email.tsx): policy copy rewritten to the same rule. Backend already compliant — stores
  only hashed mailbox_assessment_receipts + flagged outcomes, never raw bodies (services/mailbox_monitor.py).
- tsc + eslint clean. Native-only; requires a production Android build (web preview hard-gated; Expo Go
  returns empty lists, handled gracefully). READ_CALL_LOG/READ_SMS are Play-restricted — user accepted.
- Earlier same session: App Gate "pick from installed apps" (listInstalledApps, launcher <queries>).
- STILL PENDING (older message): recognise Apollo's own VPN in Network Gate; recognise Apollo-caused device
  changes; dated security/privacy/protection setting-change log attributing Apollo-caused changes.

## Next-steps batch (2026-06) — VPN recognition, Call Guard move, device change log, easy dismiss
- Apollo's own VPN recognised (networkAnalysis.ts): new input apolloVpn; new scenario N11 "Apollo's own
  protection VPN" (resting) takes priority over N09/N10 so the Network Gate never asks the user to confirm
  Apollo's own Site Gate tunnel. network.tsx passes apolloVpn = protection.running === true. connection.ts
  never flagged VPNs (no change). Test: gate8 N11 (34 pass).
- Call Guard "Automatically check incoming numbers" MOVED from Settings → Call Gate (app/call.tsx): toggle +
  disclosure card at top of the pre-result view, bound to storage apollo.call.auto_check. Removed the
  Settings Call Guard section. Defaulted ON during onboarding: ApolloContext.completeSetup seeds
  apollo.call.auto_check="true" when never set (so a later user choice is preserved).
- Device security-settings change log + Apollo attribution:
  - deviceAnalysis.ts: DeviceSecurityChange gains attributedTo ("apollo" | "user_or_unknown");
    deriveDeviceSecurityChanges takes apolloVpnActive — a VPN that turns on while Apollo's protection is
    running is attributed to "apollo" and downgraded to low_risk (not flagged). Added DEVICE_CHANGE_LABEL.
  - app/device.tsx: persists a dated log (apollo.device.changelog.v1, newest-first, cap 50) and renders a
    "Recent security setting changes" card with date-time + an "Apollo"/"Review" tag per entry. Passes
    protection.running as apolloVpnActive.
- Easy dismiss for flagged items (PatrolItem.tsx): flagged ("Needs you") list cards now show a one-tap
  "Dismiss" that calls resolveEvent without opening the detail (detail already had Mark as handled/contained).
- tsc + eslint clean. Suites: gate5/6/7/8, gatesOverview, phase2Patrol all pass.
- Native-only pieces (call/SMS pickers, VPN/device signals) still require a production Android build to test;
  web preview hard-gated. READ_CALL_LOG/READ_SMS are Play-restricted (user accepted).

## Nav + Check It/Gates separation, Change Log Detail, Trusted Callers (2026-06)
- Navigation reorder (app/(tabs)/_layout.tsx): tab order is now Home → Higgins → Check It → Gates → Patrol
  (both the iOS-26 NativeTabs and the standard Tabs blocks). Gates sits directly after Check It, before Patrol.
- Gates = passive status (app/(tabs)/guard.tsx): each gate still shows purpose ("What this Gate helps with"),
  status pill, current help, and attention alert. The primaryAction button now renders ONLY when
  tone === "attention" (a required corrective action, e.g. Restore protection) — the check_* diagnostic
  buttons no longer appear on non-attention gates (those belong to Check It). Intro now says "To check
  something yourself, use Check It." No check/test/scan/diagnostic controls remain on Gates. Enforcement and
  evidence rules unchanged.
- Check It unchanged (already manual-only).
- Change Log Detail (app/device.tsx): change-log rows are now Pressable; tapping opens the matching settings
  screen (openChange maps vpn_change→vpn, profile_change→security, service_enabled→accessibility, else apps;
  web shows guidance text) to confirm the change.
- Trusted Callers: new src/domain/trustedCallers.ts (AsyncStorage key apollo.call.trusted.v1, matches on last
  10 digits). PhonePickerSheet caller rows have a Trust/Trusted toggle. ApolloContext auto-check poll now
  skips trusted numbers (acknowledges from queue, no assessment/event) so Apollo stays quiet for them.
- tsc + eslint clean; gatesOverview/gate8/phase2Patrol pass. Native-only pieces need a production Android build.

## Trusted callers/senders mgmt + change-log filter (2026-06)
- Manage Trusted Callers (app/call.tsx): a "Trusted numbers" card lists trusted numbers with Remove
  (untrustCaller), refreshes after the picker closes. getTrustedCallers/untrustCaller from trustedCallers.ts.
- Change Log Filters (app/device.tsx): the change-log card has All / Review-only buttons; Review-only hides
  "Apollo"-attributed entries; empty state "No changes need review."
- Trusted Senders (src/components/PhonePickerSheet.tsx + ApolloContext): SMS picker rows show a Trust/Trusted
  toggle (numeric senders, reusing trustedCallers store). The JS Text-Guard background assess loop now skips
  trusted senders (acknowledge, no assessment/Patrol item) so Apollo stays quiet for them.
- tsc + eslint clean.
## PENDING (large, deferred to a focused session): Higgins First Check + Re-check malware/compromise
  baseline (onboarding step 3, capability-based FirstCheckCapability, result model
  CLEAR/ATTENTION/HIGH_RISK/CONFIRMED_THREAT/LIMITED/NOT_AVAILABLE/ERROR, per-platform adapters reusing
  Diagnostic Core + device signals, Check-tab "Higgins Re-check", Checkup history, full test matrix). Spec
  captured in this message; not yet implemented.

## Device Gate — Phase 3 (native collectors extended) — DONE (2026-06)
Extended each platform's native collector to read two more signals the OS legitimately exposes to a normal
app (no new permissions), and wired them into the registry-driven review engine (src/domain/deviceReview.ts):
- New DeviceSignals field `screenLockSecure: boolean | null` (deviceAnalysis.ts, EMPTY_SIGNALS).
  - Android: KeyguardManager.isDeviceSecure() (AppDeviceSignals.kt).
  - iOS: LAContext.canEvaluatePolicy(.deviceOwnerAuthentication) = a passcode is set (DeviceSignalsTruth.swift,
    ApolloSecurityModule.swift). Windows/macOS → null → stays Manual.
  - `lock` check now returns Checked (secure) / Action required (no lock) / Manual (unreadable).
  - iOS `encryption` check now returns Checked when a passcode is set (iOS encrypts automatically), Action when
    none, Manual when unreadable.
- Android `userTrustedCertificates` now populated via the AndroidCAStore keystore ("user:" aliases) instead of
  always null, so the `certificates` check reports real extra user-trusted CAs on Android.
Truth rules preserved: anything the build can't read stays null → Manual/Unavailable, never a false Checked.
Tests: deviceReview.test.ts (+ screen-lock & iOS-encryption cases), DeviceSignalsTruthTests.swift updated. Full
TS/Node suite green. Also fixed the last legacy failure: package6Source.test.ts now loads app.config.js (there
is no app.json), matching iosSourceReadiness.test.ts.
NOTE: native reads (KeyguardManager / LAContext / AndroidCAStore) only verify on a real Android/iOS build — the
web preview shows the Safe Start build-gate and cannot exercise them.

## Device Gate — Desktop collectors read firewall + OS updates directly — DONE (2026-06)
Windows/macOS desktop host (Tauri) now observes two more review signals directly instead of leaving them Manual:
- New Rust command `security_audit` (desktop/src-tauri/src/lib.rs) returns `{ firewallEnabled, firewallDetail,
  updatesCurrent, updatesDetail }`:
  - Windows firewall via `netsh advfirewall show allprofiles state` (ON for every profile → on); updates via the
    Windows Update Agent searcher (0 pending → current).
  - macOS firewall via `/usr/libexec/ApplicationFirewall/socketfilterfw --getglobalstate`; updates via
    `softwareupdate -l --no-scan` ("No new software available." → current).
  - Linux/other → all null (not_implemented) so the crate still compiles. Registered in generate_handler!.
- DeviceSignals gained `firewallEnabled` and `osUpdatesCurrent` (deviceAnalysis.ts, EMPTY_SIGNALS).
- DesktopSecurityAdapter.getDeviceSecuritySignals() (new, optional on SecurityPlatformAdapter) invokes
  `security_audit` + `network_status` and maps them into DeviceSignals (vpnActive, firewallEnabled, osUpdatesCurrent).
- device.tsx now detects a desktop host (desktopHostKind) → runs the review as "windows"/"macos" and collects
  signals from the desktop adapter instead of the mobile AppDeviceSdk.
- deviceReview.ts: `firewall` → Checked/Action/Manual from firewallEnabled; `os_updates` (windows/macos) →
  Checked/Review/Manual from osUpdatesCurrent (mobile stays Manual — not readable there).
Tests: deviceReview.test.ts (firewall + OS-update desktop cases). Full TS/Node suite green, tsc + lint clean.
NOTE: the native reads only verify on a real Windows/macOS desktop build; cargo check here stops at a system
GTK/pkg-config dependency (container limitation), not a code error.

## About Apollo popup + Higgins headshot + Desktop antivirus/settings-jump + Preview boot — DONE (2026-06)
- About Apollo: new scrollable popup `src/components/AboutApolloSheet.tsx`, opened from Settings → Help & about →
  "About Apollo" (replaced the old static text block). Uses the supplied Higgins+Apollo photos
  (assets/images/higgins-apollo-full.png hero, higgins-apollo-portrait.png in Meet Higgins) and the full approved
  copy (10 Gates chips, Scam Alerts, Meet Higgins, Your Privacy & Data, Free Forever, Harmony Wellness Group).
- Higgins headshot (assets/images/higgins-headshot.png): now shown on the "Hear Higgins" button
  (src/components/HigginsSpeakButton.tsx), the Higgins chat header + message avatars (app/(tabs)/ask.tsx), and the
  About Apollo "Meet Higgins" section. NOTE: after adding new image assets, Metro needed a cache clear
  (rm -rf .metro-cache/* then restart expo) or the images render as blank circles.
- Desktop antivirus: security_audit (lib.rs) now also reads Windows antivirus via Security Center2 productState
  (macOS/Linux → null, stays manual). DeviceSignals.antivirusEnabled + deviceReview `antivirus` evaluator (Windows
  Checked/Action; mac/android Manual).
- Desktop "Open Settings" jump: lib.rs open_settings_target gained "firewall" and "updates" targets (Win:
  ms-settings:windowsdefender / ms-settings:windowsupdate; mac: Network / Software-Update settings). device.tsx
  openCheck now calls openDesktopSettings(desktopReviewTarget(id)) on a desktop host and the button reads "Open
  Settings" there.
- PREVIEW BOOT: the app is hard-gated to only boot in a production config ("no mocks in runtime"); dev/staging show
  SafeStartScreen. To let the in-container web/Expo-Go preview run for UX/content review, frontend/.env now sets
  EXPO_PUBLIC_APP_ENV=production and EXPO_PUBLIC_DEVICE_PREVIEW_HARNESS=off. On web this uses the honest browser
  adapter (reports "no native protection"), so no fake protection is shown. The simulated-device harness is off.
  securityConfig/boot unit tests are unchanged (they test the function, not .env). Verified: onboarding → setup →
  Home/Gates/Higgins all render in the preview.

## QUEUED (large, not yet started) — two product briefs received, to be done one at a time:
1. Global Scam Early Warnings + Higgins "growling" alerts (AU/US/UK/EU sources, severity LOW/MODERATE/HIGH/EXTREME,
   Australian-relevance, Home section, scams.tsx filters, growling push, Higgins explanations). Extend existing
   government_alerts/learning_feeds/context_tools/ask.py/push.py + home.tsx/ask.tsx/scams.tsx/hubClient.ts.
2. Privacy, Data Storage, Retention & Deletion corrections (authoritative inventory, retention rules, Clear Patrol
   + "Delete My Apollo Data" device-scoped deletion, per-Gate privacy audit, Settings → Privacy & Data screen,
   onboarding/About consistency, honest deletion-state messaging, tests).

## Global Scam Early Warnings (#1) — FOUNDATION DONE (2026-06)
- NEW backend/services/scam_intel.py (pure, tested): region_for, classify_severity (LOW/MODERATE/HIGH/EXTREME,
  evidence/keyword rules — NOT AI; official_advice & tips stay LOW; alarming words alone never reach EXTREME),
  australian_relevance (confirmed/potential/overseas_only/unknown), is_growling (HIGH|EXTREME + confirmed|potential),
  is_fresh_advisory (<=21d), higgins_explanation (structured AU-English, never claims a personal attack), enrich().
- government_alerts.snapshot() now attaches region/severity/sourceSeverity/australianRelevance/higgins + a top-level
  `growling` advisory (freshest eligible). Coverage string updated (AU/US/UK/EU).
- International sources+feeds added to content/learning_catalogue_au.json (FTC, FBI/IC3, Europol, ENISA, NCSC UK)
  with country/region; import_package persists country/region. NEW learning.seed_catalogue_sources_feeds() runs on
  startup (idempotent, sources+feeds only) — server.py wired. 9 sources / 7 feeds configured & verified.
- context_tools.scams: fixed published_at→publishedAt bug; now returns region/severity/australianRelevance.
- tests/test_scam_intel.py (9) pass; updated test_phase2_remediation allowlist to the per-source invariant.
- Frontend: hubClient GovernmentAlert extended (region/severity/relevance/growling/higgins); app/higgins/scams.tsx
  rebuilt with filters (All/Australia/Global/USA/UK/Europe/High/Extreme), severity+region+AU-relevance pills,
  expandable Higgins explanation, growling highlight, "Ask Higgins about this".
- DEFERRED in #1: server-side push delivery of growling advisories (localAlerts already titles "Apollo is growling"
  for growling/ears_up; a server trigger for new HIGH/EXTREME advisories is not yet wired), ask.tsx consuming the
  scamTitle/scamSource params as bounded Higgins context, and live-feed availability verification (feeds will show
  unavailable/stale honestly until reachable).

## Navigation + Scams tab (#2) — DONE (2026-06)
- app/(tabs)/_layout.tsx: tabs are now Home · Higgins · Check It · Scams · Patrol (NativeTabs + Tabs). Gates tab
  removed; guard kept as href:null hidden tab for compatibility. Scams icon = ExclamationTriangle / sf
  exclamationmark.triangle.fill. Tab label is "Scams" (screen title stays "Scam Alerts").
- Gates moved to /gates stack route (app/gates.tsx re-exports (tabs)/guard; registered in app/_layout.tsx). guard.tsx
  shows a ChildScreenHeader (back) when rendered under /gates (useSegments) else the RootScreenHeader tab header.
  Legacy /(tabs)/guard still resolves.
- app/(tabs)/scams.tsx re-exports higgins/scams; that screen picks RootScreenHeader when under (tabs) else
  ChildScreenHeader.
- Check It: "View Gates" card added at top (→/gates). Settings: Protection & permissions now a single "View Gates"
  row (→/gates); removed the duplicate Website-protection shortcut + Site Gate status panel + in-settings activation
  (VPN activation still lives on the Gates screen). Removed now-unused useProtectionHealth/enableSiteProtection.
- Home: NEW src/components/HomeScamAlerts.tsx compact section (top 3, growling first, severity+region, "View all
  scam alerts"→/(tabs)/scams), separate from Gate coverage.
- appDestination ApolloRoute += "/gates","/(tabs)/scams". Tests updated: phase2Navigation + iosSourceReadiness parity.
  Full TS/Node suite green, tsc+lint clean. Verified in preview: tab bar + Scams screen render.

## Privacy & Data / Deletion (#3) — NOT STARTED (next session; large standalone spec)

## Home — eliminate repetition + honest findings (P0 brief) — DONE (2026-06)
- ApolloHero no longer embeds the specific incident (removed the problemBox showing attention[0].title/problem/
  higgins). The hero now shows only Apollo's OVERALL state + honest reason + a single "See what needs attention"
  action. The specific incident(s) live solely in the "Needs your attention" section → no duplicate presentation.
- home.tsx: Recent Patrol now EXCLUDES event ids already surfaced in "Needs your attention" (attentionEventIds)
  so history doesn't echo the active alert. Removed the "This week" weekly digest card from Home (reduced scroll +
  removed a Pressable>Card that was a likely nested-button source). Dropped now-unused imports (Sparkles,
  ChevronRight, buildWeeklyDigest).
- Attention gate routes updated to /gates (was /(tabs)/guard).
- Earlier backend fix already maps raw states (ears_up→"something worth a closer look") so no internal status leaks.
- Verified in preview: hero shows "Apollo is growling / Protection is unavailable or unverified." + "See what needs
  attention"; no runtime error banner; Scam Alerts section renders a HIGH AU growling item. Full TS/Node suite,
  tsc, lint all green.
- NOTE: the exact "nested <button>" React error could not be reproduced in the current state; the structural
  simplifications remove the most likely causes. If it recurs in a specific state, capture that state to pinpoint.

## STILL QUEUED (large, not started) — in requested order:
1. Privacy & Data / Deletion (settings screen, Delete My Apollo Data, retention, verified deletion).
2. Growling Push (server push for new HIGH/EXTREME scam advisories, deep-link to the alert).
3. Ask Higgins Link (carry scamTitle/scamSource into Higgins chat context).
4. Live Feed Check (verify/adjust overseas source feed URLs).
5. Social Media & Messaging Scam Protection (reuse Internet Gate + add "Scam Check" in Check tab + Share to Apollo;
   NO new Gate/infra).


## PROJECT RULES — Agent Constraints

### Testing Agent
- **DO NOT invoke the testing agent without the user's explicit approval.** Always ask before calling `deep_testing_backend_v2` or `expo_frontend_testing_agent`.

### Screenshots
- **DO NOT take screenshots unless the user explicitly approves or requests them.** No speculative screenshot captures.

## Four-Tab Threat Investigation / Patrol Outcome Screens (2026-10)

**Requirement:** Completely overhaul the patrol event detail screen (`patrol/[id].tsx`) from a monolithic ScrollView into a structured 4-tab interface.

**Tabs:**
1. **Overview** — Higgins' conversational briefing + current outcome card + status pills + "what to do" + action buttons + connected incident link
2. **Probe** — Magnum DI detailed analysis: risk level assessment, what happened, scenario context, caller info (call events), findings list, conclusion
3. **Evidence** — Factual foundation: evidence provenance badge, recorded indicator, enforcement evidence, supporting references, domain details, timestamps
4. **History** — Chronological, deduplicated timeline of significant events (detection, probe, user action, resolution) + metadata footer

**Constraints:**
- No new backend endpoints, DB models, or investigation engines
- Tabs managed as local state inside the screen (not Expo Router tabs)
- All tabs share same data fetched once — no redundant reloads
- History tab must deduplicate events
- Visual: dark navy background (#0B1220) for active tab, light grey (#EDF2F7) for inactive, white rounded cards

**Files created:**
- `src/components/patrol/InvestigationTabBar.tsx`
- `src/components/patrol/OverviewTab.tsx`
- `src/components/patrol/InvestigationTab.tsx`
- `src/components/patrol/EvidenceTab.tsx`
- `src/components/patrol/HistoryTab.tsx`
- Refactored `app/patrol/[id].tsx` as the container


## Project Rules (Standing Instructions)

- **Do NOT call testing agents or take screenshots without explicit user approval.** Always ask first.

## Scam Alerts redesign + header cleanup (2026-06)
- `app/higgins/scams.tsx`: compact list (severity-tinted category icon, severity + region pills, 2-line title, source · date, chevron), single-select region chips (All/Australia/USA/UK/EU/Global), sort toggle (Latest first / Highest severity), pull-to-refresh, emerging patterns section. No Ask Higgins button.
- New `app/higgins/scam/[id].tsx` (id = official alert URL): back / "Scam Alert" / share header, 4 equal-width tabs Overview | What to look for | How to stay safe | Source, plus "Read the official alert" button. All content comes from the alert's `higgins` and `facts` fields; empty sections are hidden, nothing invented.
- `src/higgins/scamAlertUi.ts`: shared helpers (cache/findAlert, icons, bullets, share).
- Settings icon taken out of all screen headers (RootScreenHeader, Home). Bottom nav stays Home | Threats | Alerts | Higgins | Settings (no Check tab, per user).
- Web preview testing: the API needs a device credential. Register through `/api/devices/register`, then seed localStorage keys `apollo.device.identity.v2` and `apollo.setup.done`.

## Scam Alerts: region memory, compact dropdown, family sharing (2026-06)
- The chosen region filter is saved (`apollo.scamAlerts.region`) and restored when Scam Alerts opens again.
- Screens narrower than 430px get a "Region: X (count)" dropdown list in place of the chip row.
- Family sharing: `POST /api/family/scam-alerts/share {device_id, url}` sends the alert to every linked family device, in both directions.
  - The server takes the alert details from its own official-source snapshot; an unknown URL returns 404.
  - It sends a push through PUSH_FAMILY, with action_url `/higgins/scam/<url>`.
- `GET /api/family/scam-alerts?device_id=` is the inbox. It only shows alerts from devices that are still linked.
- UI: "Send to my family" button on the alert detail (prompts to link family if no one is linked yet). "Sent by your family" section at the top of the Scam Alerts list, and "Scam alerts from your family" section on the Family screen.
- The `url` field was added to the family egress allow-list.

## Main tab headers: info icon + Threats status line (2026-06)
- On Threats, the description line is replaced by the last check time ("Last check run …" / "No check has been run yet", from `lastVerifiedAt`). An "About Threats" info popup was added.
- Info icon is 50% bigger. InfoButton went from 10 to 15, then to 23; the Higgins header icon is now 23 (same as Threats) and sits at the far right.
- The icon sits at the far right of the title on every main tab except Home: Threats, Alerts, Higgins and Settings (new About Settings). Home has no info button, per the user.
- In the Settings tab, the close X is replaced by the info icon. The X still shows when Settings is opened as a modal.
- The info icon is the right-most header item on every screen: ChildScreenHeader, text-guard and call now show the close X before the info icon. The icon sits flush with the right edge of its 44pt touch area.
- The user asked for no more enhancement suggestions in summaries.

## Cross-platform Device Malware & Compromise Check (2026-06)
- Engine (`src/domain/firstCheck.ts`) runs 7 capability-based checks on every platform:
  1. OS malware report
  2. Root/jailbreak/system integrity
  3. Installed apps and powerful access
  4. Apps from unknown sources
  5. VPN/profiles/certificates
  6. Security settings and updates
  7. Apollo's own protection
- Each check carries an explanation, evidence, a platform limitation and an action.
- The report has a `capabilityNote` explaining what this platform lets Higgins check.
- `osReportedThreat` is always supplied (no more universal null):
  - `signals.osThreatReport`, or `osThreatNotAvailable(platform)` when the adapter has none, which yields an explicit NOT_AVAILABLE.
- Evidence rules:
  - A trusted OS report → CONFIRMED_THREAT.
  - Heuristics → CAUTION or SUSPICIOUS at most.
  - Scanner switched off → CAUTION.
  - Report failure → ERROR.
  - CLEAR only when more meaningful checks executed than were blocked.
- Platform adapters:
  - **Android:** `AppDeviceSignals.kt` adds Play Protect (SafetyNet Verify Apps `isVerifyAppsEnabled` + `listHarmfulApps`, using the `play-services-safetynet:18.1.0` dependency) and root heuristics (su/magisk paths, test-keys).
  - **iOS:** `DeviceSignalsTruth.swift` adds jailbreak files and a sandbox write probe. The OS threat report is explicitly not_available.
  - **Windows:** Tauri `security_audit` adds the Defender threat report (`Get-MpComputerStatus`/`Get-MpThreat`, real-time protection, tamper protection) and SmartScreen.
  - **macOS:** Tauri `security_audit` adds SIP (`csrutil`), Gatekeeper (`spctl`) and MDM enrolment (`profiles`). XProtect is not_available.
- `currentPlatform()` uses the desktop adapter kind on Tauri.
- UI (`FirstCheckResult.tsx`):
  - New "What this device lets Apollo check" card.
  - Each row shows Evidence, Couldn't check and What to do.
- Native code (Kotlin, Swift, Rust) is untested here: no compilers in this container; it needs device builds.
- CheckToolHeader is now full width, so its info icon sits at the far right.

## Apollo Privacy Simplification (2026-06)
- **Inventory:** `core.data_classification`'s only production caller was `llm_boundary`. The `Classification` enum, `classify_field`, `SECURITY_FIELDS` and `PERSONAL_DATA_FIELDS` were used only inside `llm_boundary` and by tests.
  - `ProcessingPurpose`, `ProtectionLevel`, `AUTHORISATION_MATRIX`, `ProcessingPathway` and the helper functions were used only by tests, so they were removed.
- `data_classification.py` (1019 → ~220 lines) is now just a field registry: `DataCategory`, `FIELD_CATEGORIES` and `classify_field`.
- `llm_boundary.field_decision(key)` is the single outbound decision per field: `credential` / `evidence` / `personal`.
  - Security indicators that also identify a person (sender, caller number, email) count as `evidence`.
  - Unknown fields count as `personal`; outcome is unchanged.
  - The compatibility `Classification` enum was removed.
- `provider.generate()` stays the single Gemini boundary. It now screens copies of Parts/Contents (`model_copy`) instead of mutating the caller's evidence objects.
- Images: the server-side `sanitization_receipt_id` was never verified (length checks only), so it was removed from all endpoints, contracts, egress allow-lists and tests.
  - The `sanitization_digest` byte binding is kept as the minimum no-raw-bypass enforcement.
  - `_require_screened_bytes()` in `routers/analysis.py` now verifies SHA-256(bytes) == the declared digest on message/extract, page/extract and vision/investigate.
  - Evidence ingest already verified the digest; the redundant length checks in `investigations.py` were removed.
- Retention and encryption are unchanged.
- `privacyInventory.ts` wording was updated: no more "cryptographic receipt" or "purpose-based authorisation" claims.
- Tests: new `tests/test_privacy_simplification.py` (7 outcome tests); `test_data_classification.py` was rewritten as outcome tests. Backend suite: no new failures versus baseline (pre-existing failures are unrelated).

## Privacy simplification follow-up (2026-06)
- The image digest is described everywhere as BYTE BINDING (byte equality between the gate-selected bytes and the upload), never as attestation. Updated: backend helper docstring and error, approvedImageUpload, the SanitizationReceipt doc, privacyInventory and test docstrings.
- Frontend receipt-ID lifecycle removed:
  - Gone: `receiptId`, the in-memory receipts store, one-time consume, 5-minute expiry, `timestamp`/`consumed`, and the deleted `tests/imageSanitization.test.ts`.
  - `requireImageSanitization(receipt)` now checks that the gate result exists and isn't withheld.
  - transferManager/client carry the gate result object instead of an ID.
- Pre-existing gap: `setSanitizationReceipt` has no caller. Investigation image uploads through transferManager therefore stay blocked (fail closed), exactly as before.
- check.tsx page-screenshot upload now uses `buildApprovedUploadFields` (fail closed).
- providerRetention:
  - Live text now says "Google's published Gemini API terms… does not control or independently verify".
  - The test pins live mode; a separate test checks that the mock text is truthful.
- test_privacy_simplification uses a private event loop and stubs usage recording, so it no longer breaks test_retention_system.
- Full backend suite vs the pre-simplification baseline (610319ee): the only new failure is the date-dependent test_family_nudge, which is unrelated. Retention-suite failures in full runs exist at baseline too (order interference); retention tests pass in isolation.

## Image privacy simplified: "Protect credentials. Preserve evidence. Let Apollo investigate." (2026-06)
- Submitting an image is the authorisation to analyse it.
  - The ImagePrivacyGate now processes automatically, with no choice screen: it blacks out detected credentials on a copy, otherwise sends the metadata-stripped copy.
  - The manual options remain only for the failure path.
- `classifyRegions` redacts only `credential`. PII, financial, medical, sender, URLs and layout are kept as evidence. Extracted text is credential-redacted only.
- Investigation transfer path (previously always blocked): `investigationImageMeta()` screens the image on-device. If a credential is detected, that image is not sent (fail closed, since it can't be redacted there); otherwise it uploads. The original is stored unchanged as evidence.
- Removed as ceremony:
  - backend `sanitization_status`/`sanitization_digest` requirements (message/extract, page/extract, vision, investigations x2, evidence ingest) and `_require_screened_bytes`
  - `approvedImageUpload.ts`
  - the digest computation in `imageSanitization.ts`
  - transferManager `sanitizationReceipts`/`setSanitizationReceipt`
  - status/digest egress allow-list entries
  - the `test_wp2_digest_validation.py` test file and other ceremony tests
- Evidence now records only `{decision, transformations, redactedRegions}` when the device reports them.
- `privacyInventory.ts` updated. It states that detection depends on on-device text recognition.

## Final Image Privacy Cleanup (Frontend) — DONE (Jun 2026)
- Removed ImagePrivacyGate.tsx (approval sheet, text-only/withhold choices).
- All image uploads (Check page screenshot, Message screenshot, Vision, Higgins screenshot artifact) now use ImageUploadPrep:
  warning → Continue → detected credentials blacked out on a copy → copy sent; original untouched.
- Higgins screenshot artifacts previously sent the original image unscreened; now also go through ImageUploadPrep.

## Evidence Viewer + Crop Before Upload — DONE (Jun 2026)
- Crop: "Crop" button in the upload warning (Cancel | Crop | Continue) opens in-app crop tool (src/components/ImageCropper.tsx, drag corners/box). Cropped image is re-screened for credentials before sending. All 4 upload flows.
- Local image evidence store (src/store/imageEvidence.ts): original (never uploaded) + exact sent copy copied into app document folder, keyed by Patrol event id and/or investigation case id. Deleted with the investigation case (caseStore.remove) and on full data wipe.
- Viewer (src/components/ImageEvidenceCompare.tsx): side-by-side "Original (on your device)" / "Sent copy" with notes (cropped, credentials blacked out), tap for full screen. Shown in Patrol threat case Evidence tab and Investigation Evidence tab.

## Remove Original + Evidence Pack — DONE (Jun 2026)
- "Remove original" (inline confirm) deletes only the on-device original; sent copy + notes stay (imageEvidence.removeOriginal, sets originalRemovedAt).
- "Share pack" builds one PDF on device (src/utils/evidencePack.ts: case title, dates, both images, notes) and opens the share sheet (print dialog on web).

## Pack Case Summary + Report Scam Helper — DONE (Jun 2026)
- Evidence pack PDF now includes Higgins's summary, key findings, recommended steps, still-uncertain items (patrol: what_happened/why/what_to_do + briefing; investigation: response overview/findings/actions/uncertainties).
- ReportScamHelper (Evidence tab, both case screens): region chips AU/UK/US (default from phone region, saved in apollo.reporting.region). AU: ReportCyber, Scamwatch, IDCARE 1800 595 160; UK: Report Fraud 0300 123 2040, 7726; US: FTC, IC3. Named brand → official website; CommBank/Westpac/ANZ/NAB also 24/7 fraud lines (src/domain/reportingContacts.ts, verified Jun 2026).

## Report Progress Tracker + NZ/Canada — DONE (Jun 2026)
- "Your progress" checklist in ReportScamHelper: Called bank / Reported to police, with done time; "x of 2 done". Stored locally per case (src/store/reportProgress.ts, apollo.report_progress.v1); deleted with investigation case and on data wipe.
- Regions now AU, NZ (Police 105, Netsafe 0508 638 723, 7726), UK, US, CA (Canadian Anti-Fraud Centre 1-888-495-8501, 7726). Region default from phone locale.

## Google DLP image.redact POC — PAUSED (Jun 2026)
- Harness ready in /app/backend/poc/google_dlp_redaction (README.md). 47 synthetic images, scoring script, report generator, isolated venv.
- Blocked: needs a service account JSON (roles/dlp.user) + project id. Existing API keys don't work for DLP.
- Production image redaction unchanged. Do not change it until POC results are reviewed and approved.
- Note: fixed env drift during setup — pytz (used by routers/admin_portal.py) added to requirements.txt.

## Bug fix: "Mark as contained" not saving (Jun 2026)
- Backend routers/patrol.py: evidence-receipt replay guard returned stored event unchanged, dropping the user's resolution for verified-block events. Now `_apply_resolution_on_replay` records status/resolved_at (never un-resolves). Test: tests/test_contained_resolution_persists.py.
- Frontend ApolloContext: remote merge now waits for local restore (`ready`) and merges against eventsRef.current (was a stale/empty `events` snapshot that let server's unresolved copy overwrite local).

## v1.1.14 UAT — Threat Case Evidence shows the actual original + Reopen case (Jun 2026)
- src/store/originalSource.ts: exact original per case on device only (key apollo.original.v1.<caseKey>), deleted with investigation case / data wipe.
- Captured at source for: messages (text+sender), email (raw + From/Subject), links (raw URL), website (host + screenshot via imageEvidence), calls (check input / number lookup / call log item), apps (name/dev/source/permissions + SDK data), accounts (alert text + provider/sender), device (signals + self-report), network (connection snapshot, captive URL, enforcement/DNS raw evidence), QR (raw payload), Higgins submissions (text/URL by case id).
- Server-investigated sources (monitored email, captured texts): ApolloContext downloads root user_submission evidence content once (before 24h expiry) and saves it.
- Evidence tab shows OriginalSourceView first inside the Original card (fallback explains originals not saved for older cases). InvestigationView Evidence also shows it.
- Reopen case: patrol/[id] "Reopen case" (confirm) on resolved cases → reopenEvent: local + PATCH /patrol/events/{id} {reopen:true}; merge honours reopened_at; patrol_records appends new revision when returning to an earlier payload. Tests: tests/test_reopen_case.py.

## Government feed edge blocks (Akamai) — fingerprint + proxy rotation (Jun 2026)
- services/outbound.py: `public_get` now rotates 4 header profiles (Apollo bot UA → bot-style Mozilla → desktop Chrome → iOS Safari) when an edge answers 403/406/429/503 or drops the connection; the winning profile is remembered per host (`_host_profile`) so healthy feeds cost one attempt. All profiles keep `Accept-Encoding: identity` (bounded reader still refuses compressed bodies). Read timeout raised to 8s (connect 4s).
- Optional egress proxies: set `OUTBOUND_PROXIES` (comma separated) in the production backend env; each proxy is tried with every header profile. Empty/unset = direct egress (unchanged). SSRF guard unchanged: the target is still resolved and validated as public before any request, and pinned-IP connect is only skipped when a proxy terminates the hop.
- Preview verified: scamwatch.gov.au 200 (HEAD 403 → GET 200, profile 0 sticky), consumer.ftc.gov 200. cyber.gov.au returns 403 on all 4 fingerprints = pod-IP block, needs a proxy.
- Tests: tests/test_p0_outbound_unit.py (rotation + sticky, transport fallthrough, proxy env parsing). Full suite 832 passed.
- Production needs a redeploy for this to take effect; if Scamwatch still 403s in prod, the prod IP is IP-blocked and `OUTBOUND_PROXIES` must be set.

## Ask Higgins check flow — preview samples, camera, intent routing, threat card (Jun 2026)
- `src/components/HigginsArtifactInput.tsx`: every category in "What do you want to check?" now shows PREVIEW-ONLY sample pickers (screenshots, links, messages, callers, emails, apps, files, device concerns). Selecting one only FILLS the field (+ a suggested question); the person still submits and the submission runs the real Triage → Magnum DI path. Apps & Files shows two sections (apps, files).
- Screenshot category gained "Take a photo" (expo-image-picker camera) with the full permission contract: check → request → respect canAskAgain → "Open Settings" via Linking.openSettings(); denial only removes photo capture, gallery still works. Sheet label is now "Screenshot or photo" (QR codes, letters, other screens).
- Sample screenshots are real bundled PNGs drawn by `/app/scripts/make_preview_screenshots.py` into `frontend/assets/images/preview/`; resolved to a local file with expo-asset so Apollo's real screening reads real bytes.
- `src/preview/simulatedItems.ts`: added SIMULATED_LINKS, SIMULATED_DEVICE_CONCERNS, SIMULATED_SCREENSHOTS.
- `src/higgins/checkIntent.ts` (new, deterministic, no AI): when a chat message pairs a check intent with a subject (email / message / call / link / app / file / photo / device), Higgins acknowledges and opens the matching input form pre-filled with the person's words. Wired into `app/(tabs)/ask.tsx` submit() before the local intent router.
- Chat starters now lead with "I want to check an email / a message / a call".
- `app/(tabs)/patrol.tsx` threat card reorganised: full-width title (3 lines), subject line, then a meta row (status pill + source · date) with the Case ID beneath; chevron moved out of the right column so the title is no longer squeezed.

## Higgins Check gaps closed (Jun 2026)
Audit against the "Developer Instructions — Higgins Check" brief found 5 real gaps; all fixed without a new engine, backend or results system.
1. **Security rules wired for real** — `SecurityPlatformAdapter.RuleBundleStatus` + optional `getRuleBundleStatus()`; implemented only in `GuardDogProductionSecurityAdapter` from the runtime's own `ruleExpiresAt`/`productionAuthority`. Carried on `ProtectionHealthSnapshot.ruleBundle`; `diagnosticCore.rulesCurrent` no longer a TODO. Failed read = unknown, missing method = "not available on this device" — never "current".
2. **Device Check now renders on the shared Check Results screen** — new pure mapper `src/domain/firstCheckResultModel.ts` (report → `CheckResultModel`): one headline, items (NOT_AVAILABLE → `not_performed`, ERROR → `error`, never `clear`), ONE action from the most severe check that has one plus one in-app destination (`actionRoute`), limitations as evidence rows. `app/recheck.tsx` rewritten to use `CheckResultScreen`; the auto-starting "Ask Higgins about this check" investigation card was removed (user-initiated "Ask Higgins about this result" only) so there is no second narrative.
3. **Real progress** — `collectFirstCheck(onProgress)` emits the 4 stages it actually performs (`FIRST_CHECK_STAGES`); `/recheck` shows "Step n of 4" + the live stage label, no timed animation.
4. **Home "checked by Higgins"** — new `home-higgins-check` row reads the stored completed check (`firstCheckStore.getBaseline().checkedAt`) and links to `/recheck`; opening the app never counts as a check.
5. **Plain-English pass** — Diagnostic Core now says "secure connection" (not VPN), "security rules", "internet connection", and explains Private DNS in plain words with the technical term in brackets.
Also added: `connection` check row (internet connection, captive portal, open Wi-Fi) in a category deliberately excluded from `MEANINGFUL_CATEGORIES` so it can't flip a LIMITED_CHECK into CLEAR.
Still intentionally absent: controlled-threat generation (no check attempts a block; the THREAT_BLOCKED enforcement-evidence gate in `backend/routers/patrol.py` is untouched).
Tests: `frontend/tests/deviceCheckResult.test.ts` (5 pass), `tests/firstCheck.test.ts` (14 pass).

## Higgins check sheet — tap feedback (Jun 2026)
Sample rows read as "not tappable" on a real device because the filled field sits below the sample list. `Sheet` now accepts a `scrollRef`; selecting a sample marks that row "Selected", shows a confirmation line, and scrolls straight to the filled field + submit button.

## DI tab — copy the Gemini request and response (Jun 2026)
`src/domain/diTransactionText.ts` (new, pure) renders one DI transaction as plain text: `diRequestText()` = everything the "Sent to Gemini" card shows (system prompt, investigation prompt, tools, attachment metadata, payload size) and `diResponseText()` = the complete response plus finish reason and the recorded processing/cost statistics. Attachment bodies are never included — only the recorded metadata.
`DiReport.tsx` puts a Copy button in each of those two card headers (`tc-di-request-copy-N`, `tc-di-response-copy-N`): tap copies, long-press shares, button shows "Copied" for 3s and the toast says where to paste. Simulated transactions are labelled as the simulator response and keep the "no Gemini API call was made" note in the copied text.

## Gemini investigation request rewritten (Jun 2026)
The Magnum DI request now contains exactly three things and nothing else:
1. **Question** — the person's message, once, as the first part.
2. **All case evidence** — complete. `evidence.model_parts()` sends each item once, labelled `[evidence <id> · kind=<kind> · <label>]`, with the FULL text (the 2,000-char inline cut and `INLINE_TEXT_CHARS` are gone). Images are sent as bytes with a single identifying line — no second textual description. Unavailable items are named with their recorded reason so their ids stay referable.
3. **Response schema** — `services/higgins/response_schema.py` (`RESPONSE_SCHEMA`, Gemini structured output). The required shape is stated ONLY there; it is never repeated or explained in the prompt. A test asserts the schema's properties equal `ModelResponse`'s wire fields exactly, so drift fails fast.

Removed: the entire `coordinator.SYSTEM` prompt (Magnum DI framework, Higgins briefing standard, JSON-shape instructions), the `INVESTIGATION BRIEF (JSON)` block (device profile, previous turns, open question, registered sources, evidence inventory) and the summarised triage intelligence. `health_check.py` also sends no system prompt and uses the same schema.

Kept: **Google Search** as a tool — verified against current Google docs (2026-10-20): Gemini 3 models support structured outputs combined with built-in tools including Google Search, and the app runs `gemini-3.8-flash`. (An earlier web search claiming incompatibility was wrong; the docs page `ai.google.dev/gemini-api/docs/structured-output` §"Structured outputs with tools" is authoritative.)

Apollo's pre-gathered specialist intelligence (RDAP, Safe Browsing, IPQualityScore, HIBP) is now registered **as case evidence**, verbatim, by `coordinator._register_triage_evidence()` (client item id `apollo-triage-intelligence`, kind `observation`, origin `apollo_inference`, idempotent) so it is sent whole and can be cited — never summarised into a prompt.

Dead code removed with it: `read_evidence` function declaration + dispatch branch and `evidence.read_text()` (the range-reading path had no remaining caller), plus the obsolete prompt-text tests (`test_round1_investigation_prompt.py` deleted; prompt assertions in `test_higgins_authority.py`, `test_higgins_briefing_acceptance.py`, `test_purpose_limited_investigation.py`, `test_user_secret_redaction.py` replaced with runtime/validator assertions).

DI tab now states plainly that no system prompt is sent, and the request card reads "Question and evidence sent".

Tests: `tests/test_gemini_request_shape.py` (new, 2) proves system == "", question first and once, every following part labelled, full text present, triage intel raw, schema attached, validator accepts the response; `test_magnum_di_acceptance.py` gained `TestGeminiRequestContract` (5). 97 pass across the six affected files. Pre-existing unrelated failure: `test_recovery_fencing.py::test_committed_case_projects_once_into_patrol_without_model_call` ('vision' category literal).

## Magnum DI model → Gemini 3.1 Flash-Lite (Jun 2026)
`provider.TEXT_MODEL` default is now `gemini-3.1-flash-lite` (stable, May 2026). Verified from the model card: text/image/video/audio/PDF input, function calling, **Search grounding** and **structured outputs** are all supported, 1,048,576 input / 65,536 output tokens — everything the new investigation request uses (the 16,384-token output budget is well inside the limit).
- `CAPABILITIES["gemini-3.1-flash-lite"]` corrected from `_LITE_CAPS` ({text, json}) to `_TEXT_CAPS`; the old entry would have made the capability gate reject the `search` capability on the investigation call.
- `VISION_MODEL` and `ADVISORY_MODEL` are now pinned explicitly to `gemini-3.8-flash` (they previously defaulted to TEXT_MODEL) so vision extraction and advisory generation keep their existing model — the switch is Magnum DI only.
- `gemini_usage.MODEL_PRICING` gained real 3.1 Flash-Lite rates ($0.25 in / $1.50 out / $0.025 cached per 1M, standard tier) and `PRICING_VERSION` → `2026-10-20`; without it, cost reporting would have fallen back to the conservative $1/$5 default and overstated every investigation.
- `admin_health.py` and `admin_portal.py` now read `provider.TEXT_MODEL`/`VISION_MODEL` instead of re-defaulting the model string, so the admin views can't drift from the real configuration.
Items 1–6 of this brief were already delivered in the previous change (see "Gemini investigation request rewritten"). Tests: 64 pass across the acceptance/request-shape/authority files.

## 10,000-word evidence cap per investigation (Jun 2026)
`evidence.EVIDENCE_WORD_LIMIT = 10_000` — the maximum words of written evidence Apollo will send in ONE Magnum DI investigation, across every document and item combined. `model_parts()` now also returns the total word count (labels excluded; images contribute no words).
`coordinator.run_turn()` checks it immediately after assembling the evidence and BEFORE any Gemini call: over the limit it returns `Outcome("evidence_too_large", evidence_words=N)` — no call is made, no evidence is marked examined, and nothing is shortened, sampled or dropped.
`jobs.py` turns that into a non-retryable failure with code `evidence_too_large` (added to `FailureCode`) and `evidence_too_large_message(words)`: states the real word count and the limit, says plainly that none of it was sent and nothing was shortened, points the person to their own AI assistant (Gemini, Claude or Copilot) for documents that long, and gives one action — remove some material and run the check again. The investigation UI already prefers the server's message, so it displays as written.
Tests in `tests/test_gemini_request_shape.py`: two 5–6k-word documents that are individually fine but together 11,000 words → `provider.generate` is never called, coverage stays `not_started`, and the message contains the counts and all three assistant names; 9,999 words still assembles normally.

## Evidence sent to Gemini: originals + new information only (Jun 2026)
Rule now enforced in `evidence.model_parts()`: send the original case evidence and any item that carries NEW investigative information; never send verbatim duplicates, workflow metadata or empty lookup envelopes.
- **Derived duplicates withheld**: an item with a `parent_id` whose whole content appears verbatim inside the parent being sent (the phone/link clues `register_clues()` extracts from an SMS) is not retransmitted. The clue records remain in Apollo for specialist lookups, evidence relationships and processing; they are only withheld from the request, and only while the parent is actually being sent.
- **Children with new information are still sent**: a page snapshot, provider finding or any child whose text is not contained in the parent is evidence in its own right.
- **Workflow metadata not sent**: `is_workflow_metadata()` matches "user-initiated/automatic … check/investigation". Fixed at source too — `app/(tabs)/ask.tsx` no longer submits "User-initiated check via Ask Higgins: <category>" or "User-initiated screenshot investigation from Check tab" as initial findings (real Apollo detection reasons in `ApolloContext` are untouched).
- **Empty lookup results not sent**: `has_intelligence()` returns False for an envelope with `providers_consulted: []` / `total_lookups: 0` and no other content. Applied in `coordinator._register_triage_evidence()` (never registered) and `routers/investigations.py` (`intel-N` items never ingested), as well as in `model_parts()` for cases already stored.
- DI tab: the "System / coordinator prompt" block is removed from the UI and the copied text (there is no system prompt).
For the SMS example the request is now exactly: the question, then one part — `[evidence <id> · kind=text · messages calls]` with the full SMS. Tests (`tests/test_gemini_request_shape.py`, 7 pass) assert precisely that: one text part, clue records still present in Apollo, no workflow metadata, no empty envelope, and a snapshot child still sent. 81 pass across the investigation suites.

## Threat case clarity, Threats listing, and two defects (Jun 2026)
1. **"What is the text message?" — vagueness fixed.** The synced patrol copy is privacy-minimised by `patrol_policy.minimal_patrol` ("Apollo checked a text message…"), but the item itself is held on the device. `app/patrol/[id].tsx` now loads `getOriginalSource(event_id)` once at screen level and uses it for: the source-card title/subtitle (sender, or the message's first line, instead of the category), the Overview subject line, and a new **"What Apollo is checking"** card (`tc-overview-checking`) that shows the sender and the full message/URL verbatim (secret-redacted, selectable) while the investigation runs. Nothing is inferred — the card only restates what Apollo holds locally.
2. **Nested-button console error fixed.** The hero paging dots (`home-hero-dots`, role=button) sat inside the hero card Pressable (role=button) → "`<button>` cannot contain a nested `<button>`". The dots row now renders below the card, outside the gesture detector; tap-to-advance and swiping both still work. Verified: 0 console errors on Home.
3. **"Where to report" card removed** — `ReportScamHelper.tsx` and `domain/reportingContacts.ts` deleted along with their only call site in `InvestigationView.tsx`.
4. **Ask Higgins investigations are saved and listed in Threats from the moment they start.** `investigation_projector.project_case_started(case)` writes the patrol record at case creation (called from the create route and from the new periodic `project_open_cases`), using the SAME deterministic `event_id` the committed projection later updates — one record per case, never two. The placeholder states only `state: "sniffing"`, "Apollo is investigating this", with no findings, assessment or conclusion. Cases that began from an existing patrol event are skipped (they already have a record).
5. **Projection bug fixed:** the gate→category map had no entry for `vision` (and others), so screenshot-started cases failed `PatrolEvent` validation and NEVER reached Threats — this was the `maintenance_component_failed component=investigation_patrol_projection` error in the logs. New `GATE_CATEGORY`/`patrol_category()` maps every gate to a valid category (vision/screenshot → message, site → website, network → connection, unknown → message). The previously failing `test_recovery_fencing.py::test_committed_case_projects_once_into_patrol_without_model_call` now passes and the maintenance error has stopped.
Tests: new `tests/test_open_case_projection.py` (2) + 45 in `test_recovery_fencing.py` pass.

## "Current status" now matches the case (Jun 2026)
The Overview status card hard-coded "Investigating with Magnum DI / Analysing sender, links and content…" whenever the event had an investigation case id — so a **Resolved** case still read as actively investigating. New pure helper `caseStatusLine(event)` in `src/domain/threatCase.ts` derives the one true line from the case: closed → "Closed" / "Closed — no threat found" with the resolution time and "Nothing is running on this case"; open + live investigation → "Investigating with Magnum DI" (the only line that reads as running, dot stays blue); open + finished investigation → "Investigation finished"; verified block → "Blocked by Apollo"; barking/biting → "Waiting for you"; otherwise "Being monitored". `app/patrol/[id].tsx` renders it with a muted dot when nothing is running. Test: `frontend/tests/caseStatusLine.test.ts` (4 pass).

## Device check is a case; patrol history; "Is my device protected?" answer (Jun 2026)
1. **A completed device check is a case.** New pure builder `src/domain/deviceCheckCase.ts` (`deviceCheckEvent`) turns Higgins' device-check briefing into one patrol event (category `device`, `evidence_provenance: local_device`, `source_metadata.type: device`): clear → `resting` + closed (reads "No threat" in the list), review → `ears_up`, action → `growling`, failed read → never `resting` and headline "Device check didn't run". `app/device.tsx` files it via `upsertEvent` once per USER-INITIATED check (signature-guarded; simply opening the screen is a background refresh and is never recorded), attaching the review results as the original source so the Evidence tab shows the facts. It therefore appears in Threats, in patrol history, and opens through the same threat-case screen. Test: `frontend/tests/deviceCheckCase.test.ts` (4 pass).
2. **Patrol history** — new `app/patrol/history.tsx`: every filed event, newest first, grouped by day (Today/Yesterday/date), NOT deduplicated, each row showing headline, time, case id and status, tapping through to the case; "Save or share this history" uses the existing `exportPatrolPdf`. Linked from the Threats screen header (`threats-history-link`, clock icon). Threats = one row per case; history = the record as it happened.
3. **"Is my device protected?" rewritten** in `diagnosticCore.buildProtectionSummary` to follow the Higgins rule (plain English, one problem, one action, technical detail only when asked). Previously it dumped "Apollo is running. 1 of 10 protections are active. This device can't report the state of Apollo's security rules… No issues need attention." — technical, cluttered and self-contradictory. Now: direct answer first (Yes / Partly / No), then at most ONE problem named with ONE action ("Open Apollo's protection settings and turn it on, then ask me to check again"), the unavailable security-rule check kept out of the answer (still recorded in facts for More details), and it can never say "no issues" while protections are off — off-but-unavailable protections are stated as unavailable. Verified live: "Partly. Apollo is running, and 1 of the 10 protections on this device is on. The other 9 aren't available on this device, so they can't be switched on here. I last checked at 06:48 PM." Test: `frontend/tests/protectionAnswer.test.ts` (5 pass).

## One device-check case, many checks (Jun 2026)
Rechecking a device after fixing something used to file a brand-new case each time (case noise). Now:
- `PatrolEvent.case_key` (new, local-only field) carries a stable case identity for repeat checks. `deviceCheckEvent` sets `deviceCheckCaseKey(deviceId)` = `device-check:<deviceId>` — one device = one case, including when a later check finds a *different* problem.
- New pure helper `caseGroupKey(event)` in `src/domain/threatCase.ts` (`case_key ?? patrol_record.logicalIssueKey ?? event_id`) is what the Threats list dedupes on (`app/(tabs)/patrol.tsx`), so device checks collapse into ONE case row showing the latest result. Patrol history is untouched — every check remains its own entry.
- A finished check now stays OPEN until the person closes it (clear results no longer auto-resolve): `status: "active"`, `resolved_at: null` for every outcome.
- Case screen (`app/patrol/[id].tsx`): new `CaseCheckRuns` card — "Checked N times · last checked <date>" plus the earlier checks, each tappable to open that patrol entry. Only shown when a case has 2+ checks.
Test: `frontend/tests/deviceCheckCase.test.ts` (6 pass).

## Dismiss a device case + what changed between checks (Jun 2026)
1. **Close a device check from the case screen.** `EventActions` labels the resolve action "Close this device check" for `category: "device"` and, once closed, states "This device check is closed. Rechecking your device files a new check on this case." `resolveEvent` now closes every event sharing the case's `case_key` (as well as scent siblings), so closing the case closes all of its checks; a later recheck files a fresh active check and the case reads as open again.
2. **Every user-initiated check files its own patrol entry.** The old content-signature guard in `app/device.tsx` silently dropped a recheck that found the same thing (and a background refresh while the briefing was open could file a duplicate). Replaced with a per-run guard: `notifyRun` increments on each user-initiated check, the briefing records its run (`briefingRun`), and the case effect files exactly one entry per run. Background refreshes never change `briefingRun` and are still never recorded.
3. **"Since the check before this one".** New pure module `src/domain/deviceCheckProgress.ts`: `comparableChecks(data)` reads the review results stored with a check (null when that check recorded none), `compareDeviceChecks(before, now)` returns the changes — `fixed` (was action/review, now OBSERVED correct), `new_problem`, `still_open`, `not_confirmed` (was a problem, now unreadable — never counted as fixed) — plus a one-line summary ("1 fixed · 1 still needing attention"). Rendered inside the `tc-overview-runs` card on the case screen, comparing this check with the one immediately before it; nothing is shown when the earlier check kept no comparable results (e.g. web, or a failed read). Test: `frontend/tests/deviceCheckProgress.test.ts` (5 pass).
Verified in the preview: two rechecks → 2 patrol-history entries, 1 Threats case ("Checked 2 times · last checked …", earlier check listed and tappable), "Close this device check" → case reads Resolved.

## Preview simulators kept out of shipped builds (Jun 2026)
Single gate `src/preview/samples.ts`: `PREVIEW_SAMPLES_ENABLED = __DEV__ && EXPO_PUBLIC_PREVIEW_SAMPLES !== "off"`. The Emergent preview is the Metro dev server, so `__DEV__` is the only signal that is automatically false in every shipped build (native or exported web) and cannot be re-enabled by a mis-set env var. All sample data (`simulatedItems`, `simulatedInbox`) is now loaded ONLY through this module — every collection is empty when the gate is off, so a screen that forgets its own gate has nothing to show. `SimulatedPicker.PREVIEW_SIMULATION` and `app/email.tsx`'s simulated inbox both sit behind it. Guard test: `frontend/tests/previewGating.test.ts` (4 pass) fails the build if any file imports the raw sample modules directly.
Backend: new `APOLLO_ENV` (preview|development|staging|test; anything else or unset = production). In production the preview-only provider modes (`simulated`, `mock`, `live_test`) refuse to start with an explicit error — only `live` may run. `backend/.env` now carries `APOLLO_ENV=preview`. Test: `backend/tests/test_provider_environment_guard.py` (4 pass).
Belt and braces: a DI record marked `simulated` renders a loud "not a real investigation" notice in a shipped build (`DiReport`).
KNOWN LIMIT (told to the user): the sample *strings* still exist in a production bundle as unreachable dead code. Metro keeps the module in the dependency graph even with `EXPO_UNSTABLE_TREE_SHAKING`; removing the bytes needs a resolver alias in `metro.config.js`, which is a protected file in this environment.

## Alerts bell in main tab headers + notification card removed (Jun 2026)
- Removed the "Notifications are off" banner from the Higgins screen AND the chat reminder Higgins used to post (`app/(tabs)/ask.tsx`; `notifHealth` state, `notifReminderShown` and the banner styles all deleted).
- New `src/components/AlertsButton.tsx`: bell that opens the Alerts tab, with an amber dot when notifications are off. The dot never appears when the platform reports `unsupported` (web/Expo Go) — nothing for the person to turn on there. Refreshes on screen focus.
- Placed next to the info icon on Home (`home-alerts`), Threats (`threats-alerts`), Higgins (`higgins-alerts`), Settings tab (`settings-alerts`) and via `RootScreenHeader` for Alerts/Protection.

## Why Apollo notifications never reached the notification bar (Jun 2026)
Three real causes found and fixed:
1. **Project ID mismatch** — `backend/.env` had `EXPO_PROJECT_ID=higgins-refine` while the app sends `extra.eas.projectId = b2eb337d-2687-46bf-b1cc-292d30c0b601`. `POST /api/register-push` rejects a mismatch with 422, so no device token was ever stored and the backend could never send anything. `.env` corrected to the UUID.
2. **Pushes addressed to deleted Android channels** — `routers/push.py` sent `channelId: "threats"` / `"growling"`, but the app consolidated to `apollo_alerts` and explicitly DELETES the legacy channels. Android drops notifications addressed to a non-existent channel. `PUSH_THREAT`/`PUSH_GROWL` now use `apollo_alerts`; priority `high` follows that channel. (`tests/test_iter6_push.py` 14 pass.)
3. **Quiet hours silenced everything** — `ApolloContext` tested `alert.channel !== "growling"`, impossible since the channel rename, so the quiet-hours check never applied correctly. Severity now comes from the event state: `barking`/`biting` always deliver, everything else respects quiet hours.
Still true by design: notifications are OFF in Expo Go and web (`SUPPORTED` excludes `StoreClient`) — they can only be seen in an installed build.

## Screenshot picker fixed, zero TypeScript errors, and the dead code behind them (Jun 2026)
`npx tsc --noEmit` went from 40 errors to 0. Four of them were real, user-visible bugs:
1. **`app/check.tsx` crashed on screenshot pick** — `setPageScreenshotUri(...)` was a leftover setter for state that no longer exists, so picking a screenshot threw a `ReferenceError` before the privacy screening could run. Removed (two call sites).
2. **Recent links on Check were sorted and dated from `created_at`** — a field `PatrolEvent` does not have, so the comparator returned `NaN` and `formatLinkDate(undefined)` printed an invalid date. Now `occurred_at`.
3. **`StyleSheet.absoluteFillObject` no longer exists in this RN version** — spreading `undefined` silently dropped `position: absolute`, so the Protection hero's background image and text overlay were laid out in flow instead of filling the card. Now `StyleSheet.absoluteFill`.
4. **`radius.xl` and `colors.brandLight` were never defined** — bottom sheets on Email/Learning and the CheckingModal card rendered with square corners, and the selected filter chip in Higgins history had no background. Added `radius.xl: 28`; chip uses `brandSecondary`.
Dead code paths that could never run, now corrected rather than deleted: `diagnosticCore` read `protection.state`/`network.transport`/`permission.granted`/`permission.essential` — none of which exist on those types — so "is my device protected?" always treated the service as running and ALWAYS answered "all required permissions are granted" even when they were denied. Now reads `protection.running`, `network.type` and `status === "granted"`, with `required` derived from the permission being applicable. The `privateDnsActive` branches were removed: `ProtectionHealthSnapshot.network` has never carried that field (it lives on `PrivateDnsStatus`, which this module is not given), so those warnings could never fire. Also fixed: `PriorityScamNotice` compared `australianRelevance` against `"directly_relevant"` (the real value is `"confirmed"`), so AU alerts were never preferred and never labelled "Australian Scam Alert"; `protectionAlerts` addressed the deleted `"default"` Android channel; `caseStore` built a `Failure` without `retryAfterSeconds`/`missingEvidenceIds`. `GATE_REGISTRY.checkResultGate` is now typed `CheckResultGate` instead of `string`, which is what made the seven check-result adapters type-check.

## Each section of an investigation says something different (Jun 2026)
The result repeated itself: the overview ended with "The link goes to abc.net.au", then `attentionReason` printed `findings[0].text` verbatim ("The content presents itself as ING but the link goes to abc.net.au…"), then the action said it again. The PDF was worse — `explanationMarkdown` opened with the overview in bold and then re-listed the findings, the uncertainties and the actions, each of which the PDF already prints as its own section.
- `preview_analysis.py`: the overview is now the conclusion plus the one thing to do (no host, no credential list); `attentionReason` states the CONSEQUENCE of acting on it, never a finding; `explanationMarkdown` is `_briefing()` — the reasoning that connects the findings (why impersonation works, why credentials matter before they are typed, why a deadline exists), with no re-list of anything returned in another field. Article agreement fixed ("an ING", not "a ING"), and bare domains written in the text are normalised through `_host()` so `www.abc.net.au` and `https://abc.net.au/...` are one destination.
- `response_schema.py` (the ONLY channel the live model sees — the coordinator sends no system prompt) carries the same contract in its field descriptions: overview = conclusion only; explanation = why they fit together, not a reprint; attentionReason = the consequence, never a copy; findings = merge anything making the same point; actions = the action only.
- `validation.py` enforces it for live and simulated alike: `deduplicate_findings()` compares the meaning-bearing words of every finding (hostnames normalised, filler words dropped) and merges subsets or ≥0.8 overlaps, keeping the version with more cited evidence. Never empties a non-empty list.
- Frontend `investigationCaseUpdate.bodyFrom()` strips the headline sentence from `what_happened`, so the case card no longer prints its own title again as the first line of the body.
Tests: `backend/tests/test_finding_dedupe.py` (4), `test_preview_simulator_specifics.py` (+2 asserting no section is a copy of another), `frontend/tests/investigationCaseUpdate.test.ts` (6). Verified end-to-end through `POST /api/investigations` and in the Higgins UI.

## Picking beats typing: the source picker is now the hero of every check screen (Jun 2026)
The pickable list used to be printed inline as a long dashed "Simulated …" block in the middle of the page, and in the Higgins "+" sheet the picker buttons sat UNDER the submit button. Now, on every artifact screen, the first card is a hero: title, one line of plain English, and a full-width primary button that opens the same popup a production build opens.
- New `src/components/SourceHero.tsx` — first action renders as the 56pt primary hero, any others as secondary beneath it.
- `app/email.tsx` (`email-hero` → `email-source-picker`), `app/message.tsx` (`message-hero` → `message-source-picker`), `app/call-guard.tsx` (`callguard-hero` → `callguard-source-picker`), `app/file.tsx` (`file-hero` → `file-source-picker`), `app/app-check.tsx` (`app-hero` → `app-source-picker`), plus `HigginsArtifactInput` where the hero now opens the sheet.
- The button is worded for production in every build ("Choose an email", "Choose a recent caller"); the PREVIEW ONLY tag lives inside the popup. Where a real list exists the hero opens it (connected inbox, `/message-picker`, `PhonePickerSheet`, the OS file picker, the installed-app sheet) and falls back to the sample popup only where the real source cannot be reached — on Messages that replaces a card that used to dead-end in a toast on iOS and web.
- Removed: the inline `SimulatedPicker` blocks on file/app-check/call-guard, the hand-rolled simulated inbox on email, and the orphaned styles behind them.


## STANDING RULES — do not remove

### No testing agent without explicit owner approval
Never call the testing subagent unless the owner explicitly says to. Manual verification or lint/restart is fine; the automated testing agent requires a direct "run tests" instruction.

### No-fallback contract (production Gemini)
Simulation is NOT a fallback for production. When the provider mode is `live`, every Gemini failure must be reported exactly as failed — the error code, HTTP status, finish reason — so Higgins can surface the honest failure to the person. There is no "try again with fake data" path, no silent substitution, no graceful degradation to mock responses. A production failure is a production failure.

## Provider cleanup: zero preview imports in production provider.py (Jun 2026)
`services/higgins/provider.py` contains zero imports or references to preview modules. The preview code lives in `services/higgins/preview/` and is installed at startup via try-import in `server.py`:
```python
try:
    from services.higgins.preview.dispatch import install_preview_provider
    install_preview_provider()
except ImportError:
    pass  # Production: preview/ not deployed
```
No environment variables (`APOLLO_ENV`, `APOLLO_PROVIDER_MODE`) are needed. The physical presence of the `preview/` directory IS the signal. In production, it's not shipped — `ImportError`, nothing to configure. In preview, it exists and installs the simulator handler on `provider._preview_generate`.

## Sniffing & Growling push notifications (Jun 2026)
- `routers/patrol.py`: sniffing events now trigger `push_owner_alert()` alongside growling — was `event.state == "growling"`, now `event.state in ("growling", "sniffing")`.
- `routers/push.py` `push_owner_alert()`: notification title differentiates state — "Apollo is sniffing" for sniffing, "Apollo is growling" for growling (was always "Apollo is growling" for both). Both respect the `sniffing_growling` category preference and quiet hours.

## The DI tab went blank in preview — the simulated transaction was being withheld (Jun 2026)
The owner reported "simulated Gemini is not running in preview": every investigation finished, but its
DI tab said "No transaction recorded". The simulator WAS running (1,229 simulated records in
`di_transactions`, each with the real request, the response and the processing statistics) — two guards
added by the earlier isolation commit (e0f3e61) hid them:
- `routers/investigations.py` `GET /investigations/{case_id}/di` dropped EVERY record with
  `simulated: true`, in every environment. Now the filter applies only when
  `get_provider_mode() != "preview"` — i.e. in production, where `services/higgins/preview/` is not
  deployed, nothing simulated can be produced, and any older record is still withheld.
- `src/components/DiReport.tsx` filtered on `__DEV__` and, for a simulated record, rendered the dashed
  warning ALONE — no request, no response, no processing. It now gates on `simulation.included` (the one
  build decision; `simulationAbsent` reports `false`, so a production build renders nothing simulated)
  and shows the full record behind a notice that says plainly the response did not come from Gemini.
Verified end-to-end against the running preview: a real `POST /api/investigations` →
`GET /investigations/{id}/di` returns one record (`Simulated`, `Preview`, `gemini-3.1-flash-lite`, the
real prompt and a 2 KB response), and the owner confirmed the "Sent to Gemini" card is back.
`backend/tests/test_di_simulated_visibility.py` (2) pins both directions.

## Preview artifact check was passing on markers that can never exist (Jun 2026)
`scripts/verify-no-simulation.mjs --preview` failed 7/9: `src/simulation/` and
`simulatedScreenshotText` are a module path and a file name, and a production-mode export carries
neither — so their absence from the production artifact proved nothing. Replaced with content strings
that only the simulation source contains (`commbank-cancel.co`, `civic-plumbing-invoices.com`), both
proven present in a preview export. Now: production 0/9 markers, preview 9/9.

## Both test suites are green again, and the tests that were testing nothing are gone (Jun 2026)
Baseline was 23 failing frontend tests (5 whole files that could not even load) and 19 failing backend
tests. Every failure was triaged as "the product changed and the test was never updated" or "the thing
under test no longer exists" — no production bug was found behind any of them, with two exceptions that
needed a decision (below). Now: **frontend 861 pass / 0 fail**, **backend 922 pass / 0 fail**,
`tsc --noEmit` clean, ESLint clean.

**Deleted — nothing left to test**
- `frontend/tests/protectionTimeline.test.ts`, `frontend/tests/gate3page.test.ts`: `src/domain/protectionTimeline.ts`
  and `src/domain/pageAnalysis.ts` were removed in the Stage 14 consolidation and have no successor
  (page analysis is server-side now). `package.json`'s `test:gate3page` script went with them.
- The `buildProtectionFindings` / `countDistinctFindings` sections of `architecturalRegression.test.ts`
  (describes 4–6) and section 1 of `phase2Corrections.test.ts`: same deleted module, `protectionDetails.ts`.
  Home derives attention from `buildHomeAttention`, which those files still cover.
- `backend/tests/test_mock_provider.py` (376 lines) **and `backend/services/higgins/preview/mock_provider.py`
  (285 lines)**: nothing imported the mock provider. The preview path runs `preview_simulator` through
  `preview/dispatch.py`; the mock provider and its `APOLLO_PROVIDER_MODE=mock` contract were dead code.
- `frontend/tests/e2e/test_iter19_share_and_incident.py` and `tests/contrast_sweep_iter39.py`: one- and
  two-line placeholders that ran nothing.

**Rewritten to the contract that actually exists**
- `backend/tests/test_provider_environment_guard.py`: the `APOLLO_ENV` / `APOLLO_PROVIDER_MODE` guard it
  tested no longer exists. It now pins the structural guard: no preview handler → `get_provider_mode()`
  is "live"; installing the dispatch is the only thing that makes it "preview", and `client()` then
  raises; `provider.py` names no preview module and no env switch; `server.py` installs the dispatch
  through an optional import.
- `phase2Corrections.test.ts`: the two limited-coverage navigation tests asserted different routes for
  "genuinely affected" vs not. Visibility loss no longer escalates, so both produce the same voice —
  collapsed into one test over both capability mixes, and `/protection-details` (a deleted screen) is
  no longer expected.
- `frontend/tests/test_guarddog_production_source.py`: `test_no_signing_infrastructure_in_core_sdk`
  asserted "no Ed25519 anywhere", but the production runtime pins a public key
  (`PINNED_SIGNING_PUBLIC_KEY`) and the SDK verifies with the platform's own Ed25519 — the old
  multi-key trust-manifest infrastructure is what was removed, not signature verification. The test now
  pins that model. `test_repository_contains_no_private_key_material` was tripping on a PEM label inside
  a vendored `cryptography` package; `.venv`/`site-packages`/`dist` are now skipped with node_modules.
- `homeStatusSeparation.test.mjs` (14 failures): its gate fixtures predated `gate.resolved`, so
  `deriveCoverage` read `undefined.coverageState`. The fixture now resolves state through the one real
  resolver (`resolveProtectionState`) instead of hand-writing a second interpretation.

**Stale wording and fixtures corrected** (the app's own copy/shape is the source of truth): "Gate"
vocabulary → plain English in `higginsChecks`, `higginsGreeting`, `homeAttention`, `higginsBehavioural`;
Android channel `threats`/`growling` → the single `apollo_alerts` in `localAlerts`; tab parity → Home /
Threats / Alerts / Ask Higgins / Learn in `iosSourceReadiness`; `protectionAnswer`'s snapshot used
`protection.state` where `ProtectionStatus` carries `running`; the email screen's inline preview
disclaimer moved into the picker popup (`fileDeviceGateUi`); the report renderer's heading and the
legacy `expo-file-system` calls in `reportHealth` / `systemHealth`; `patrol.py`'s push branch is now
`event.state in ("growling", "sniffing")` (`test_iter7_quiet_and_phone`); `_PROVIDER_MODE` monkeypatches
replaced with `_preview_generate` in `test_privacy_simplification`, `test_privacy_screening_enforcement`
and `test_recovery_fencing`.

**Two that needed a judgement, not a rename**
1. `p0TruthPrivacyFile` expected visibility loss / stale verification to leave "resting".
   `resolveApolloState` deliberately keeps the state resting and carries the truth in `visibilityLost`
   + the reason + the route ("a protection status issue, not a security threat"). The test now asserts
   that flag, reason and route — the all-clear is still never claimed when Apollo cannot see.
2. The same file expected a caller's phone number and "password abc" to be redacted from the Ask
   Higgins context. The canonical policy (`privacyPolicy.ts`) redacts credentials with a connector
   ("password is …", "code: 884213") and only the OWNER's own personal data — a third party's number is
   the SUBJECT of the check and must survive or Call Guard cannot check it, and broadening the regex to
   bare "password <word>" would redact "password reset email". Test now pins that: the code is
   redacted, the number under investigation is not.

**Still skipped on purpose** (not failures): credentialed integration tests (`APOLLO_RUN_CREDENTIALED_INTEGRATION=1`),
`ImagePrivacyGate.tsx` checks for a gate handled differently now, checkpoint/ledger replay removed with
the single-pass coordinator, and server-side report retention which is disabled.

## Play Store readiness review (2026-06, review only — no code changed)
Verdict: 3 blockers, 6 warnings, 8 manual checks.
- Blockers: READ_SMS + READ_CALL_LOG in modules/apollo-security manifest (restricted SMS/Call Log group, on-demand picker is not an eligible core use); no public privacy-policy URL; no in-app "report this answer" control on Gemini output (Higgins chat / Magnum DI) — Play AI-Generated Content policy.
- Warnings: Expo template perms SYSTEM_ALERT_WINDOW + READ/WRITE_EXTERNAL_STORAGE (block via android.blockedPermissions); expo-audio default enableBackgroundPlayback adds FOREGROUND_SERVICE_MEDIA_PLAYBACK; FOREGROUND_SERVICE_MEDIA_PROJECTION declared but family-assist excluded on Android; ACCESS_FINE_LOCATION declared but never requested; EXPO_PUBLIC_BACKEND_URL not in eas.json production env (client.ts throws if missing); Gmail gmail.readonly needs Google OAuth verification + CASA.
- Passes: target/compile SDK 36 (RN 0.86), AAB production profile, root ErrorBoundary, no QUERY_ALL_PACKAGES / AccessibilityService, photo picker (no READ_MEDIA_*), RECORD_AUDIO blocked, no billing, no accounts + in-app "Delete My Apollo Data", ML Kit 16.0.1 is 16 KB-ready.


## Higgins Overview shows the full Gemini response (2026-10)
- `src/components/InvestigationView.tsx` Overview tab now renders every field Magnum DI returns: overview, explanationMarkdown, attention label + attentionReason, findings (text + basis + confidence), uncertainties, scope, sources used, and the full action instruction (no 2-line truncation). Verified live in preview; tsc, lint and 817 frontend tests pass.
- Pending user decision: Play SMS/Call Log permission approach (remove from Play build behind an off-by-default switch, "Calls Apollo screened" list, declaration drafts).

## Play restricted permissions: READ_SMS / READ_CALL_LOG removed from Play builds (2026-10)
- Removed both from `modules/apollo-security/android/src/main/AndroidManifest.xml`. `plugins/withRestrictedPhonePermissions.js` blocks them (`tools:node="remove"`) by default. Re-enabling requires `APOLLO_ANDROID_RESTRICTED_PERMISSIONS=READ_CALL_LOG|READ_SMS` plus `APOLLO_ANDROID_RESTRICTED_PERMISSIONS_APPROVAL=<Play approval ref>`; any other value fails the config load. `eas.json` production pins it to "off". `expo.extra.restrictedPhonePermissions` drives JS gating (`PhonePickers.isSupported("call_log"|"sms")`). Native `isDeclared()` refuses undeclared permissions.
- Call Guard: "Recent calls" was replaced by **Calls Apollo screened**: the native history written by `ApolloCallScreeningService` only after `respond()`, in its own try (last 50, 30 days, incoming only). Bridge: `getScreenedCalls` / `clearScreenedCalls`. UI: `src/components/ScreenedCallsList.tsx` on `/call-guard` (tap = check) and in a sheet on `/call` (tap = use number). Cleared by Delete My Apollo Data and listed in the privacy inventory.
- Text Guard / Check a message: the inbox hero and Recent messages section are hidden unless READ_SMS is declared (preview samples still show). Added a permission-free "other ways" card (Text Guard notification access, paste, screenshot, Share where the app offers it). Share copy no longer claims every app supports it (share.tsx, settings, text-guard, message-picker, backend app_knowledge).
- Docs: `/app/docs/APOLLO_PLAY_RESTRICTED_PERMISSIONS_FUTURE_DECLARATIONS.md` (NOT FOR CURRENT PLAY SUBMISSION).
- Tests: `tests/restrictedPhonePermissions.test.ts` and `tests/screenedCalls.test.ts`; updated `deviceCapabilities.test.ts`. 837/837 frontend tests and tsc pass. Prebuild verified: default build removes both permissions; the approved switch adds only the named one. The Kotlin was not compiled here (no Android SDK) — a native build is required.

## Higgins Triage → TC FlyBy → Magnum DI: the 6 routing corrections (2026-10)
- **Triage extracts every input first** (`teddy/__init__.py::_material`): submitted text/links, the text the phone read from a screenshot (`deviceExtractedText`, sent by `investigation/client.ts::investigationImageMeta`, credential-redacted, allow-listed + redacted in `privacy.ts`, stored as a derived text child in `evidence.ingest_file`), and the text layer of documents. Anything not extracted is a recorded gap (`magnum: true` only for images Magnum can read; audio/attachments/omitted pages are uncertainties). An image examined through its extracted text is marked examined.
- **One deciding test** (`teddy/decide.py::evaluate`): could Magnum DI change Apollo's finding or Higgins' action? Concern outcomes the evidence already supports stand (confirmed → likely scam (full KB pattern) → corroborated impersonation → opening → established signals). Otherwise Magnum gets only these issues: reading (an unextracted image), reasoning (a consequential request through an unverified route), relating (a register name conflict / org name merely mentioned beside another address / pattern vs official links when the request goes elsewhere). No fixed list or input type routes to Magnum; `message_analysis` is `not_needed` unless the test sends it.
- **Bare links use the same rule**: no link-only special case; a lookalike address (org name inside the host, `official._lookalike`) is a warning sign by itself for any input.
- **KB patterns**: phrase-level indicators only, negations ignored; impersonation patterns need an off-site link.
- **One outcome system** (`outcomes.py`); Teddy results: `report.compose(decision, …)` → threat / pattern / impersonation / signals / clear / undetermined; gaps → `completion: partial` + remainingEvidenceIds.
- **Magnum receives only the unresolved slice**: brief ("For Magnum DI to settle") + evidence each issue needs + anything Teddy didn't examine (`_magnum_rows(needed, settled)`).
- Admin drilldown: "Settled By" shows Not needed; new "Sent To Magnum DI" row. Triage payment requests also catch "must be paid to".
- Tests: `tests/test_teddy_routing.py` (24), full backend suite 1054 passed; tsc clean.
- Family Change Alerts: dropped at the user's request ("No family alerts") — not to be built or suggested.

## Teddy DI renamed TC FlyBy + investigator credited correctly (2026-10)
- Every display string "Teddy DI" → "TC FlyBy" (backend copy, admin portal, tests). Internal codes kept: `teddy_official|teddy_kb|teddy_search`, item ids `teddy-di-checks/brief`. Model label now `teddy-flyby`.
- Case wire now carries `answeredBy` (`repository.case_view` from `routing.answeredBy`); saved on-device investigations keep it. App credits the right investigator: `investigatorName()` in `messageVoice.ts` (TC FlyBy / Magnum DI; older results default Magnum DI). Used in InvestigationView (found / sources / history / follow-up note), follow-ups (`followUp.ts`, backend `presenter.investigation_follow_up(..., answered_by)`), threat-case timeline, patrol evidence header. In-progress spinner says "Apollo is investigating…".
- Egress allow-list now includes `sanitizationDecision`, `redactedRegions`, `sanitizationTransformations`.
- Rules each layer operates under: `/app/memory/OPERATING_RULES.md`.
- Wording that predates TC FlyBy (not changed, flagged to user): Higgins' Gemini prompt "MAGNUM DI INVESTIGATES AND SEARCHES"; gate triage docstring; check/message screen copy "Magnum DI will investigate it".

## Old wording updated + "How Apollo checks" screen (2026-10)
- Higgins' Gemini prompt (`chat.py _PERMANENT_CORE`, `app_knowledge._ROLES/_FLOWS`), Higgins' on-phone answers (`localResponder.ts`), gate-triage docstrings, presenter, and check-screen copy (check, message, email, account, text-guard, device, call-guard, CheckingModal, gate-details, patrol, ask) now name TC FlyBy first and Magnum DI only for deeper investigation. Magnum-only statements (its questions, failures, DI record, resubmit) unchanged.
- New screen `app/how-apollo-checks.tsx` (content `src/domain/howApolloChecks.ts`, test `tests/howApolloChecks.test.ts`): five roles in check order with their rules, five results with their pills, Apollo's promises. Linked from the hamburger menu ("How Apollo checks"), Higgins' destinations (frontend `appMap.ts`, backend `app_knowledge` learning routes), and Higgins' "how Apollo works" / "what is Magnum DI" answers.

## Investigator badge + "What does this mean?" link (2026-10)
- Threats list: each finished investigation shows "Settled by TC FlyBy" / "Settled by Magnum DI" (`threatCase.settledBy`, PatrolEvent `investigation_answered_by`, copied from the committed result by `investigationPatch`; no badge when not recorded — never guessed).
- "What does this mean?" (`components/OutcomeExplainerLink.tsx`) beside every investigation result: InvestigationView status card (all check screens + Ask) and the threat detail Overview (new outcome pill). Opens `/how-apollo-checks?outcome=<key>`, which scrolls to "What the results mean" and highlights that result.
- Bug fixed: when TC FlyBy settled a case before the app attached (`caseStore.attach` found it already answered), the result was never committed to the device, so the threat stayed "Investigating" and the server copy wasn't purged. Commit handshake is now `commitAnswered()` used by both paths (skips if same revision already stored).
- Seen, not fixed (pre-existing, flagged to user): one message check creates two Threats entries; dev warning "Encountered two children with the same key" on Threats/threat detail.

## 24-hour deletion, counted from when the investigation finishes (2026-10)
- User choice: the 24 hours start when the investigation is finished; a check still running is never cut off.
- `repository.start_deletion_clock()` sets `content_delete_by` (case) + `delete_by` (content chunks, upload chunks, uploads) = finish + 24h. Called on: `accept_turn` with status complete/partial (a Magnum question waiting on the person is not finished), `jobs._fail` (failed check), `cancel_job`. `create_job` calls `stop_deletion_clock()` so a follow-up turn is never cut off; the clock restarts when it finishes.
- `sweep_evidence_content()` expires (revoke + cleanup) finished cases past `content_delete_by` with no active job. MongoDB TTL index `submitted_content_24h_after_finish` on `delete_by` is the backstop. `read_bytes` never serves content past `delete_by`. The earlier "24h from arrival" `stored_at` index was removed (and dropped from the DB).
- Rule book (privacy section) updated + stamped; `test_rulebook.py` pins the wording to `EVIDENCE_RETENTION_SECONDS`.
- Tests: 6 new in `tests/test_retention_system.py`; `test_apollo_kb` Tavily-user check now looks for imports (the rule book's watch list only names the path). Full backend suite: 1076 passed (one live-API triage test is flaky under parallel load, passes alone). End-to-end: a real check finished → clock set on the case and all 3 content rows.

## Rule book in closed sections + new rule sections + deletion note on each result (2026-10)
- Rule book (`backend/content/rulebook.md`, stamped) gained sections 10–18 incl. Your data, Threats list, Websites and links, Call/Text Guard, Email and accounts, Apps and files, Device and internet, Scam alerts, Permissions. Every `## ` section starts CLOSED in the app (`src/components/RuleBookSections.tsx`, Open all / Close all, `?section=<id>` opens that one) and the admin portal (`_rule_book_sections` → `<details>`, hash opens it; styled with the portal's dark-theme vars).
- Deletion note (`src/components/ServerCopyNote.tsx`, logic `src/domain/serverCopyNote.ts`): on the threat detail Overview and InvestigationView. Shows the confirmed removal time (`confirm-commit` now returns `removedAt`, saved via `deviceStore.recordServerCopyRemoved`), else the latest leave-by time (earlier of case `expiresAt` and `contentDeleteBy`), else for older results only "have left" after 24h. "See the rule" opens the rule book at Your data.
- Verified: frontend node suite 908/908, backend rulebook/retention/KB tests pass, screenshots of closed sections, open/close all, both note wordings and the deep link.

## Times: phone's own time zone, 12-hour clock, everywhere (2026-10)
- App: `src/utils/twelveHourClock.ts` installed once in `app/_layout.tsx` makes every `toLocaleString`/`toLocaleTimeString` 12-hour ("3:16 pm", a 2-digit hour loses its leading zero; an explicit hour12/hourCycle is kept). Times already used the phone's zone; fixed the UTC leftovers: domain "Registered" date (`domainInfo.ts`), support reference date (`supportReference.ts`), the "read at" time Higgins repeats (`deviceSnapshot.ts` sends it pre-formatted local).
- Investigation report PDF: the app sends `?tzOffset=` (fallback: device's stored `tz_offset_minutes`); `pdf_export.generate_pdf(tz_offset_minutes=)` prints case/evidence/expiry/generated times local 12-hour + "All times are the phone's local time (UTC±hh:mm)". Shared helper `core/local_time.py` (label, parse, clamp, zone_label).
- Admin portal: Perth/AWST hard-coding removed. `_t()` emits `<time class="lt" datetime=UTC>`; `_LOCAL_TIME_SCRIPT` in `_shell` shows it in the admin browser's zone, 12-hour, fills `.tz-name`, and appends `?tz=<offset>` to PDF links (admin PDFs use it). "Today" cost totals still start at midnight UTC — labelled.
- Tests: `frontend/tests/twelveHourClock.test.ts`, `backend/tests/test_local_time.py`. Verified in a Perth-zoned browser (04:16 UTC → 12:16 pm).

## Fix: Scam Alerts "two children with the same key" (2026-10)
- Root cause: the FTC feed (`ftc-consumer-alerts`) puts a rendered `<a href="…">view</a>` in `<link>`, percent-encoded after the site address, so 23 items got addresses like `https://consumer.ftc.gov/%3Ca%20href%3D%22…` (open nothing), and 10 articles had two feed items sharing one broken address → duplicate React keys on `app/higgins/scams.tsx`.
- `learning_feeds._feed_link()` reads the href inside a wrapped link (escaped or percent-encoded); `repair_feed_links()` (startup, server.py) fixed feed items, candidates, Learn citations and KB entries, and kept one feed item per address. `government_alerts.snapshot()` now shows each official address once. Rule book (Scam Alerts) says so; stamped.
- Tests: `test_environment_parity.py::test_a_link_the_feed_wraps_in_page_code_reads_as_the_articles_own_address`. Verified: 0 broken URLs, 0 duplicates, no duplicate-key warning on Scam Alerts.

## Name: "Apollo SG" (2026-10)
- Every user-facing "Apollo Scam Guard" now reads "Apollo SG": About screen title (`app/about.tsx`), investigation report PDF author + footer (`services/higgins/pdf_export.py`), compliance docs (`docs/compliance/*`). Home-screen app label stays "Apollo" (`app.config.js`).

## Fix: Higgins answer scrubbed before the shared report is built (2026-10)
- `InvestigationView.tsx` and `app/patrol/[id].tsx` pass `scrubMessage(response.overview)` / `scrubMessage(response.explanationMarkdown)` into `buildReport`, so both screens dedupe and show the same cleaned text. `tests/messageGuardrails.test.ts` passes again (917/917).

## Report: the same point in other words is said once (2026-10)
- `reportSections.ts` `Said.repeats()` also drops a sentence when ¾ of its meaningful words (stop words removed, light plural stem) are in one sentence already said, with the same yes/no (a negation is never merged into its opposite). The "not taken further" reason is attached to the How sentence that gives the same reason in other words.
- TC FlyBy (`teddy/report.py`): "How Apollo checked" and the scope share one sentence (`_checked()`), and the official-threat reason uses one phrase in both places.
- Verified with a live AusPost phishing check: Ask Higgins and the Threat detail show the identical report: "What it means" once, How once with the reason once. Tests: `tests/reportSections.test.ts` (2 new), frontend 919/919, backend teddy/triage 42 pass.

## Apollo SG banner, home-screen name, Send to family, Learn article tidy (2026-10)
- Banner (`backend/logo/apollo_sg_banner.jpg`, 1200×408, cropped from the owner's artwork; constants in `core/brand.py`): tops every family email (`services/email._wrap`, loaded from public `GET /api/brand/banner.jpg`, `routers/brand.py`), the investigation PDF header (`pdf_export.generate_pdf`, replaces the old logo + "APOLLO SCAM GUARD" text) and admin portal PDFs (`admin_portal._pdf_html`). Existing family invitation/alert emails kept (owner's choice).
- Home-screen name: `app.config.js` name "Apollo SG" (needs a new build to show on a phone).
- Send to family (every threat, `src/components/ShareWithFamily.tsx`, logic `src/domain/familySummary.ts`): "Send to family in Apollo" → `POST /api/family/threats/share` (family.py) writes `shared_events` for every linked family device (either direction) + push to `/family/alert/{id}`; "Share another way" → phone share menu (text/WhatsApp/email). Summary = result, what happened, what to do, website (written example[.]com in shared text) or call number. Never the original message, links or pictures. No Apollo email for this (owner's choice). Family alert screen shows result/what happened/involved/"sent you this summary". Egress allow-list extended. Rule book §11 updated + stamped.
- Learn article (`app/higgins/learning/[slug].tsx`): removed "Think before you tap" hero card and "Key takeaways" card; Higgins avatar moved left of the title as a 72px rounded square.
- Tests: `frontend/tests/familySummary.test.ts`, `backend/tests/test_family_share_and_banner.py`. Verified: frontend 922/922, backend 42 pass, PDF banner checked, live share to a linked device in the preview.

## Play compliance clean-up, banner in app, Family Reply Notes (2026-10)
- Play: removed `ACCESS_FINE_LOCATION` (never requested), blocked `SYSTEM_ALERT_WINDOW` (`android.blockedPermissions`), `expo-audio` `enableBackgroundPlayback: false` (no mediaPlayback FGS). Verified with `expo config --type introspect`. Guard test `frontend/tests/playPermissions.test.ts`. Owner checklist for Play Console forms (VPN service, FGS systemExempted + mediaProjection, notification access disclosure, Data safety): `backend/content/play_console_declarations.md`, shown in the admin portal under **Play Store** (`/api/admin/play-console`, collapsible sections, PDF with the banner via `/api/admin/reports/play-console/pdf`).
- Banner in app: `src/components/BrandBanner.tsx` (white rounded panel, both themes) on About (replaces logo + "Apollo SG" title) and onboarding step 1 (replaces logo + eyebrow). Asset `frontend/assets/images/apollo_sg_banner.jpg`.
- Family Reply Notes: `POST/GET /api/family/shared-events/{event_id}/notes` (family.py, collection `threat_notes`; kinds calling / wait / custom ≤140; max 20 per family member per alert; push to owner → `/patrol/{event_id}`; also latest answer in `family_acks`). Family alert screen: "Send {name} a quick note" (I'm calling you now, Don't do anything yet, Write your own note + "Never send codes or passwords" hint). Owner threat detail: "From your family" card (`src/components/FamilyNotes.tsx`, refetch 30s). Ack endpoint now reaches the owner for threats that exist only on the phone (uses the shared copy's owner) and labels via `_label_of`.
- Verified in preview: owner shares → family member sends preset + own note → owner's threat shows both. Tests: frontend 925/925, backend family/banner/email 11 pass. Rule book §11 updated + stamped.

## Better Article Search (Apollo KB, word rules only, no AI) — DONE (June 2026)
- New concept-based lexical search in `backend/services/higgins/knowledge.py` (everyday-word synonyms, rarity weights, chatter removal, generic-only rule).
- Ranking order (strict, user chose "ranking rules win"): current before historical → titles that name something before vague titles → score → text-index score (`_rank`).
- Benchmark: main top1 17.9% → 83.9% (top3 89.3%); holdout top1 16.7% → 61.9%. Ranking rules cost 0 points.
- Tests: `tests/test_kb_search.py` (11 pass), baseline `tests/kb_benchmark_baseline.json`; rulebook updated + stamped.

## Learn article header (June 2026) — DONE
- `frontend/app/higgins/learning/[slug].tsx`: "Learn with Higgins" now sits centred in the top bar like "Scam Alert"; Higgins picture beside the title removed.

## Scam Alerts: where an alert applies (June 2026) — DONE
- Word rules, no AI (`scam_analysis.applies_in`): an alert counts as local to its source's country if its headline or summary names something only that country has (agency, benefit, payment service, election, state, its people). If it also names another country, it applies everywhere.
- `government_alerts._alert` adds `appliesIn` / `appliesInLabel` / `appliesInReason`. An alert local to a country other than Australia becomes overseas_only and never growls.
- Frontend: home is the phone's region setting (`homeRegion()`; GB counts as UK, EU members as EU). The "All" list hides alerts that are local to another country and shows a count of hidden ones. Each stays under its country's filter. The Home priority notice follows the same rule. The detail Source tab shows "Where it applies".
- Tests: `backend/tests/test_scam_scope.py`. Rulebook §17 updated and stamped.

## New brand logo (June 2026) — DONE
- The owner's new Apollo SG logo, with the "Better Protection…" tagline removed and a transparent background (letter counters too): `frontend/assets/images/apollo-sg-logo.png` (1200×392).
- Home header (`app/(tabs)/home.tsx`) now uses it at 58% of screen width, capped at 280.
- Splash: `assets/images/splash-logo.png`, a 1024 square with the logo kept inside Android 12's circle safe zone. `app.config.js` uses imageWidth 288 on #F5F7FA. It only shows in a new native build.
- Removed the old `apollo-scam-guard-logo.png` and `splash-image.png`.
- Setup welcome (onboarding) and About now show the new logo through `BrandBanner` (white rounded panel, padding md). Old `apollo_sg_banner.jpg` removed.
- App icon change was tried and then reverted at the user's request. `icon.png`, `adaptive-icon.png` and `favicon.png` are back to the originals.
- App display name changed to "ApolloSG" (app.config.js name). Slug, bundle IDs and scheme unchanged.

## Architecture Q&A (Jun 2026)
- Answered: where Magnum DI (coordinator.run_turn via jobs.py), TC FlyBy (teddy/search.run, first turn only) and Ask Higgins (chat.reply via /higgins/chat, Ask tab) run, and which Gemini models each uses (TEXT/TEDDY = gemini-3.1-flash-lite default; CHAT = gemini-3.8-flash via .env). No code changes.

## Gemini model per feature (Jun 2026)
- New services/higgins/model_choice.py: per-feature model stored in `gemini_model_choices` (Magnum DI, Ask Higgins); TC FlyBy always follows Magnum DI (uses the job's provider_model). Default = provider.TEXT_MODEL (gemini-3.1-flash-lite), so Ask Higgins switched to the cheaper model (GEMINI_CHAT_MODEL env is no longer read).
- Gemini Map: one-tap <select> per feature (only models whose capabilities fit: Magnum needs search+vision+json, Ask Higgins json), POST /api/admin/gemini-map/model, audit action gemini_model_change.
- Removed VISION/ADVISORY/TRIAGE/RECOVERY/CHAT/TEDDY model constants + their admin rows (Triage, System, Releases pages). Parity snapshot now reports "models".
- Fixed stale tests (iter7 pairing phone, parity keys, reusable-intel writer list); rule book updated + stamped. Full backend suite: 1229 passed.

## Triage "Limited" fixes + incomplete-check policy (Oct 2026) — DONE (awaiting owner review)
- New completeness module (backend services/triage/completeness.py, mirror frontend src/domain/triage/completeness.ts; words in triage_catalogue.json v3 "completeness"). A check Apollo needed but couldn't finish is recorded in `incomplete_checks` {check, status, failure, detail, source, at}; a No Threat with one is labelled "No threat found by available checks" (contract.outcomeLabel), never the unqualified label; wording by kind of check + failure, never provider. Not cached on the server.
- No reputation source answering → still Limited (gap carries `failure`). Safe Browsing alone down, unverified final destination (LINK-02 now not_met, not a gap), failed/stale number lookup → incomplete check.
- CB-03 no longer a gap without a claimed charge/brand (ordinary messages with a number aren't Limited).
- /call/risk-check reads the phone_risk_cache (24h) before spending an IPQS credit; live failure → last known score `freshness="stale"` + `failure`; no cache → unknown + failure. IPQS/Safe Browsing/redirect failures classified (timeout, quota_exhausted, auth_failure, rate_limited, server_error, provider_unavailable, malformed, nonexistent_domain, redirect_limit, …).
- Every number check (allow/risky/unknown) now sends telemetry; telemetry carries `incomplete` codes (egress allow-list updated); admin Triage page lists "Checks that didn't complete".
- Callback scams: 1800/1300/13 numbers without leading 0, charge claim + dispute/urgency → CB-01 (backend + messageAnalysis mirror); M16 advice no longer PayPal-only.
- Tests: backend tests/test_incomplete_checks.py, frontend tests/incompleteChecks.test.ts. Backend 1305 passed (3 pre-existing teardown errors in test_case_identity_and_limited_causes.py, same before change); frontend 1043/1043. Rule book updated + stamped. Testing agent NOT yet run (owner asked to review first).
