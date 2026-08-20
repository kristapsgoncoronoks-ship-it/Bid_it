# TODO — Task Board

Live board per the founder's charter (statuses: `Backlog` · `Planned` · `In Progress` · `Blocked` ·
`Testing` · `Review` · `Completed`). Supersedes the 2026-07-27 audit snapshot preserved at the bottom
of this file — every P0/P1/P2 item it listed as `Approved`/`Backlog` is now closed. This file is the
current source of truth; `docs/M0-exit-gate.md` and `docs/plan/plan-a/wo/` (WO-1…47) are the detailed
per-order record.

**Plan:** Plan A (evolve Bid_it) — decided 2026-07-25, reaffirmed 2026-07-28. See
`docs/plan/PLAN_A_vs_PLAN_B.md`. Plan B (`docs/plan/plan-b/GREENFIELD_plan.md`) was considered and set
aside; not executed.

---

## Milestone status

| Milestone | Theme | Status |
|---|---|---|
| **M0** | Security/correctness debt sprint | ✅ **Completed** — WO-1…11 (incl. B1.5). All 12 exit-gate criteria met. See `docs/M0-exit-gate.md`. |
| **M1** | Feature completion + independent audit | ✅ **Completed** — WO-12…46. Every named epic shipped; 18-item audit (R1–R19) closed except two decision-gated/backlog items (below). |
| **M2** | "We can take money" — billing go-live | 🔶 **In Progress** — WO-47 (quota model) + WO-48 (dogfood billing fallback) shipped. Three items still owner-blocked (below). |
| **M3** | Transport vertical phase 1 — VAT refund claim engine | 🔶 **In Progress** — WO-49 (foundation: claim grain, `is_synthetic()`, module entitlement) + WO-50 (`fuel_transactions`: typed model, idempotent ingestion, `product_group` derivation) + WO-51 (`vat_claimed_invoices`: the one-invoice-one-submission lock, R4/R5) + WO-52 (claim-line construction + note→invoice resolution, R2/R16) + WO-53 (monthly close as a durable job + locked-line protection, R31/R60/R30) + WO-54 (frozen claim lines + frozen VAT base at submission, G2.5 "the linchpin") + WO-55 (Art. 9 goods-code mapping, G2.8, R11) + WO-56 (G2.6 slice 1: period-end + Art. 17 minimum + deadline scanner, R7/R8/R9) + WO-57 (G2.6 slice 2: annual mop-up + quarterly duplicate-block, R6) + WO-58 (G2.6 slice 3: document-presence gate + receipt-control waivers, R10/R15) + WO-59 (G2.7: status lifecycle 1A→5, R12/R17) + WO-60 (G2.10 slice 1: the adjustable checklist engine, R45) + WO-61 (G3.1 slice 1: per-country supplier legal-entity registry, R21/R22) + WO-62 (G3.2 slice 1: the fuel-card parser registry + the Eurowag parser, R20) + WO-63 (G3.2 slice 2: the E100 fuel-card parser, R20's second worked example) + WO-64 (G3.2 slice 3: the Q8/Kuwait Petroleum fuel-card parser — the first multi-country/multi-currency-in-one-statement proof, `net_eur_eff`/Port-One-rebate merge explicitly deferred to the future G4.2) + WO-65 (G3.2 slice 4: the DKV fuel-card parser — the supplier-STATED-EUR money model, `fx_source="stated"` reachable from transport for the first time) + WO-66 (G3.3: the two independent validation regimes, R25 — the nine-rule capture review gate blocking registration at `statement_ingest`, and the human-typed engine tie-out halting `run_close`) + WO-67 (G3.2 slice 5: the TFC by Moya fuel-card parser — the DERIVED-NET hub-only discount money model, parser-local arithmetic over the unchanged shared contract, the first network onboarded against WO-66's live gate) + WO-68 (G3.2 slice 6: the Moeve fuel-card parser — the per-line-IVA VAT-inclusive money model at the harvested 6-dp internal precision, the cash-at-pump settlement flag as provenance-only, rate policy reused from the WO-66 gate's harvested ES (21, 10) dual entry) + WO-69 (G3.2 slice 7: the BP/Aral fuel-card parser — the PLN independently-given money model on the existing dated-ECB-rate branch, the MPP split-payment annotation as settlement-side advisory, the ORS fee line as an ordinary VAT-bearing line; **G3.2 CLOSED — all seven §5.1 networks parse deterministically**) + WO-70 (G3.3 slice 2: the anti-drift extraction baseline + `regression_check` — the harvested "flags a drift when a re-extraction moves net or vat by more than 0.02", advisory per §4.19, keyed (statement-SHA-256 × currency), recorded at first successful registration; **G3.3 CLOSED** — both R25 regimes AND the anti-drift paragraph are real) + WO-71 (G3.4: deterministic advisory post-capture checks, R26 — IBAN MOD-97 via `core/bank_id`, per-country VIES-format VAT-ID structure, the no-I/O `vies_check` stub, and the cross-entity invoice duplicate scan; every finding advisory per §4.19 — an error-severity finding never blocks, proven end to end; **G3.4 CLOSED**) + WO-72 (G3.5: receipt control — cadence × activity expectation over the harvested three-cadence set + §5.1 per-network defaults, the persisted `vat_receipt_controls` slot grid with overrides that survive re-runs, the orphan check, and the `run_control` close stage; ADVISORY per §4.19 — a `missing` slot never gates a claim/close, the blocking side stays with WO-58/WO-60; **G3.5 CLOSED**) + WO-73 (G2.11: customer lifecycle + per-country activation gates, R44 — `vat_customer_lifecycles` (prospect→pending→active→inactive) + `vat_country_activations` ((none)→requested→active), the fail-CLOSED `enforce_activation` gate in `submit_claim` after R8/before R6 per D5+§3.E, preparation surfaces deliberately ungated; F3's `country_requirements`/`country_ready_to_activate` deferred to the customer-document-store slice; **G2.11 CLOSED (core)**) + WO-74 (G2.12: evidence pack + claim workbook — `claim_pack.py`: the two filing artifacts of a FROZEN claim rendered from ONE loaded pack (workbook = Claim header + R2-grain Lines + TOTAL row equal to the frozen VAT base; evidence pack = the §3.K K6 ZIP filing bundle under the §3.M M1 vault tree with every vaulted invoice document + a SHA-256 `manifest.csv`), the identical-lines-and-totals acceptance proven structurally AND cell-for-cell; R3's FIRST blocking consumer — any synthetic frozen line refuses both artifacts (`synthetic_line_in_pack`); frozen-lines-only (`claim_not_frozen`), totals-drift refusal (`claim_totals_drift`, §4.10), missing-document-bytes refusal (`evidence_document_unavailable`); read-only, nothing persisted, no migration; **G2.12 CLOSED — the last non-decision-gated M3 service row**) + WO-75 (the R3 LOCK GATE: `claim_gates.enforce_no_synthetic_lines` — the submit-side consumer of THE one `is_synthetic()` predicate, wired into `lock.submit_claim` at the head of D5's engine-gate group per C9's `bad`-gate-first order (after R44 activation, before the R6 duplicate machinery): a claim whose materialized unfrozen lines include an UNMATCHED/INPUT/aggregate ref refuses 409 `unresolved_invoice_refs` with NOTHING mutated — no freeze, no locks, status stays `draft` — closing WO-74 design decision 8's recorded gap; **R3's full consumer set is now wired**: lock gate (hard), workbook/evidence builders (hard), checklist/stage view (advisory)) + WO-76 (transport routes slice 1 — `api/routes/transport/claims.py`, the claim lifecycle over HTTP: create/list/detail, line materialization+read, advisory checklist/stage reads, the D5 submit chain and R5 withdraw as nine thin controllers on the EXISTING WO-49 VAT_READ/VAT_WRITE/VAT_SUBMIT structural permissions; every refusal code is the service's own; tenancy parity now PROBES `vat_refund_claims`/`vat_claim_lines` over the real routes) + WO-77 (transport routes slice 2 — the ADMIN/CONFIG surfaces + the FILING ARTIFACTS: `api/routes/transport/admin.py` (status-code vocabulary, checklist-rule admin R45, cadences + the persisted receipt-control grid and its override G3.5, note→invoice-ref overrides R16, tie-out expectations R25 regime 2) + `customers.py` (the R44 lifecycle + per-country activation ladder, closing the "no route exists yet" gap that module's own docstring recorded) + six claim-scoped additions to `claims.py` (waivers R15, the manual status code R17/R12, and `GET /{id}/workbook` + `GET /{id}/evidence` — the G2.12 filing artifacts finally served, with the downloaded bytes really parsed by openpyxl/zipfile and the manifest SHA-256s re-hashed); 27 routes on the SAME existing VAT_READ/VAT_WRITE/VAT_SUBMIT permissions, every refusal the service's own code, EIGHT more tenancy-parity EXEMPT rows converted to real HTTP probes) + WO-78 (transport UI slice 1 — the VAT claims WORKSPACE: `frontend/src/pages/VatClaims.tsx` + `VatClaimDetail.tsx` over the WO-76/WO-77 routes; the D5 refusal vocabulary rendered as actionable human sentences with the raw slug shown nowhere, `below_minimum`'s override surfaced, the ADVISORY checklist that never disables Submit, the status-code ladder built from the service's own vocabulary, string-exact Decimal money with no float round-trip, the UI computing no total, and the G2.12 workbook/evidence downloads; permission-mirrored (VAT_READ/WRITE/SUBMIT) and module-gated nav; 29 Playwright specs, ZERO backend change) + WO-79 (the fuel-transaction READ surface — `services/transport/fuel.py`/`schemas/transport_fuel.py`/`api/routes/transport/fuel.py`: the FIRST code path that returns a `fuel_transactions` row, on the existing VAT_READ (TRANSPORT_READ left reserved for the derived analytics slices; identical role coverage pinned by a test), entity+period required with optional supplier/country, `period` accepting a claim reference period via the SHARED `claim_lines.period_months`, Decimal-as-string incl. `qty` and the FX quadruple, module-gate → opaque-404 entity fetch → query; `fuel_transactions` converted from a tenancy-parity EXEMPT row to a real HTTP probe; and the SUBMIT PICK-LIST it unlocks in the SPA — the `(supplier, invoice_ref, fuel_transaction_id)` lock tuple selected off the claim's own transactions instead of typed, with the typed path preserved as the fallback; WO-78 deviation 1 (a supplier column on the claim-line grain) deliberately NOT built because no unambiguous link exists on the wire) + WO-80 (transport UI slice 2 — the ADMIN/CONFIG WORKSPACE: `frontend/src/pages/VatAdmin.tsx`, one tabbed page over `admin.py` (checklist-rule admin R45 incl. its COMMITTING seed, the persisted receipt-control slot grid + override G3.5, cadences, note→invoice-ref mappings R16, tie-out expectations R25 regime 2, and the R17 status-code vocabulary as a reference panel that links to the claim rather than duplicating the VAT_SUBMIT action) + `VatCustomers.tsx` (the R44 lifecycle + per-country activation ladder — the screen the claim workspace's own `customer_not_active`/`country_not_activated` sentences finally send an operator to) + the claim-scoped R15 waiver panel on the claim detail; the advisory/gate distinction carried in the COPY and asserted as TEXT (the receipt-control board "blocks no claim, halts no close and changes no figure"; a typed tie-out expectation "stops the monthly close"); nothing the backend lacks was invented — no note-override delete (asserted by absence), no control run, no status labels; 47 new Playwright specs, ZERO backend change) shipped. G2.6 is fully closed (R6-R10, R15 all real gates); R20 is closed for Eurowag AND E100 only (Q8/DKV/TFC/Moeve/BP carry no R20 claim of their own); R25 is closed (both regimes real gates); **G3.2 is closed** (Eurowag, E100, Q8, DKV, TFC, Moeve, BP — no fuel-card network remains); **G3.3 is closed** (WO-66 + WO-70); **G3.5 is closed** (WO-72); **R44 is closed** (WO-73 — the F3 informational helper rides the future customer-document-store slice). **G2.9 is CLOSED** (WO-95 — the fee freezes with the VAT base at submission, R13/C10/C11; the 2026-08-08 owner decision settled the MODEL, and the engine FAILS CLOSED on the number nobody has decided rather than defaulting one: an org with no configured rate cannot submit, 409 `fee_rate_not_configured`. `docs/DECISIONS-NEEDED.md` §10 now records only the percentage and the minimum as open). **M3 does NOT close on it**: G2.9 was the last SERVICE row, but the ANALYTICS half of the `api/routes/transport/*` batch and the analytics UI surface are still outstanding. Remaining in M3: the rest of the ANALYTICS half of the `api/routes/transport/*` batch (`excise.py` NOW EXISTS with one — WO-91, an M5/G4.6 row delivered against this batch's own file list, closing the last name on it; **`recovery.py` and `overcharges.py` likewise** — WO-81 and WO-82 respectively — WO-81, an M5/G4.3 row delivered against this batch's own file list; `fuel.py` EXISTS but as a raw-row READ surface for the claim workspace, not the €/L analytics slice ADR-P3 names, and WO-76/WO-77/WO-79/WO-81 together leave every BUILT transport service route-reachable) and the REST of the UI surface (WO-78 shipped the claim-lifecycle workspace, WO-79 its submit pick-list and WO-80 the ADMIN/CONFIG screens — checklist rules, cadences, the receipt-control grid, note overrides, tie-out expectations, the claim-scoped waivers and the customer-lifecycle ladder — so EVERY built transport route now has a screen; what remains of the UI batch is the ANALYTICS surface, which has no backing service yet). Carried forward from WO-79/WO-80 and now FORMALLY RECORDED as `docs/DECISIONS-NEEDED.md` §11: the claim-line SUPPLIER attribution needs a BACKEND slice (`build_claim_lines` recording the supplier, and a decision on what an `UNMATCHED` multi-supplier bucket carries — it aggregates several suppliers, and a claim line's `invoice_ref` is the RESOLVED AP invoice number while a fuel transaction's is the RAW statement note, so the two cannot simply be joined) before any UI can show it honestly. 70-100 day milestone; remaining slices tracked below. |
| M4 | Payments & cash depth | `Planned` |
| **M5** | Transport vertical phase 2 — recovery intelligence | 🔶 **In Progress** — WO-81 (G4.3/R38: the cash-recovery analytics service + its read route — every claim of a refund year bucketed into the six harvested readiness states with the north-star euros, built strictly on the canonical claim services and NEVER a forked query; `TRANSPORT_READ`, the permission WO-79 reserved for exactly this derived-analytics slice; read-only, no migration, no new permission) shipped — the first M5 row, and the first backing service the analytics half of the transport route batch has ever had. WO-82 (G4.5/R41: supplier overcharge detection + claim-back — the harvested contract audit (§2.5's two term types, the two flag strings, TOLERANCE 0.005 €/L, `recover_eur = gap × litres` dropped if ≤ 0) over the validated fuel lines on the NET EUR/L final basis, plus §4.5's `detected → packaged → claimed → recovered \| rejected \| written_off` claim-back lifecycle and §2.4's booked-cash `recovered_total` — which CLOSES WO-81's deviation 1: the dashboard's `overcharges_eur` is now real, obtained by CALLING the new service rather than forking a query; two tenant tables with FORCE RLS in the same migration, both straight into real tenancy-parity probes; `TRANSPORT_READ` reads / `VAT_WRITE` writes, no permission member invented) shipped. WO-83 (G4.5/R41 + R53: R41's two send-ready ARTIFACTS — the Excel evidence packet and the formal PDF claim letter with §2.4's 30-day credit/refund demand — rendered from the ONE line source `contract_audit.audit()` already was; *"both artifacts show identical lines and totals"* proven STRUCTURALLY (one loader, one column spec, two sync renderers that cannot query) and CELL-FOR-CELL over the parsed bytes; R53's framing and §3.G G1's basis PRINTED on both from the same constants the API returns; four fail-CLOSED refusals rather than a misleading document; two downloads on the existing `TRANSPORT_READ`, no table, no migration, no new permission, no new dependency) shipped — **G4.5 is CLOSED and so is R41**. WO-84 (G4.2/R50: the off-invoice rebate merge into `net_eur_eff` + the source guard — the recon finding that `net_eur_eff` was an exact COPY of `net_eur` on every production row, so `contract_audit`'s `applied` term was identically zero and its short-discount flag over-claimed by the whole contracted rebate in a letter WO-83 had just made client-reachable; §4.2's two-tier model implemented with a litres-pro-rata allocation stated as a documented interpretation and a cumulative-then-quantize walk that loses no cent, idempotent because it always recomputes from the as-invoiced net, written by the ENGINE as the first close stage and never by a web request (§3.H), with R50's guard in both halves — an unsourced rebate refused fail-CLOSED and a DISAPPEARED rebate layer warned loudly from §2.5's history-learned 'Expected rebate' expectation; §4.15 refusing a non-EUR rebate rather than guessing a rate; one tenant table with FORCE RLS in the same migration and a real tenancy probe in the same commit) shipped — **G4.2 is CLOSED and so are R50 and R49**. WO-85 (G4.1/R51: the canonical query registry — `app/services/transport/queries.py`, six named pure org-scoped Select builders that 18 call sites over `fuel_transactions`/`vat_claim_lines` now go through, closing ONE byte-identical fork in the claim-building path (`build_claim_lines` vs `checklist._unresolved_suppliers`) and the triple re-typing of the unfrozen-claim-line cut behind the R3 gate / R10 gate / G2.5 freeze — plus its DELETE, the fourth writer; the deliverable is the STRUCTURAL guarantee: an AST scan over the transport service AND route packages refusing any rival `select()` or `<Model>.org_id` filter, with a seeded-violation self-test, demonstrated by re-introducing the real fork; R51's materialised-metric half is a documented PARTIAL HARVEST — no transport rollup table exists to drift-check; no table, no migration, no route, no SPA change, zero pre-existing tests edited) shipped — **G4.1 is CLOSED and so is R51's query-layer half**. WO-86 (transport UI slice 3 — **the recovery intelligence workspace**: `/recovery`, `/overcharges` and `/rebates` over the twelve WO-81/WO-82/WO-83/WO-84 routes that `grep -rn` proved no pixel consumed; the six readiness buckets with deadline risk kept OUTSIDE them, both honest nulls rendered as facts (a null median reads "not yet measurable" with its sample size, a non-zero `currency_mismatch_claims` gets a named notice explaining the €0.00 contribution), the claim-back ladder from a verbatim `TRANSITIONS` mirror, both artifacts downloadable with `overcharge_evidence_drift` explained as the rebate/freeze race it is, and the rebate registry stating the §3.H close boundary with NO faked preview because the backend has none; 18 refusal codes mapped, `transport.read` mirrored as its own member, money string-exact and grep-proven, ZERO backend change; 54 Playwright specs) shipped — **the analytics UI is CLOSED for every built transport route**. WO-87 (G4.7 + R52 + R53's SECOND framing: **the two overpay grains, the internal benchmark and §2.5's full expected-rebate learning loop** — the same-day *"cheapest rival"* grain (diesel only, ≥2 suppliers that day, positive deltas only, "rival" excluding the supplier itself, an exact tie proven NOT an overpay and a lone day proven to yield nothing) and the country×month *"best of your own suppliers"* grain, shown on ONE fixture to give 200.00 and 0.00 and asserted to differ — R52's *"they will not reconcile; that is correct"* made a test rather than a sentence, with the two euro fields named differently so nothing can add them; plus the median €/L rebate learned per (supplier, country) from all history that WO-84 had recorded as a deliberate partial harvest, flagging the line that quietly lost it. **R53's second framing is STRUCTURAL**: `savings.LEGAL_FRAMING` verbatim on every result, no claim vocabulary in any field name or route path (seeded-violation self-test), an AST import scan in BOTH directions proving no overpay euro can reach `overcharge.detected_eur`, and no write verb at all on the router. §4.15 is a real gate off a real recon finding — `fuel_ingest` never checks `fx_source` against `net_eur`, so a row with no established EUR basis makes the analysis REFUSE rather than shrink the comparison set. `q_savings` finally lands in the WO-85 registry as `price_comparison_transactions`, taking no `supplier` argument by design; no table, no migration, no permission member, no SPA change) shipped — **G4.7's named core is CLOSED and so is R53** (both framings now have a consumer). WO-88 (the G4.7 follow-up, R56's first ledger row: **FX provenance consistency at the ROW WRITER** — WO-87's own recon finding closed. `fuel_ingest.ingest_transaction` never compared `fx_source` with `net_eur`, and `ck_fuel_transactions_fx_source` constrained only the value domain, so a row could assert *"no rate was available"* and *"€1,400.00"* at once and every consumer below the three WO-87 analyses — claim lines, the demand-letter euro, the tie-out, the close, the recovery dashboard — summed it as a real conversion. Now refused at the one writer (fail CLOSED, before any DB read, existing `fx_rate_unavailable` code) AND by three CHECK constraints, including the value-domain one `vat_off_invoice_rebates` never had; the migration prints and REFUSES rather than guessing a rate it cannot know; six fixtures that asserted a SEK/PLN line with a EUR figure and no provenance were raised to the `ecb` provenance a real ingestion records, no assertion weakened; WO-87's analysis-boundary refusal kept as the third layer) shipped. WO-89 (the follow-up WO-88 scoped out, R56's SECOND enforcement consumer: **the WRONG-provenance rule** — WO-88 closed the euro that denies a rate was USED, this closes the euro that denies a rate was NEEDED. A non-EUR currency claiming `fx_source='eur'`, the IDENTITY provenance, was not merely representable but **stored by the production writer** — the recon probe drove `ingest_transaction` and got back a PLN line asserting €1,400.00 with "no conversion required", which WO-88's gate, WO-88's CHECK and WO-87's analysis guard all pass. Closed by a THIRD clause in the SAME predicate and a THIRD conjunct in BOTH constraints under their existing names, under a DISTINCT code `fx_provenance_inconsistent` because `fx_rate_unavailable`'s remedy — go and get the rate — is the wrong instruction here; the migration drops before it creates, so its pre-flight scans all three combinations and a failed run provably leaves the old constraint in place. `invoices`/`expense_items` ASSESSED and closed by analysis on corrected evidence — branch structure, not a nullable column — with the storage-layer gap reported as a platform finding; no fixture raised, because an unbounded sweep found none to raise) shipped. WO-90 (transport UI slice 4 — **the savings / negotiation-evidence workspace**: `/savings` over the three WO-87 `TRANSPORT_READ` GETs that `grep -rn "transport/savings" frontend/src` proved no pixel consumed. R53's SECOND framing is the governing constraint and is carried into the SPA as FOUR ASSERTED ABSENCES rather than as copy — the framing and the price basis rendered verbatim off every response, no contract-breach vocabulary in the new page, helper or wire-interface field names (word-boundary source scan with a seeded-violation self-test, so the scan can still fail), no path into the contract-breach flow in either the source or the DOM, and no mutating control at all (every button asserted to be a tab). R52 became page text: both grain labels off the wire beside the sentence that says the two totals are not expected to agree and must not be added, with the two euros proven never to appear together. `days_without_a_rival` is a named count with its reason, never a €0.00 finding. Money is the server's string end to end, grep-proven; 36 Playwright specs (171 → 207); ZERO backend change, and no refusal entry added because all four codes already had sentences) shipped — **every built transport route now has a screen again.** WO-91 (G4.6/R42 + R53's THIRD framing: **the diesel excise-duty refund — the second recoverable-cash stream, and the figure that asserts nothing**. The recon: `grep -rn "excise" backend/app` returned ONE hit — `authz.py`'s own `TRANSPORT_READ = "transport.read"  # fuel/toll analytics, excise (advisory)` — a permission reserved for a surface never built, while `api/routes/transport/__init__.py` named the missing module by file name. `excise_report` sums the period's validated DIESEL litres EXACTLY per (entity × country) off a new canonical-registry cut (deliberately NOT `price_comparison_transactions` with an extra argument: an overpay comparison is RELATIVE so scoping changes the answer, excise is ABSOLUTE so it cannot) and applies ONE `q2` to `litres/1000 × rate`. Rates are an operator override over the harvested EUR 30.00/1,000 L PLACEHOLDER (§2.4/Appendix B's own word) in one new tenant table with FORCE RLS in its creating migration, audited old→new, restricted to the harvested seven states (an eighth would assert a regime the spec records none of) and refusing a zero (the absence of the regime is expressed by holding NO rate — `rate_for` returns `None`, never `0`, so a state outside the seven yields NO ROW and is reported in `skipped_countries` with its litres and no euro at all). **The governing constraint is the eligibility limitation, and it is STRUCTURAL:** §3.L's *"Asserts NO eligibility (vehicle >=7.5t / carrier registration not modelled)"* becomes ONE server-side constant naming both conditions and denying the entitlement reading, rendered by every result shape, every schema and both workbook sheets; a REQUIRED literal `eligibility_asserted: false` that survives a UI truncating prose; the euro named `indicative_excise_eur` with no claim word anywhere in the surface, scanned against WO-87's `CLAIM_WORDS` IMPORTED rather than re-typed; and an import scan in both directions proving no excise euro can reach `overcharge.detected_eur`. Each scanner has a seeded-violation self-test. **§4.14/§4.15 land differently and are stated, not inherited:** the module reads `qty` and NO currency amount (asserted by column name), so an `fx_source='unknown'` row does NOT refuse here as it does in `savings.py` — a litre count is not arithmetic on euros. The customs packet renders from the SAME `excise_report` through ONE column spec by a sync function holding no session (asserted three ways, plus cell-for-cell over the parsed workbook) and REFUSES rather than emitting an empty document. Reads on the reserved `TRANSPORT_READ`, the two rate writes on the EXISTING `VAT_WRITE` — no permission member invented. It also fixed WO-90's reported defect and found it wider: `invalid_period` is ONE wire code raised by SEVEN services with THREE sentences, mapped in the SPA to the CLAIM instruction only, so FOUR month-shaped pages told an operator to type `2026-Q2` into a `YYYY-MM` field; split additively with a `periodShape` selector — no wire slug changed, both sentences asserted in Playwright) shipped. WO-92 (transport UI slice 5: **the excise screen** — `/excise` over WO-91's five routes, which were `curl`-only; two panels, the customs-packet download and the rate registry, and R42's acceptance line about a UI finally has a UI to be true of. The eligibility non-assertion is preserved the way the backend built it: the five framing strings render VERBATIM off the wire on the header AND inside each panel, the SPA holds none of them (a spec walks every file under `src/` proving it), `eligibility_asserted: false` is STATED rather than dropped, the vocabulary scan over the two new modules + the five new interfaces' field names is WO-87's `CLAIM_WORDS` plus `entitle` with a seeded-violation self-test, and a country with no rate held renders litres and lines and NO euro column — the €0.00 that would mean *"this state refunds you nothing"* cannot appear. 39 Playwright specs, zero backend files touched) shipped. WO-93 (**G4.4/R39: the client claim-status portal** — the first surface in this vertical written for the CLIENT rather than the operator, and the first implementation of a rule that had no row in `docs/transport/rules.md` at all. `grep -rn "claim-status\|client_status"` returned nothing in any layer, so a client either saw nothing about their own claims or saw the operator's vocabulary (`/recovery` renders the readiness slugs, `/vat-claims` renders `status_code`). The internal 1A..5 codes are now translated into §3.D's own six plain-language stages — `prep · ready · filed · awaiting · refunded · needs_attention`, verbatim, no seventh — by a TOTAL map over every code a claim can carry, with the assignment stated as a documented interpretation (the spec names the stages and the codes but never pairs them). **R39's acceptance line is entirely an absence and is enforced structurally**: no leaf string of a response EQUALS any internal code (equality, not containment — `"2"` is a code and `"2026-Q2"` is a period, and the vocabulary is IMPORTED from `status.py`), no field name in the dataclasses or schemas carries code/fee/action vocabulary, the service is AST-asserted never to read a `fee_*` column, no server-owned string reads as an instruction, and the page renders no control of any kind — each scan with a seeded-violation self-test. Dispatch is on the ENGINE STATUS FIRST, which makes the surface immune to a defect this order found and did NOT fix (§4.20): `lock.withdraw_claim` leaves a stale `status_code` against §3.D D7. Nothing is forked (`claim.list_claims` + `status.derive_stage` + `freeze.preview_vat_base`, proven by an AST scan for any rival `select()`), `vat_eur` is `Decimal | None` so a cross-currency draft states no figure rather than a false `0.00`, the plain-language labels are SERVER-owned so the SPA cannot re-word them, and the route declares the EXISTING `VAT_READ` — the permission the READ_ONLY client role already holds, chosen over `TRANSPORT_READ` on WO-79's own reservation wording because this returns claim ROWS, not portfolio aggregates. No table, no migration, no permission member) shipped — **G4.4 is CLOSED and so is R39**. WO-94 (**the two recorded defects**, each re-verified independently before a line changed and both real: §3.D **D7**'s unimplemented second half — `lock.withdraw_claim` left `status_code` populated, the defect WO-93 found, recorded and pinned a test against — now cleared at the transition that owns the withdrawal, in the same flush as the lock deletion, with the withdraw audit event's `meta` going from `None` to old→new under `set_status_code`'s own field names, plus the counted, printed, idempotent data-only backfill `f2a91c07d4e6` for rows already carrying the inconsistent pair; and backlog **N3**'s duplicated upload cap, which the sweep found was SEVEN hard-coded caps in six route modules — two of them, the 25 MB `_ATTACH_MAX` pair, DEAD behind `reject_active_content`'s 15 MB — collapsed onto the single `filesec.max_bytes()` with an AST scan and four self-tests refusing a second one. Both behaviour changes stated in the order rather than slipped in) shipped. Remaining: G4.8 (refund-estimate funnel), and G4.7's four follow-up slices, each recorded with its blocker — the peer benchmark (R55; needs a cross-entity cohort policy decision), the margin report (needs §3.H H5's `my_prices`/`wholesale_prices` tables), supplier reliability (needs an append-only `advertised_prices` table) and the six anomaly rules (R54); each will need its own UI slice when its service lands (WO-87's own three analyses got theirs in WO-90). |
| M6 | Integrations & enterprise go-live | `Planned` |

**Test suite:** 761 → 1169 → 1216 → 1247 → 1259 → 1290 → 1303 → 1309 → 1322 → 1352 → 1357 → 1369 → 1384 →
1393 → 1402 → 1435 → 1497 → 1527 → 1578 → 1610 → 1645 → 1679 → 1699 passed (+938 total, +20 this
session; the 1679 baseline was measured at WO-69's close-out), 10 skipped (pg-only, verified
separately on real Postgres), 0 known regressions, as of WO-70. WO-71: 1699 → **1718 passed, 10 skipped** (+19 new R26 tests; full suite re-run green at the WO-71 commit). WO-72: 1718 → **1744 passed, 10 skipped** (+26 new G3.5 tests; full suite re-run green at the WO-72 commit). WO-73: 1744 → **1764 passed, 10 skipped** (+20 new R44 tests; 21 pre-existing tests raised in fixture privilege via `activate_entity`, 0 assertions weakened; full suite re-run green at the WO-73 commit). WO-74: 1764 → **1785 passed, 10 skipped** (+21 new G2.12 tests; 0 pre-existing tests touched, 0 assertions weakened; full suite re-run green at the WO-74 commit). WO-75: 1785 → **1795 passed, 10 skipped** (+10 new R3 lock-gate tests; 9 pre-existing successful-submit tests raised in fixture privilege via the shared `register_documented_invoice` conftest helper (resolved+documented lines) and the G2.12 frozen-synthetic seeding switched to a direct row tamper (its own `vat_id` precedent) because the legal path now correctly refuses, 0 assertions weakened; full suite re-run green at the WO-75 commit). WO-76: 1795 → **1817 passed, 10 skipped** (+22: 20 new claim-route tests + 2 new tenancy-parity probe params (`vat_refund_claims`/`vat_claim_lines` EXEMPT→probe); 0 pre-existing tests touched, 0 assertions weakened; full suite re-run green at the WO-76 commit). WO-77: 1817 → **1853 passed, 10 skipped** (+36: 26 new admin/artifact route tests + 8 new tenancy-parity probe params + 2 new authz-coverage regression tests (the transport package's routes were outside the CI coverage net — FastAPI's lazy `include_router`; fixed and pinned) (`vat_receipt_waivers`/`vat_checklist_rules`/`vat_supplier_cadences`/`vat_receipt_controls`/`vat_note_invoice_overrides`/`fuel_tieout_expectations`/`vat_customer_lifecycles`/`vat_country_activations` EXEMPT→probe); 0 pre-existing tests touched, 0 assertions weakened; full suite re-run green at the WO-77 commit). WO-78: **1853 passed, 10 skipped — UNCHANGED** (a frontend-only order: zero backend files touched, so the backend regression net is the flat line it should be; the new coverage is 29 Playwright specs in `frontend/e2e/vat-claims.spec.ts`, taking the `npm run test:e2e` list CI runs from 31 to 60 passing). WO-79: 1853 → **1865 passed, 10 skipped** (+12: 11 new fuel-route tests + 1 new tenancy-parity probe param (`fuel_transactions` EXEMPT→probe); 0 pre-existing tests touched, 0 assertions weakened; full suite re-run green at the WO-79 commit) plus 10 new Playwright specs taking the `npm run test:e2e` list from 60 to 70 passing. WO-80: **1865 passed, 10 skipped — UNCHANGED** (a frontend-only order: zero backend files touched, so the backend regression net is again the flat line it should be; the new coverage is 47 Playwright specs — 42 in the new `frontend/e2e/vat-admin.spec.ts` plus five waiver specs on the claims spec — taking the `npm run test:e2e` list CI runs from 70 to 117 passing). WO-81: 1865 → **1900 passed, 10 skipped** (+35 new recovery-analytics tests — the six readiness buckets each proven with a claim genuinely constructed in that state, the 60-day deadline window asserted on both sides of its edge one day apart, the §4.14 cross-currency draft, the euro reconciliation against hand-computed Decimals, and the route matrix; 0 pre-existing tests touched, 0 assertions weakened; full suite re-run green at the WO-81 commit, `1900 passed, 10 skipped in 1983.85s`). Frontend untouched — no e2e run needed, the Playwright list stays at 117. WO-82: 1900 → **1971 passed, 10 skipped** (+71: 25 new contract-audit detection tests + 24 new claim-back lifecycle tests + 20 new overcharge-route tests + 2 new tenancy-parity probe params (`vat_supplier_contract_terms`/`vat_overcharge_claims`, classified as real HTTP probes in the same commit that created them — never EXEMPT); 1 pre-existing assertion RE-PINNED (the hard-coded table count in `tests/test_docs_truth.py`, 79 → 81, because this order adds two tables — a truth-up, not a weakening), 0 assertions weakened; full suite re-run green at the WO-82 commit — 1971 passed, 10 skipped in 2201s. (The first full run reported one failure, `test_readme_scale_numbers_match_the_live_tree`, purely because the README's scale line was edited WHILE that 37-minute run was in flight: pytest had already compiled the old `== 79` constant at collection and read the new README at run time. The file passes in isolation and in the clean re-run.) Postgres 16 gate re-verified on a fresh scratch cluster: `test_rls.py` (incl. the RLS/model set-equality check over the two new tables) + `test_numbering_concurrency.py` + `test_transport_lock_concurrency.py` = 6 passed on a NOSUPERUSER role, `alembic upgrade/downgrade/upgrade` clean, both tables confirmed `relrowsecurity`+`relforcerowsecurity`.) Frontend untouched — the Playwright list stays at 117. **WO-83 did not extend this line**; the tree collected 2017 tests at its commit `03c9326` (README still claimed 1981 — the collected-test figure is deliberately NOT asserted by `tests/test_docs_truth.py`, so CI was never red), so the WO-83 baseline is **2007 passed, 10 skipped** and WO-84 re-pins both figures. WO-84: 2007 → **2053 passed, 10 skipped** (+46: 31 new merge/guard tests + 14 new rebate-route tests + 1 new tenancy-parity probe param (`vat_off_invoice_rebates`, classified as a real HTTP probe in the same commit that created the table — never EXEMPT); 1 pre-existing assertion RE-PINNED (the hard-coded table count in `tests/test_docs_truth.py`, 81 → 82, because this order adds one table — a truth-up, not a weakening), 0 pre-existing tests touched, 0 assertions weakened; full suite re-run green at the WO-84 commit — `2053 passed, 10 skipped in 2085.84s`. Postgres 16 gate re-verified on a fresh scratch cluster: `test_rls.py` (incl. the RLS/model set-equality check over the new table) + `test_numbering_concurrency.py` + `test_transport_lock_concurrency.py` = 6 passed on a NOSUPERUSER role, `alembic upgrade/downgrade/upgrade` clean and `alembic check` reporting no drift, `vat_off_invoice_rebates` confirmed `relrowsecurity`+`relforcerowsecurity`.) Frontend untouched — the Playwright list stays at 117. WO-85: 2053 → **2073 passed, 10 skipped** (+20 new registry/anti-forking/equivalence tests; 0 pre-existing tests touched, 0 assertions weakened, 0 pinned docs-truth numbers moved — the order adds no table, no migration and no module to `app/services/*.py`, so `tests/test_docs_truth.py`'s counts are untouched and only README's deliberately un-asserted collected-test figure is re-pinned 2063 → 2083; full suite re-run green at the WO-85 commit — `2073 passed, 10 skipped in 1882.51s`. The transport subset alone was run green twice mid-order, 886 passed. No Postgres gate re-run was needed: this order creates no table, alters no migration and takes no lock.) Frontend untouched — the Playwright list stays at 117. WO-86: **2073 passed, 10 skipped — UNCHANGED** (a frontend-only order: zero backend files touched, so the backend regression net is the flat line it should be; the new coverage is 54 Playwright specs in the new `frontend/e2e/recovery.spec.ts`, taking the `npm run test:e2e` list CI runs from 117 to 171 passing; 0 pre-existing specs modified, 0 assertions weakened, and the only pinned docs-truth number moved is README's SPA page count 49 → 52, updated in the same commits that add the pages). WO-87: 2073 → **2135 passed, 10 skipped** (+62 new G4.7 tests — 37 analytic (the hand-computed same-day figure, the exact-tie boundary asserted as an EMPTY findings tuple and its one-cent-above twin, the lonely day, the cross-country and cross-day non-comparisons, the volume-weighted supplier price, the effective-price ordering, both sides of the §4.15 EUR-basis gate, the median-vs-mean robustness case, both sides of the 0.005 €/L rebate boundary, the R52 two-grain divergence on ONE fixture, the write-nothing column-by-column comparison and the overlapping-data tenant case), 11 R53 framing/structure tests (two of them seeded-violation self-tests) and 14 route tests; 0 pre-existing tests touched, 0 assertions weakened, and NO pinned docs-truth number moved — the order adds no table, no migration and no module to `app/services/*.py` or `app/api/routes/*.py` (`_py_module_count` globs those directories non-recursively, so a transport sub-package module does not move them), leaving only README's deliberately un-asserted collected-test figure re-pinned 2083 → 2145; full suite re-run green at the WO-87 commit — `2135 passed, 10 skipped in 1977.23s`. No Postgres gate re-run was needed: this order creates no table, alters no migration and takes no lock.) Frontend untouched — the Playwright list stays at 171. WO-88: 2135 → **2162 passed, 10 skipped** (+27 new tests — 26 FX-provenance tests (the service gate refusing each inconsistent combination with a proven-empty table and no audit event, the gate's ordering ahead of any DB read, all four legal combinations accepted plus the EUR/NULL identity carve-out and its lower-case twin, the DATABASE refusing each combination on a raw insert AND on an UPDATE that tampers a stored row, a positive control proving the constraint does not refuse everything, the rebate table's two new constraints incl. free text, and WO-87's analysis guard re-asserted unchanged) plus 1 migration test proving the pre-flight REFUSES over a seeded violating row and succeeds over a clean one; **8 pre-existing fixtures raised in privilege** — seven non-EUR lines that carried no FX provenance at all (`test_g3_3_tie_out`, `test_g2_5_freeze`, `test_g2_6_submission_gates`, `test_wo82_contract_audit`, `test_wo83_overcharge_artifacts`, `test_wo85_canonical_queries`, `test_wo81_recovery`) plus one PLN line labelled with the EUR identity provenance (`test_g3_4_capture_checks`), each now recording the `ecb` provenance a real ingestion records; **0 assertions weakened**, 0 tests deleted, and WO-87's two §4.15 tests keep their names, their `fx_rate_unavailable` assertion and their reason for existing (the writer's refusal is the new first layer; the unmodified guard is then driven by a row storage can no longer supply). The seventh fixture was found by the FULL SUITE, not by the recon — the first sweep's grep was truncated at 30 lines — and the correction is recorded in the work order rather than quietly patched. One pinned docs-truth number moved: README's Alembic revision count 86 → 87, in the same commit as the migration (the collected-test figure, deliberately un-asserted, is re-pinned 2145 → 2172). Full suite re-run green at the WO-88 commit — `2162 passed, 10 skipped in 2140.65s`. Postgres 16 gate re-verified on a fresh scratch cluster (a constraint lands): `test_rls.py` + `test_numbering_concurrency.py` + `test_transport_lock_concurrency.py` = 6 passed on a NOSUPERUSER role, `alembic upgrade/downgrade/upgrade` clean, `alembic check` reporting no drift, the three constraints confirmed in `pg_constraint` and both illegal INSERTs rejected BY NAME on real PostgreSQL as well as on SQLite.) Frontend untouched. WO-89: 2162 → **2192 passed, 10 skipped** (its own +30 wrong-provenance tests; the suite line it deferred is pinned here, measured on the WO-90 tree). WO-90: **2192 passed, 10 skipped — UNCHANGED** (a frontend-only order: zero backend files touched, so the backend regression net is the flat line it should be — `2192 passed, 10 skipped in 1774.14s (0:29:34)`, zero FAILED/ERROR lines. The new coverage is 36 Playwright specs in the new `frontend/e2e/savings.spec.ts`, taking the `npm run test:e2e` list CI runs from 171 to **207 passing**; 0 pre-existing specs modified, 0 assertions weakened, and the only pinned docs-truth number moved is README's SPA page count 52 → 53, updated in the same commit that adds the page. No Postgres gate re-run was needed: the order creates no table, alters no migration and takes no lock.) WO-91: 2192 → **2273 passed, 10 skipped** (+81 = 79 new WO-91 test functions across five files + the `vat_excise_rates` tenancy-parity probe + one scanner self-test added when a structural read was hardened; 0 pre-existing tests modified, 0 assertions weakened, 0 regressions — `2273 passed, 10 skipped in 1838.48s (0:30:38)`, zero FAILED/ERROR lines. Frontend: the `npm run test:e2e` list CI runs goes 207 → **209 passing** (+2, the two `invalid_period` refusal assertions), `npx playwright test` over every spec 234 passing. Pinned docs-truth numbers moved in the migration's own commit: README tables 82 → 83, Alembic revisions 88 → 89, and the hard-coded table literal in `tests/test_docs_truth.py`; the collected-test figure is refreshed with this line. **The Postgres gate is REQUIRED for this order and has not been run here** — `vat_excise_rates` is a new tenant table, so `tests/test_rls.py::test_rls_migration_covers_every_tenant_table` must run against a real NOSUPERUSER Postgres before merge; it passes on SQLite in the default job, which proves the model/migration set-equality but not the FORCE RLS policy itself.) WO-92: **2273 passed, 10 skipped — UNCHANGED** (a frontend-only order: zero backend files touched, so the backend regression net is the flat line it should be. Frontend: the `npm run test:e2e` list CI runs goes 209 → **248 passing** (+39, the whole of the new `frontend/e2e/excise.spec.ts`); **1 pre-existing spec assertion SCOPED, none weakened, none deleted** — `vat-claims.spec.ts`'s bare `getByText("diesel")` was unambiguous only while nothing else in the shell said "diesel", and the new "Diesel excise" nav destination (rendered on every page) made it resolve to two elements; it now names the role the target always had, `getByRole("cell", {name: "diesel"})`, which is the WO-80 decision-2 strengthening. The only pinned docs-truth number moved is README's SPA page count 53 → 54, in the same commit that adds the page. No Postgres gate re-run was needed: the order creates no table, alters no migration and takes no lock.) WO-93: 2273 → **2332 passed, 10 skipped** (+59 = 47 new test functions across three files (`test_wo93_client_status.py` 38 cases, `test_wo93_client_surface.py` 12, `test_wo93_claim_status_routes.py` 9 — the extra 12 over the function count are two parametrizations: the ten manual codes and the four invalid years); **0 pre-existing tests modified, 0 assertions weakened, 0 fixtures raised, 0 regressions** — `2332 passed, 10 skipped in 2005.49s (0:33:25)`, zero FAILED/ERROR lines. Frontend: the `npm run test:e2e` list CI runs goes 248 → **270 passing** (+22, the whole of the new `frontend/e2e/claim-status.spec.ts`); **0 pre-existing specs modified** — the new nav label "Claim status" was checked against every bare `getByText(` in the existing specs before finishing and collided with none (the WO-92 hazard, looked for rather than assumed). The only pinned docs-truth number moved is README's SPA page count 54 → 55, in the same commit that adds the page; the collected-test figure is refreshed with this line. No Postgres gate re-run was needed: the order creates no table, alters no migration and takes no lock.) WO-94: 2332 → **2353 passed, 10 skipped** (+21 = the 21 new WO-94 test functions — 8 in `tests/transport/test_wo94_withdraw_status_code.py` and 13 in `tests/test_wo94_upload_cap.py`; **0 pre-existing tests deleted, 0 fixtures raised, 0 assertions weakened, 0 regressions** — `2353 passed, 10 skipped in 1941.47s (0:32:21)`, zero FAILED/ERROR lines. ONE pre-existing test was REWRITTEN and it is the point of the order: WO-93's `test_wo93_a_withdrawn_claim_is_not_shown_and_its_stale_code_is_never_read` asserted the defect (`status_code == "2"` after a real withdrawal) as part of pinning the portal's immunity to it. It keeps its name and its meaning and now proves MORE — it asserts the fix (`status_code is None`), then writes a stale code back onto the row by hand, the shape a pre-WO-94 database still holds, and asserts the portal still shows nothing. Two pinned docs-truth numbers moved: README's Alembic revision count 89 → 90 (one commit LATE — the migration shipped in `21f31ab` without it, leaving that commit red until `00324d9`; the deviation is recorded in the work order rather than hidden) and the collected-test figure 2342 → 2363, refreshed with this line. **The Postgres gate WAS run** even though the order adds no tenant table, because a migration lands: on a fresh PostgreSQL 16 cluster under a NOSUPERUSER `appuser` role, `alembic upgrade head` / `downgrade -1` / `upgrade head` clean, `alembic check` reporting no drift, `tests/test_rls.py` + `test_numbering_concurrency.py` + `test_transport_lock_concurrency.py` = 6 passed, and the D7 backfill proven ON POSTGRES over a seeded legacy row — `withdrawn|3B` + `submitted|2` → *"clearing status_code on 1 withdrawn claim(s)"* → `withdrawn|NULL` + `submitted|2`. Frontend untouched — no SPA file references any cap (`grep -rn "15 MB\|25 MB\|MAX_UPLOAD" frontend/src frontend/e2e` is empty) and no backend wire shape changed, so the Playwright list stays at **270**.) WO-95: 2353 → **2403 passed, 10 skipped** (+50 = the 50 new WO-95 test functions — 28 in `tests/transport/test_wo95_fee_rates.py`, 16 in `test_wo95_fee_freeze.py`, 6 in `test_wo95_client_surface_with_fees.py`; **0 pre-existing tests deleted, 0 skips added, 0 assertions weakened, 0 regressions** — `2403 passed, 10 skipped in 2409.12s (0:40:09)`, zero FAILED/ERROR lines. **Fixtures were raised in THREE places and the first attempt was wrong, which is recorded rather than hidden:** `conftest.enable_transport` now seeds the org's standard contingency rate (the WO-73 `activate_entity` precedent), because `lock.submit_claim` refuses without one — but seeding it by CALLING `fee.set_rate` emitted a `transport.fee_rate_set` audit event that broke 3 pre-existing exact-audit-trail assertions (`test_wo88_fx_provenance`, `test_wo89_fx_wrong_provenance`, `test_wo91_excise_rates`), and 15 route tests in `test_wo76_claim_routes`/`test_wo77_admin_routes` 409'd because both files define their OWN `_enable_transport` and never pass through the shared helper. The full suite caught all 18; none was fixed by loosening an assertion — the conftest now seeds the ROW directly (so the audit windows those three suites describe are byte-identical) and the two route helpers call the same `seed_fee_rate`. That fixture raise is also what makes WO-93's client-surface wire scan non-vacuous: all three WO-93 files pass BYTE-FOR-BYTE UNMODIFIED (verified by `git diff`) and now run over a claim carrying a real frozen fee. Two pinned docs-truth numbers moved in the migration's own commit: README tables 83 → 84 and Alembic revisions 90 → 91, plus the hard-coded table literal in `tests/test_docs_truth.py`; the collected-test figure is refreshed with this line. **The Postgres gate WAS run** (a new tenant table lands): on a fresh PostgreSQL 16 cluster under a NOSUPERUSER `appuser` role, `alembic upgrade head` / `downgrade -1` / `upgrade head` clean, `alembic check` reporting no drift, `tests/test_rls.py` + `test_numbering_concurrency.py` + `test_transport_lock_concurrency.py` = **6 passed**, and `vat_fee_rates` confirmed `relrowsecurity`+`relforcerowsecurity` with its `tenant_isolation` policy and its partial unique index `uq_vat_fee_rates_org_standard` present in `pg_indexes`. Frontend untouched — no route or wire shape changed, so the Playwright list stays at **270**.) **WO-96: 2403 → 2403 passed, 10 skipped — UNCHANGED, and that is the entire point** (a dependency-modernisation order: every backend and frontend pin moved to its latest release, so the regression net had to be the flat line it is. The suite was run IN FULL five times — a baseline at `6a3a43b` (`2403 passed, 10 skipped in 2037.98s (0:33:57)`, which independently confirmed the figure WO-95 reported and `docs/RELEASE-READINESS.md` carried as attributed), then once per stage that touches backend: Stage A patches/minors (`1979.76s`), Stage C reportlab 4.2.5→5.0.0 (`1893.43s`), Stage D pypdf 5.1.0→6.15.0 (`1897.80s`), each `2403 passed, 10 skipped` with zero FAILED/ERROR lines. **0 tests added, 0 deleted, 0 skipped, 0 assertions weakened, 0 fixtures raised** — a bump is not licence to touch a test, and none was touched. Frontend: `npm run test:e2e` **270 passing** after Stage A, after Stage B (vite 6→8 + `@vitejs/plugin-react` 4→6) and after Stage E (react/react-dom/both `@types` 18→19), the same 270 throughout; React 19 needed no application-code change across the 55 SPA pages and `tsc --noEmit` was clean first time. The document renderers were additionally verified by PARSING generated output rather than trusting green — page geometry, extracted text in order, the money edge cases `1234567.89 / 0.01 / -100.00 / 0.00 / 2.005`, and the `factur-x.xml` attachment bytes all identical before and after, because those documents reach a tax authority and a supplier. **The Postgres gate WAS run** at Stage A, C and D even though the order adds no table and no migration, because `alembic` itself moved a minor (1.18.5 → 1.19.1): on PostgreSQL 16.13 under a NOSUPERUSER `appuser` role, `alembic upgrade head` clean, `alembic check` reporting no drift, single head `d4c7b1e93f27`, and `test_rls.py` + `test_numbering_concurrency.py` + `test_transport_lock_concurrency.py` = **6 passed**. One pinned docs-truth number moved: README's stack line React 18 → 19, in the same commit that ships react 19. One recorded environment finding, not a defect: the first Stage C gate run failed `test_rls_users_visibility_is_membership_driven` on a duplicate `ix_users_email` left by the Stage A run in the scratch cluster being REUSED — CI provisions a fresh service container per job and never sees it; fixed by recreating the database, no test touched.)

---

## Project profitability — phase 1 shipped 2026-08-16 (PP-1)

Design: [`docs/design/project-profitability.md`](docs/design/project-profitability.md)
— INDUSTRY-NEUTRAL by owner requirement (industry words in examples only; the
e2e suite literally greps the rendered page against the guard list). The loop,
for any project-shaped business: open a project → attach the contract → issue
sales invoices under it → allocate supplier/subcontractor invoices and expenses
→ book wage/equipment cost lines → read revenue − costs.

- [x] **The revenue link** — `issued_invoices.project_id` (composite tenant FK,
  SET NULL — deleting a project never takes legal documents with it). Set in
  `build_invoice` so the draft-edit copy path carries it; a credit note INHERITS
  its parent's project (seed-verified: removing the inheritance turns the test
  red) so reversals land where the revenue did.
- [x] **The P&L** — `project_profit.pnl`, NET EUR, basis STATED ON THE WIRE
  (`basis: net_eur_live`) and rendered from the wire, so the phase-2 freeze
  changes the copy by changing the field. What counts is pinned test by test:
  drafts are not revenue (seed-verified), unapproved expense reports are not
  costs, binned invoices leave the P&L and return on restore — the recycle bin
  composes for free via the central guard.
- [x] **Manual cost lines** — `project_cost_entries` (wages/per_diem/equipment/
  other, a closed generic set). NOT payroll, by owner decision. Negative
  corrections allowed, zero refused; deletion audits WHAT was removed.
  Mutations are INVOICE_WRITE (bookkeeping), not SETTINGS_MANAGE (org config) —
  pinned by a test.
- [x] **The contract on the project** — `project_documents` + upload/download
  (attachment + nosniff), its own object-store prefix. The e-sign seam's slot.
- [x] **Tenancy, all three layers in one commit** — TENANT_MODELS (83), two
  real parity probes (cross-tenant list/fetch/delete/download all opaque), and
  ENABLE+FORCE RLS in migration `e2b4d6f8a0c2` — the archived_invoices lesson
  applied rather than relearned.
- [x] **Screens** — `/projects/:id` (P&L card + cost-line form + contract
  panel), project picker on the issue form, project codes on `/cost-objects`
  link through. 5 e2e specs; the full browser suite is green at 339.

- [x] **Phase 2 shipped (same day, PP-2):** line-level + % allocation under the
  precedence rule (line > split > whole-invoice) via ONE write
  (`PUT /invoices/{id}/allocation` — all three levels at once, so they can
  never contradict), cent-exact with the rounding residue on the largest
  PERCENT — the drift test (10.00 at 33.33/33.33/33.34) caught the first
  implementation putting it on the largest rounded share, which degenerates to
  an arbitrary id tiebreak when all shares round equal. The close-time FREEZE:
  closing a project stores its P&L in the same transaction as the transition
  (`costing.update` hook, `pnl_frozen` in the audit meta); late documents
  surface as labelled `adjustments` deltas next to the frozen figure; reopening
  discards the snapshot, audited. `basis` moves live→frozen on the wire and the
  screen follows the field. Margin + profit columns on the projects list
  (`/masters/projects-pnl-summary`). Seeds: residue rule removed → red (after
  the drift case was added — the 60/40 case stayed green, a lesson recorded in
  the test's docstring); freeze bypassed → red.

- [x] **Phase 2 UI closed (PP-2b):** the allocation editor on the invoice
  detail screen — one card, one write (whole-invoice project + % split rows in
  a single PUT), hidden entirely for orgs that never opened a project. The GET
  answers in exactly the shape the PUT accepts, pinned by a round-trip test, so
  the editor cannot corrupt an allocation it didn't touch. Client-side the
  sum-to-100 rule is guidance (disabled Save + amber total); the server remains
  the control.
- [x] **Phase 4 shipped (PP-4):** offers/estimates + the invoicing plan, per
  §5a and the owner's answers. Offers are VERSIONABLE (a revision is a new row,
  the prior flips to superseded — history survives every edit; seed-verified
  both ways), numbering is CLIENT-SET (`organizations.offer_prefix`, platform
  enforces per-org uniqueness only), and ACCEPTANCE seeds the invoicing plan —
  but only an EMPTY one (a hand-shaped plan is never rewritten; seed-verified).
  The plan tracks contracted vs. actually-issued using the SAME revenue figure
  the P&L shows (pinned: the two screens cannot disagree), and the P&L gains
  `estimated_revenue` (latest accepted offer) — estimated-vs-actual readable
  from day one. Two new tenant tables with probes + FORCE RLS in the same
  commit. ProjectDetail gains Offers and Invoicing-plan cards. Small follow-up:
  an org-settings surface for `offer_prefix` (service honors it; only the
  editor UI is missing).

**PP-5a (2026-08-20) — dynamic document templates SHIPPED** (§5a machinery):
org-less `platform_templates` masters (operator-writable; demo contract/
acceptance/offer-cover texts seed on first read and state they are examples,
not legal advice — the lawyer's texts replace them by key with zero code
change) + per-org `org_templates` saved versions (FORCE RLS + parity probe in
the same commit). A client adjusts a master into a FROZEN own copy — platform
edits never reach saved versions — keeps multiple named versions, and picks
one when generating; `{{token}}` render fills issuer/customer/project/offer/
plan and leaves unknown tokens visibly unreplaced; generate-document renders
to PDF and files it with the project's documents. Templates page + picker on
ProjectDetail. Wording changes need SETTINGS_MANAGE.

Phase 3+: module-conditional recovered-VAT line, e-sign, budget-vs-actual;
phase 5 remainder per §5a (acceptance & handover as a project state,
adjustable final invoicing; the lawyer's standardized texts drop into the
shipped template machinery when they arrive).

**The FULL lifecycle — owner vision 2026-08-16, recorded so it is not lost**
(design: `docs/design/project-profitability.md` §5a): open project →
**offer/estimate** → contract → invoicing per contract (an **invoicing plan**
tracked against actually-issued) → project costs → **acceptance & handover**
(a countersigned acceptance document, generated from a template) → **final
invoicing** (the remainder of the contracted sum, gated on acceptance) →
close → frozen P&L. Plus **standardized contract + acceptance templates**
(per-org adaptable, prefilled from the project). Owner answers, same day:
the **lawyer will produce the standardized texts** (machinery builds against
per-org custom templates meanwhile); **final invoicing is ADJUSTABLE** —
computed remainder ± explicit labelled adjustment lines for unexpected costs/
damages either way, reconciling instead of hiding; **offer numbering is
client-configurable** (per-org scheme, platform enforces only uniqueness).
Sequenced as phases 4 (offer + invoicing plan) and 5 (acceptance + templates
+ final invoice); nothing in phases 1–3 needs rework — the stages slot in
front of and behind the loop.

---

## Pilot status — 2026-08-15 (updates the 2026-08-12 entry below)

Three of that entry's four gates stay closed. What changed since:

**Verified at `75befc4`** (executed, not recalled): backend suite **2633 passed,
10 skipped** · ruff clean · ruff format clean · mypy clean over **339** files ·
single head `a4d7e0c16b93` · browser suite **293 passed** at `1bbb154` — the
consent dialog changed after that run and has NOT been re-verified in a browser.

**Deletion is now a complete, audited chain** (next section). That closes a real
diligence finding: "a clerk clicked Delete and the record was gone" no longer
describes this product.

**Still open for the pilot, owner-side — re-checked, not recalled:**
- [ ] **Run the deploy.** Production is still `15116e1`. Nothing from 2026-08-12
      is live, and nothing from 2026-08-14/15 either — that is now **56 commits
      and 7 migrations** of undeployed work, including the whole deletion chain.
- [ ] **Set the fee rate once deployed** — the VALUE is decided (15% / €50,
      2026-08-15) and the HTTP surface exists; it is one call in the runbook.
- [ ] **GitHub Actions runners (billing).** Confirmed still dead: no run since
      2026-08-12, and that run's jobs each died in 2-10 seconds with no logs.
      Every push since — twelve — has triggered nothing.
- [ ] **One real supplier statement, redacted**, for a first real-data pass.
      Unchanged and still the highest-value open item on this page. The ~250
      tests added on 14/15 August do not move it: they are self-authored over
      fixtures, exactly like the 2445 that passed while four money defects sat in
      the code.

**Engineering, not pilot-blocking, added 2026-08-15:**
- [ ] Deploy runbook needs regenerating — `DEPLOY-RUNBOOK-2026-08-12.md` predates
      seven migrations.
- [ ] `main` is behind again: buildable (repaired at `ec93e4b`) but 56 commits
      back.

---

## Deletion, the recycle bin, and the platform archive — 2026-08-14→15

Not a numbered WO. Design and owner decisions:
[`docs/design/deletion-and-archive.md`](docs/design/deletion-and-archive.md),
[`docs/design/platform-archive.md`](docs/design/platform-archive.md).

Deleting an invoice used to destroy the row outright. It is now a chain, every
step audited and every destructive step fenced:

> delete → recycle bin, 30 days, restorable by admin/owner → purge → platform
> archive, 3 years, readable and downloadable by the company owner → expiry

- [x] **Soft delete + one central hiding rule** — enforced through the existing
  `do_orm_execute` hook so no query can forget it. Proven to cover column-only
  selects, aggregates AND explicit-ON joins over line items; that last shape
  decided whether every category, budget and benchmark figure would have been
  silently wrong for 30 days.
- [x] **Delete becomes reversible** — Trash screen, restore behind a separate
  `INVOICE_RESTORE` permission (admin/owner only, narrower than who may delete).
- [x] **Server-enforced consent gate** — a client may delete a paid or approved
  invoice (owner decision) but only having been warned every time, the warning
  VERSIONED and frozen verbatim into the audit event.
- [x] **30-day purge** — refuses under a legal hold, batched, org-scoped on the
  DELETE itself.
- [x] **Multi-select delete** — held back until deletion was reversible.
- [x] **Platform archive** — sealed `archived_invoices`, written in the SAME
  transaction as the delete so a record cannot be destroyed without being
  archived. Record + source PDF. Client's own company owner reads it. Under RLS.
- [x] **P0/P1 defects found by an 8-role review of the above, and fixed** —
  including a purge that would have raised on every transport tenant daily
  forever (composite-FK `SET NULL` nulling a NOT NULL `org_id`), a Trash screen
  that stated a false total, a silent single-delete, and a plan-quota bypass the
  bin had made free and repeatable.

**In the same spirit as the 2026-08-12 lesson:** the review found two P0s that
2633 passing tests did not. Both were found by reading code against intent, not
by running it. The suite still catches a wrong shape, not a wrong figure.

- [x] **Archive client-facing screen** (2026-08-16) — `/invoices/archive`,
  linked from Deleted invoices, which is the only route a client has to it. No
  restore, and it says so rather than leaving people hunting. Both windows
  (`retention_years`, `expiry_notice_days`) are published by the server so the
  screen cannot promise a period the archive does not keep. 14 e2e specs — one
  of which was proving nothing until a seeded violation exposed it: a negative
  assertion with no positive anchor passed against a page that had not finished
  its first fetch, and went on passing with the notice window deliberately
  hardcoded.

- [x] **Archive expiry purge** (2026-08-16, P0-1 of the bug scan) — until this,
  `expires_at` was stamped, published and printed while NOTHING enforced it:
  "kept for three years, then removed" was true only up to the comma, and the
  document bytes were retained forever. `archive.purge_expired` + the
  `ARCHIVE_PURGE` daily job: legal-hold refusal, batched, org re-asserted on the
  DELETE, audit event carrying the destroyed records, and byte collection AFTER
  the commit — only for shas referenced by no surviving archive row and no live
  invoice's extraction run (content-addressed store, so reference-counted).
  Seed record: org predicate off the DELETE alone stays green (the org-scoped
  SELECT is the redundant second layer — that is the belt holding without the
  braces, recorded here so nobody mistakes it for a vacuous test); both layers
  off goes red; the live-reference check removed goes red; the schedule unwired
  goes red.

- [x] **Pre-expiry notice + the paid retention extension** (2026-08-16, the
  owner's chosen next build) — `archive.send_expiry_notices` + the daily
  `ARCHIVE_NOTICE` job for every tenant: ONE email per owner covering every
  un-noticed record inside the 60-day window (never one per record), stamped so
  it repeats never, and an undeliverable notice stays visibly OWED — rows
  unstamped, `skipped_no_email` audited — instead of being marked done. The
  extension is `organizations.archive_retention_years`, operator-granted over
  `PATCH /platform/tenants/{id}` (billing wires up later): granting it REACHES
  BACK — existing rows re-stamped to `archived_at + 365×years` and their notice
  stamp cleared so a fresh notice precedes the new expiry — because an extension
  bought after the notice must protect the records the notice was about.
  Extend-only in both directions: a below-included override is ignored, clearing
  re-stamps nothing. Both seeds went red (stamping undeliverable notices;
  forgetting existing rows), 7 tests.

**Not built:** `expiring_soon()`
      exists and is tested; the notification and billing do not. The more
      important of the two: three years is likely BELOW the Baltic statutory
      floor, so a client who does not extend loses records they were obliged to
      keep, and the notice is what makes that survivable.
- [ ] **Extend the bin to other entities** (owner-approved). Expenses, expense
      reports, issued-invoice attachments and recurring schedules are still
      destroyed on click — one with no confirmation at all.
- [ ] **Real invoice→VAT-claim link, then refuse those deletes**
      (owner-approved). Today an invoice in a FILED claim can be bulk-deleted
      with no warning; the only existing link is a heuristic string match.

**Owner decisions 2026-08-15**, recorded in `docs/DECISIONS-NEEDED.md`: purge
stays on · bin extends to all entities · add the claim link then refuse ·
archive first · archive keeps record + document · archive read = the client's own
company owner, plus platform staff under a named, time-boxed, reason-logged grant
· **3 years included, longer is a PAID extension.**

**Owner decisions 2026-08-16** (the P0-2 reconciliation, built same day —
`tests/test_retention_chain.py`): retention purge routes invoices THROUGH the
chain (soft-delete into the bin as "retention policy", then the ordinary
30-days→archive→3-years pipeline; expenses/email keep hard delete until the bin
learns them) · the archive keeps its FULL 3 years regardless of a shorter tenant
policy — the platform's compliance backstop, to be stated in the DPA · ex-client
gets pre-expiry notices at the last owner address + one-time export on request ·
next build = the pre-expiry notice + paid extension.

---

## Pilot status — 2026-08-12

**Scope decided: a SUPERVISED PILOT with named clients**, not an open beta
(`docs/DECISIONS-NEEDED.md`). Four gates; three are closed.

| Gate | State |
|---|---|
| The four money defects | **closed** — `8fb0333` (camt.053), `4cfc365` (penalty double-billing + cross-currency sum), `4b47c4a` (foreign bank line cannot settle a EUR record) |
| Restore drill (R14) | **passed** — `scripts/restore_drill.sh`, evidence in `RELEASE-READINESS.md` §3.4 |
| Fee rate configurable | **surface built** — `set_rate` had NO HTTP route, so the `fee_rate_not_configured` gate could only be opened from a Python shell. `GET/PUT/DELETE /api/v1/transport/fee-rates` closes that. The VALUE (15% / €50) is one call after deploy, in the runbook |
| Merged to `main` | **done** — `ec93e4b`, clean fast-forward, and it repaired `main`'s build |

**The lesson from the four defects, worth keeping:** every one passed 2445
tests. The suite catches a wrong *shape*, not a wrong *figure*. All four were
found by running the code on realistic input and reading the output — and three
times a first-draft test passed against the unfixed code, so each fix was only
trusted after watching the test go red with the fix stashed.

**Still open for the pilot, owner-side:**
- [ ] Run the deploy — production is still `15116e1`, nothing from 2026-08-12 is live.
- [ ] Set the fee rate once deployed (`PUT /api/v1/transport/fee-rates`).
- [ ] GitHub Actions runners (billing) — still no independent verification.
- [ ] One real supplier statement / invoice, redacted, for a first real-data pass.

**Still open, engineering, NOT pilot-blocking:**
- [ ] The document-bytes volume has not been restore-tested (only the database has).
- [ ] Sign-in form labels are not programmatically associated (`Login.tsx` — no
      `htmlFor`/`id`), so a screen reader announces unlabelled fields.
- [ ] MT940 unsupported; the unsupported-format message omits XML, which IS supported.
- [ ] Vite 8 first-load payload roughly doubled (perf, not correctness).
- [ ] EU statutory late-payment interest (2011/7/EU: ECB + 8pp, €40 Art. 6) is
      deliberately NOT modelled — we under-claim. Reopen before the open beta.

---

## Release status — 2026-08-09

**Verdict: release-PREPARED, not released.** Ready for a supervised pilot with
a client who knows they are one; not ready for self-serve. Full gate,
evidence and criteria: [`docs/RELEASE-READINESS.md`](docs/RELEASE-READINESS.md).

**Verified at `ce37708`** (executed, not recalled): backend suite **2403 passed,
10 skipped** · browser suite 270 passed · ruff clean · 563 files formatted ·
mypy clean over 328 files · single head `d4c7b1e93f27` · `alembic check` no
drift on real Postgres 16 · Postgres-only gates (RLS + numbering + lock
concurrency) 6 passed under a NOSUPERUSER role · pii-scan clean · every backend
and frontend dependency at latest, `npm audit` 0 vulnerabilities.

The backend re-run WO-95 left in flight **completed and confirmed 2403/10**, and
WO-96 then held that figure across four major-version bumps.

**Blocking release, none of it engineering's to clear:**
- [ ] **GitHub Actions has no runners** — every job fails in ~1s with
  `runner_id: 0` and no logs (account/quota condition). Consequence: no
  independent verification of anything, no routine Postgres gate, no docker
  build per change. **This alone disqualifies a release.**
- [ ] **Branch never merged; `main` cannot build** until the `manualChunks`
  fix reaches it.
- [ ] **No fee rate configured** — by WO-95's fail-closed design, no claim can
  be filed until the percentage and minimum are typed.
- [ ] **R14 backup/restore** — still decision-gated. No client data should
  enter a system whose restore has never been rehearsed.
- [ ] **Nothing validated against real data.** Every test is self-authored
  over fixtures derived from a harvested spec: they prove internal
  consistency, not correctness. WO-84 is the evidence — `net_eur_eff` was
  silently identical to `net_eur`, so the platform demanded money from
  suppliers who had already paid, and every test passed. **A shadow run (one
  real client, one real quarter, reconciled against what was actually filed
  and recovered) is the cheapest way to find the next one.**

---

## New work created by the 2026-08-08 decisions

Recorded in `docs/DECISIONS-NEEDED.md` → "Decisions taken". Two answers went
beyond the question and opened work rather than closing it.

- [ ] **Supplier reliability rating** (from §12) — owner-specified criteria:
  overcharges, exchange-rate treatment, and lines charged that were never
  agreed. This is G4.7's deferred reliability board arriving with its spec.
  Needs a design pass before code: each criterion's contribution, the window,
  and a presentation that reads as evidence rather than a verdict on a
  counterparty.
- [ ] **Partial rejection of a VAT claim** (from §13) — does not exist;
  `status.py` names the "decision received"/"rejected" transitions as unbuilt
  and entangled with G2.9. `fee.py` documents the seam it would use
  (recompute over a reduced base at the *frozen* rate).
- [ ] **§11 supplier list** on an `UNMATCHED` claim line — small, specified,
  serves the preparation surface only (these lines are already refused at
  submit by R3).
- [ ] **§12 explicit `ignore`** on a detected overcharge — audited, so a
  breach nobody intends to chase can leave the worklist without pretending it
  was written off.
- [ ] **Still open from the owner:** the fee percentage and minimum; and
  whether §13's freeze-until-partial-rejection applies to supplier overcharge
  claim-backs or only to VAT claims.

---

## Dependency & CI health (out-of-band, 2026-08-08)

The eight Dependabot PRs were merged to `main` at the owner's direction. Five landed
(both minor/patch groups, reportlab 5, pypdf 6, vite 8); three conflicted. Two of the
conflicted three — react and react-dom — are a MATCHED PAIR and must land together or
not at all. What that episode taught, twice over:

- [x] **`main`'s frontend was un-installable** — vite 8 landed while `@vitejs/plugin-react`
  stayed on 4, whose peer range stops at vite 7, so `npm ci` failed repo-wide (every
  frontend job, on every branch). Fixed by merging the rebased #32 (plugin-react 6.0.5).
- [x] **The build then failed underneath it** (`manualChunks is not a function`): vite 8
  bundles with rolldown, which accepts only the FUNCTION form. Fixed portably in
  `frontend/vite.config.ts` (commit `9540ab3`) — one shape that builds on rollup AND
  rolldown, chunk boundaries unchanged (vendor/recharts still emit separately, verified
  under Vite 6 here and Vite 8 against a `main` checkout).
- [x] **`@playwright/test` and the CI container image are a matched pair too** — the group
  bump moved the library to 1.62.1 while `frontend-e2e` stayed pinned to
  `v1.61.1-jammy`. The skew failed the specs in the most misleading way available (five
  passes, then a wall of "did not run"). Fixed to `v1.62.1-jammy` **plus a guard step**
  that compares the resolved library against the tag parsed out of `ci.yml` and fails
  with an explanation (commit `3c651f1`). A version pinned in two files WILL drift; the
  guard makes the next drift a one-line message instead of an investigation.
- [ ] **`main` still cannot build** until the `manualChunks` fix reaches it — either this
  branch merges, or that single edit is applied to `main` directly. `npm ci` works there
  now; `npm run build` does not.
- [x] **react / react-dom (#28, #27)** — landed together on this branch by **WO-96 Stage E**
  (`0377b66`), with both `@types` packages in the same commit. React 19 across the 55 SPA
  pages needed **no application code change**: `main.tsx` already used `createRoot`, and the
  SPA carried no `propTypes`/`defaultProps`, no string refs, no `findDOMNode`, no bare
  `useRef()` and no `JSX.*` namespace use. Still has to reach `main`.

All eight PR checks are green at `3c651f1` — backend, frontend, frontend-e2e,
docker-build, lint, pii-scan and postgres.

### WO-96 — every dependency to latest (2026-08-11)

**Completed.** `docs/plan/plan-a/wo/WO-96-dependency-modernisation.md`. Staged in five
commits, never one sweep — patches and minors first, then **each major alone with its own
full verification**, so a regression found later reverts exactly one library:

| Stage | Bump | Commit |
|---|---|---|
| A | all patches/minors, both halves | `9af0cfd` |
| B | vite 6→8 **+** `@vitejs/plugin-react` 4→6 (pair) | `974579b` |
| E | react + react-dom + both `@types` 18→19 (quartet) | `0377b66` |
| C | reportlab 4.2.5→5.0.0 | `80abd4c` |
| D | pypdf 5.1.0→6.15.0 | `ce37708` |

Backend **2403 passed / 10 skipped** and browser **270 passed** before and after **every**
stage. No test weakened, skipped or deleted; no fixture touched. Every dependency in
`requirements.txt`, `requirements-dev.txt` and `package.json` is now at its latest release.

- [x] **The Playwright pair was ALREADY SKEWED on this branch** and is now closed. `ci.yml`
  pinned `v1.62.1-jammy` while `package.json` pinned `^1.61.1`, so the guard added at
  `3c651f1` to catch exactly this drift was itself red here — only the `ci.yml` half of that
  fix ever arrived. Reproduced locally as `lib=1.61.1 img=1.62.1 GUARD_FAIL`, now matched.
  The lesson holds and got a second demonstration inside a week: **a version pinned in two
  files WILL drift**, and half a fix travels between branches as easily as a whole one.
- [x] **`npm audit` went from 4 vulnerabilities (1 moderate, 3 high) to 0**, carried by the
  axios and postcss bumps — unlooked-for, and on its own worth the exercise.
- [ ] **OPEN — the SPA's first-load payload roughly doubled under Vite 8.** Rolldown
  reassigns the shared React runtime whatever `manualChunks` asks, so the 416 kB `recharts`
  chunk is now `modulepreload`ed on **every** page; critical-path JS **~329 kB → 772,780 B**.
  Correctness is unaffected and all 270 specs pass — this is exactly the "behaviour change
  that passes the tests" class. Two traps recorded with it: total emitted bytes *fell* 1.1%
  (so an aggregate check scores it an improvement), and React 19 restored the chunk *sizes*
  without changing the preload set (so it reads fixed and is not). Needs its own order; the
  only levers are rolldown-specific and would destroy the one-config-builds-on-either-bundler
  property bought at `9540ab3`. Measurements in the WO and `docs/RELEASE-READINESS.md` §3.8.
- [ ] **DEFERRED — `stripe` stays at the commented `11.4.1`** (latest 15.5.0). It is
  commented out, uninstalled and imported lazily only when a Stripe secret key is set, so no
  test in the suite can execute it. Moving that number would be moving a pin on faith, which
  is the one thing this order forbade. Owned by ADR-0013 and the billing go-live.

---

### WO-97 — the issued-invoice PDF, redesigned (2026-08-11)

**Completed.** `docs/plan/plan-a/wo/WO-97-invoice-layout.md`, design record
`docs/design/invoice-layout.md`, code `5de37fa`. Three complete A4 candidates were rendered
from one synthetic dataset; the owner chose **A, the refined ledger**, and A was then built
into the production renderer — not shipped as the prototype, which had a real defect (a
reportlab cell holding a `Paragraph` ignores the table's `ALIGN`, so every figure came out
flush left).

Preceded by `c1e5ee8`: the **Factur-X claim can no longer lie**. `build_pdf` printed
"EN 16931 · Factur-X XML embedded" unconditionally and attached an empty `factur-x.xml`, so a
PDF carrying no structured data asserted that it did. Production always supplies real CII, so
the case was latent — `tests/test_invoice_pdf_facturx_claim.py` keeps it that way. The
empty-attachment test was **rewritten before it landed**: its first form asserted only that
the payload was truthy, which the unfixed code passed with `b"\n"`. It now requires the
attachment to parse as XML. Same vacuous-assertion pattern this programme criticised in WO-95
an hour earlier; caught here only by stashing the fix and watching the test still pass.

- [x] **The totals can no longer be orphaned from the lines they total.** `KeepTogether`
  prevents a block being *split*; it does not bind it to the table above. At 30 lines the
  totals landed alone on page 3. They are now the final column-spanning row of the line table
  with a `NOSPLIT` over *(last line, totals)*. `rowSplitRange` looks right and is not —
  reportlab drops it from the continuation table after the first split.
- [x] **Verified by rendering, not only by asserting.** Every assertion in
  `test_invoice_pdf_layout.py` passes on a page whose columns collide; text extraction cannot
  see layout. Seven cases were rasterised and looked at: simple, three VAT rates, 28 lines
  across three pages, credit note, reverse-charge exemption, seven-figure + negative amounts,
  no PO.
- [x] **A credit note no longer asks to be paid** (`b6d12db`). It printed the collection IBAN
  under a "Payment" heading beside the seller's `payment_instructions` — free text written for
  invoices, in practice a due-in-N-days demand — on a document that is not payable. Only the
  reference wording had been made conditional, which made the rest read as deliberate. Now:
  `Credit` / *No payment is due on this document.* / the reference, and **no guess** at whether
  the credit is offset or refunded, since this layer does not know.
  **Correction to the first report of this:** the `DUE` date was also flagged and was **not** a
  product defect — `issued_service` sets `due_date=None` on every credit note and the renderer
  already drops the column. It appeared only because the throwaway render harness invented a
  due date. Rendering a case the product cannot produce is a way to report a bug that is not
  there; the fix is to build the stress case from the shape the service actually writes.
- [ ] **OPEN — the corrected invoice's number is not printed on a credit note.** Art. 219
  treats a corrective document as referring to the original. `build_pdf` receives
  `corrected_invoice_id` but not the corrected invoice; wiring a DB read into a pure renderer
  is a signature change. Recorded in `docs/design/invoice-layout.md` §5 with the other four
  deliberate gaps.

---

## M3 — In Progress

- [x] **WO-49** — `Completed` — M3 opener: the transport-vertical foundation. `app/models/transport/
  vat_claim.py` (`VatRefundClaim`/`VatRefundClaimLine`, the `(org, entity, refund_country, ref_period)`
  claim grain, R1 — `entity_id` reuses the existing `issuer_profiles` registry rather than a new
  legal-entity table); `app/services/transport/claim_gates.py::is_synthetic()` (R3, the ONE predicate
  every future lock/checklist/readiness/workbook gate must import — harvested verbatim from
  `BA_fleet_fuel.md` C2); `app/services/transport/claim.py::get_or_create_claim` (idempotent on the
  grain, R1's acceptance test verbatim); the `transport` module entitlement (default OFF, absent from
  every plan's module set — pricing is owner-blocked, `docs/DECISIONS-NEEDED.md` §10); 4 new
  permissions (`vat.read/write/submit`, `transport.read`) in all 8 `ROLE_PERMISSIONS` rows ahead of any
  route (ADR-P3 rule 5); migration `02d418169f97` (2 new tenant tables, RLS in the same migration,
  defense-in-depth CHECK constraints for the period shape and R11's "goods code 9 never" rule); the
  `test_boundaries.py` cross-domain-import CI assertion ADR-0023 promised. Explicitly NOT built (future
  M3 work orders, `ARCH_plan.md` G2.2 onward): the lock table, any gate (period-end/deadline/minimum/
  checklist/receipt-waiver), fee freezing, status derivation, goods-code mapping, `fuel_transactions`,
  the monthly close job, capture/entity-resolution, and every `api/routes/transport/*` route. Detail:
  `docs/plan/plan-a/wo/WO-49-G1.1-G2.1-G2.3.md`.

- [x] **WO-50** — `Completed` — G1.2: the typed `fuel_transactions` model
  (`app/models/transport/fuel_transaction.py`) per `BA_fleet_fuel.md` section 4.2 (the canonical
  transaction schema) + section 8.1 items 4-6 (no duplicated positional schema; split the overloaded
  `note` into `invoice_ref`+`provenance_note`; a real natural key). Note: `ARCH_plan.md` tags this task
  R29/R30, but those R-numbers are actually about engine read-only ownership and the separate claims
  store — not the transaction schema; corrected in `docs/plan/plan-a/wo/WO-50-G1.2.md`. Natural key
  `(org, entity, supplier, period, line_seq)` — caller-assigned, deterministic line position — makes
  ingestion insert-or-no-op, never Fleet Fuel's DELETE-by-period; `app/services/transport/product_group.py
  ::derive_product_group()` centralizes the PROMO → HVO → {AdBlue,Parking,Toll/Fees} → Diesel →
  Service/Other precedence the same way `is_synthetic()` is centralized; `app/services/transport/
  fuel_ingest.py::ingest_transaction()` gates on the module entitlement first, resolves the entity via
  `issuer.get_by_id` (opaque 404), `q2`-quantizes every monetary column while leaving `qty` deliberately
  unrounded, audits exactly once per real insert. `invoice_id` is a nullable FK into `invoices` (ADR-P3
  rule 1) — the same table `vat_claim_lines.invoice_id` (WO-49) points at, so the two transport tables
  relate only through the shared AP invoice, never a new transport-internal cross-reference. Migration
  `fc45baaf3283` (1 table, RLS in the same migration); RLS proven on real Postgres (cross-tenant SELECT
  returns zero rows, cross-tenant INSERT blocked by `WITH CHECK`). 68 tables, 74 revisions. Detail:
  `docs/plan/plan-a/wo/WO-50-G1.2.md`.

- [x] **WO-51** — `Completed` — G2.2: the one-invoice-one-submission lock table. `app/models/transport/
  lock.py` (`VatClaimedInvoice`, `UNIQUE(org_id, entity_id, refund_country, supplier, invoice_ref)` IS
  the lock, R4 — `entity_id`/`refund_country` denormalized so the constraint spans EVERY claim, not just
  the one that currently holds a row, and widened with `org_id` per this codebase's standing convention
  over the harvested BA text, which predates multi-tenancy); `app/services/transport/lock.py::
  submit_claim` (a minimal stub `draft`→`submitted` transition — acquires one lock row per invoice via a
  plain ORM INSERT, never an upsert, in the SAME flush as the claim's status mutation, so a lost race
  raises `IntegrityError` and rolls back the whole transition, nothing partially applied) and
  `withdraw_claim` (R5 — the ONLY function that deletes a lock row, proven both structurally via a
  grep-based test and behaviorally via a test that directly mutates a claim's `status` and asserts no
  lock release cascades). Three composite FKs off the lock row: `(org_id, claim_id)` CASCADE into
  `vat_refund_claims`, `(org_id, entity_id)` RESTRICT into `issuer_profiles`, `(org_id,
  fuel_transaction_id)` RESTRICT into `fuel_transactions` (WO-50's composite unique constraint existed
  specifically for this FK target — one representative transaction row per lock; protecting every row
  sharing an `invoice_ref` is a future close/re-close guard's job, flagged explicitly as NOT solved by
  this FK alone). Migration `dea0a87e6b0d` (1 table, RLS in the same migration). The headline proof: a
  real-Postgres concurrency test (`tests/test_transport_lock_concurrency.py`, added to the CI `postgres`
  job) fires two DIFFERENT claims racing `asyncio.gather` over the SAME invoice key — exactly one wins,
  the loser's status reads back its unchanged pre-submission value from a fresh query, proving the whole
  transaction rolled back, not just the lock insert; a second test proves `withdraw_claim` then frees the
  key for a third claim. All 6 pre-existing pg-only files (`test_rls.py`, `test_rls_connection_reuse.py`,
  `test_numbering_concurrency.py`, `test_payment_run_pay_concurrency.py`,
  `test_credit_note_lock_concurrency.py`, `test_expense_decision_concurrency.py`) re-verified green on
  the same scratch cluster. 69 tables, 75 revisions. Detail: `docs/plan/plan-a/wo/WO-51-G2.2.md`.

- [x] **WO-52** — `Completed` — G2.4: claim-line construction + note→invoice resolution.
  `app/services/transport/invoice_match.py::resolve_invoice_ref` — the ONE C3 resolution order (two
  note-matching heuristics — prefix / stem-contained, a documented interpretation of an underspecified
  BA phrase — then the admin-curated override, only consulted once both heuristics fail to resolve
  uniquely and NEVER displacing a heuristic match, then the sole-registered-invoice fallback, else
  UNMATCHED); `app/models/transport/note_override.py::VatNoteInvoiceOverride` (R16's admin override
  table, `ondelete=CASCADE` on the target FK — a real defect caught live: a composite-FK `SET NULL`
  would try to null the NOT-NULL `org_id` column too, so CASCADE deletes the dead override row instead);
  `app/services/transport/claim_lines.py::build_claim_lines` (materializes the LIVE, unfrozen
  `VatRefundClaimLine` rows for a `draft` claim from its in-scope `fuel_transactions` — R2, one row per
  (invoice, product_group), never an `ALL:` aggregate; refuses a non-draft claim; only ever touches
  `frozen_at IS NULL` rows, future-proofing G2.5's freeze). Two new read-only AP-domain seams
  (`app.services.invoices`, `app.services.vendors.get_by_name`) fill the `invoice_service` gap ADR-0023
  always named, so `services/transport/*` never imports `app.models.invoice`/`app.models.vendor`
  directly (`test_transport_services_do_not_import_other_domain_models` stays green). Migration
  `4cb7fca7e508` (1 table, RLS in the same migration). `tests/test_tenancy_parity.py`'s exemption
  registry gained a `vat_note_invoice_overrides` row (no route yet to drive an HTTP-level probe through).
  70 tables, 76 revisions, 83 service modules. Detail: `docs/plan/plan-a/wo/WO-52-G2.4.md`.

- [x] **WO-53** — `Completed` — G1.3/G1.4: the monthly close as a durable job + locked-line
  protection. `app/services/transport/close.py::run_close` (re)builds live claim lines (G2.4) for
  every `draft` claim in scope for a closed `"YYYY-MM"` period, on the PRE-EXISTING
  `app.services.jobs` durable-job framework — no new mechanism, since that framework already
  provides idempotent-by-key enqueue, dead-letter + manual retry, and rollback-then-fail on any
  handler exception (R31/R60 verbatim, with zero new infrastructure). `enqueue_close` keys the job
  on `idempotency_key=f"transport.close:{period}"`; registered in `app.services.job_handlers`
  (`transport.close`) so the close only ever runs through `jobs.run_once`, never inline in a web
  request (no `api/routes/transport/*` route exists to call it synchronously either). Fleet Fuel's
  own `consolidate→build_master→history→run_control→backup` ETL pipeline is deliberately NOT ported
  — there is nothing to consolidate FROM, since `fuel_transactions` ingestion (G1.2) is already
  insert-or-no-op, not Fleet Fuel's DELETE-by-period-then-reinsert. G1.4 ("locked lines are
  protected from a re-close") turned out to be already STRUCTURALLY true from G2.2/G2.4 alone —
  `run_close` only ever queries `status == "draft"` claims (a submitted claim's lines are invisible
  to it) and `vat_claimed_invoices`' pre-existing `RESTRICT` FK into `fuel_transactions` (WO-51)
  independently refuses a raw delete of a locked transaction at the database level — proven directly
  for the FIRST time by this order's own test, since no prior order had exercised that FK's
  delete-time behavior. No migration (no new model/table). Detail: `docs/plan/plan-a/wo/WO-53-G1.3-G1.4.md`.

- [x] **WO-54** — `Completed` — G2.5 ("the linchpin", `ARCH_plan.md`'s own word): frozen claim
  lines + frozen VAT base at submission. `app/services/transport/freeze.py::freeze_claim_lines`
  stamps `frozen_at` on every currently-unfrozen `VatRefundClaimLine` and sets `claim.vat_eur`/
  `vat_local`/`currency` from EXACTLY that claim's own lines (C10 — never a raw period `SUM`);
  `lock.py::submit_claim` calls it in the SAME flush as lock acquisition + the status flip, so a
  lost lock race rolls back the freeze too (proven by a same-session backstop test mirroring
  WO-51's own). Refuses (`claim_currency_mismatch`/`claim_line_mixed_currency`) rather than sum raw
  local-currency amounts across more than one currency, at both the per-line-bucket level
  (`build_claim_lines`, extended) and the whole-claim level (`freeze_claim_lines`) — master-context
  §4.14. `vat_claim_lines` gained 3 additive nullable columns (`net_local`/`vat_local`/`currency`,
  migration `bc783e1ec7c2`, no RLS change — existing table) so `build_claim_lines` (G2.4) captures
  the local-currency figure per line. Fee freezing (R13/G2.9) stays explicit future work. 70 tables,
  77 revisions. Detail: `docs/plan/plan-a/wo/WO-54-G2.5.md`.

- [x] **WO-55** — `Completed` — G2.8: the Art. 9 goods-code mapping, independent of the
  G2.2-G2.7 critical-path chain (deps G1.2 only). `app/services/transport/goods_code.py::GOODS_CODE`
  is harvested VERBATIM from `BA_fleet_fuel.md` A6 (Diesel/HVO/Promo adj → "1", Toll/Fees → "4",
  AdBlue/Parking/Service/Other → "10"); `derive_goods_code()` defaults an unrecognised
  `product_group` to "10", never "9" (R11), on top of the pre-existing DB CHECK constraint from
  WO-49 — two independent layers. `build_claim_lines` (G2.4) now populates every line's
  `goods_code` at construction time (additive change to an already-shipped function; the full
  pre-existing transport suite passed unmodified). No migration (the column has been nullable
  since WO-49). Detail: `docs/plan/plan-a/wo/WO-55-G2.8.md`.

- [x] **WO-56** — `Completed` — G2.6 slice 1: the hard period-end gate (R7) + the Art. 17
  minimum-amount gate (R8) + the 30-Sep deadline risk scanner (R9) — closing `ARCH_plan.md`'s
  own highest-scored risk item (L-1, score 6: the fatal 30-Sep time-bar). `app/services/transport/
  deadline.py`/`minimum.py` (new, pure functions, no DB access); `lock.py::submit_claim` gains the
  period-end gate (409 `period_not_ended`) and the minimum gate (409 `below_minimum`, an
  `override_minimum` param that records the exact comparison in `status_note`), previewed via a new
  `freeze.preview_vat_base` BEFORE the freeze/lock machinery — matching Fleet Fuel's own D5 gate
  order, so a below-minimum or not-yet-ended claim never mutates anything. Sweden/Denmark compare
  `vat_local` against their fixed statutory amounts (harvested verbatim); every other country
  (including Poland, deliberately) compares `vat_eur` against €400/€50. Every pre-existing
  `submit_claim` test call site (WO-51/54/55 + the real-Postgres concurrency test) was re-audited
  and given `override_minimum=True` where its own purpose was unrelated to R8 — one fixture bug
  (a not-yet-ended test period) caught and fixed while verifying on a scratch Postgres cluster
  (7 pg-only RLS/concurrency files all green together on a fresh DB). G2.9 (fee freezing) explicitly
  NOT attempted — `docs/DECISIONS-NEEDED.md` §10 updated: no established "customer"/fee-rate concept
  to build against without guessing the commercial model. No migration. Detail:
  `docs/plan/plan-a/wo/WO-56-G2.6-slice1.md`.

- [x] **WO-57** — `Completed` — G2.6 slice 2: the annual claim mop-up + quarterly overlap
  duplicate-block (R6). `lock.py::_apply_annual_mop_up_or_duplicate_block` runs after the R7/R8
  gates, before the freeze: an ANNUAL claim silently excludes an invoice already locked by a
  QUARTERLY claim (the mop-up, not a conflict) but still locks a genuinely new one; a QUARTERLY
  claim treats ANY existing-lock overlap as a duplicate and blocks the WHOLE submission before any
  mutation; an annual claim with nothing left after exclusion is refused ("nothing to claim
  annually"). Two annual claims overlapping the same invoice is a fail-closed blocking duplicate
  (an interpretation beyond the harvested text). One pre-existing WO-51 test now expects the new,
  cleaner `ConflictError`/`duplicate_invoice_lock` instead of a raw DB `IntegrityError` — a real
  improvement (catches an already-known duplicate before any mutation), not a weakened assertion;
  the DB constraint and the genuine-concurrent-race case stay independently proven, re-verified on
  a fresh scratch Postgres cluster after this order's `lock.py` changes. No migration. Detail:
  `docs/plan/plan-a/wo/WO-57-G2.6-slice2.md`.

- [x] **WO-58** — `Completed` — G2.6 slice 3: the document-presence gate (R10) + receipt-control
  waivers (R15). `app/services/transport/document_gate.py::enforce_document_presence` checks every
  real, RESOLVED `vat_claim_lines` row (never an `UNMATCHED` one) has >=1 captured document with real
  stored bytes (`ExtractionRun.source_sha256 IS NOT NULL`) — reads the claim's own MATERIALIZED lines,
  not `submit_claim`'s still-caller-supplied `invoices` tuple, since the lines are what actually gets
  frozen; a new batch seam `app/services/extraction.py::invoice_ids_with_documents` (one query, no N+1)
  is the AP-domain read this needed. A new tenant table `vat_receipt_waivers` (grain `(org, claim,
  supplier)`) backs `app/services/transport/waiver.py` (`set_waiver`/`remove_waiver`/
  `waived_suppliers`): `set_waiver` refuses (422 `waiver_supplier_has_invoices`) a supplier with any
  registered invoice for the claim's refund country (reusing `invoice_match.registered_invoices`, never
  a second implementation), otherwise records the waiver idempotently on a `draft` claim;
  `claim_lines.build_claim_lines` excludes a waived supplier's transactions from grouping BEFORE the
  resolution step (C9's "excluded from the claim by construction" — never even an `UNMATCHED` line);
  `lock.submit_claim` stamps every active waiver into `status_note` at submission. Both gates wired
  into `submit_claim`'s D5 order after the R6 mop-up/duplicate-block gate and before the freeze.
  Migration `312f33068c4b` (1 new tenant table, RLS in the same migration; up/down/up clean on real
  Postgres). README's "Scale of the codebase" truth-up sentence and `test_docs_truth.py`'s hard-coded
  table count updated (70→71 tables, 77→78 revisions, 1332→1379 collected tests). Explicitly NOT
  attempted: wiring `is_synthetic()` as an actual submission-blocking gate over a remaining, un-waived
  `UNMATCHED` line (a real, pre-existing gap — flagged, not solved); G2.9 (fee freezing, still
  decision-gated); G2.7/G2.10; any `api/routes/transport/*` route. Detail:
  `docs/plan/plan-a/wo/WO-58-G2.6-slice3.md`.

- [x] **WO-59** — `Completed` — G2.7: the status lifecycle 1A→5 (R12/R17), narrowly scoped.
  `app/services/transport/status.py::derive_stage` computes the system-derived `AUTO_CODES` value
  (`1A`/`1B`/`1C`/`1E`) for a `draft` claim in D3's literal order — an unresolved `UNMATCHED` line or a
  resolved invoice missing its document → `1A`; period not ended → `1B`; a "verdict caveat" (a
  DOCUMENTED INTERPRETATION: below the Art. 17 minimum, or an active receipt-control waiver) → `1C`;
  else `1E` — reusing WO-58's own `claim_gates.is_synthetic`/`document_gate` rather than re-deriving
  either check (a new non-raising twin, `document_gate.missing_document_invoice_ids`, keeps the blocking
  gate and this read-only preview on ONE query). `status.set_status_code` is the ONE writer of
  `status_code`: refuses every `AUTO_CODES` value ("system-controlled") and refuses every `MANUAL_CODES`
  value — INCLUDING `"2"` itself — while the claim is still `draft` (`claim_not_submitted`), matching
  R17's own acceptance tests verbatim; on an already-locked claim it stamps the workflow-code LABEL (+
  `action_deadline` for `2B`/`3D`'s soft reminder, R12) WITHOUT ever touching the coarse engine `status`
  column — deliberately, since the real `ENGINE_OF` engine-state transitions for 3/3A/3B/3C/3D/4/4A/5
  collide with G2.9's decision-gated fee engine. `lock.submit_claim` additively stamps
  `status_code = "2"` in the same flush as its existing writes. No migration (`status_code`/
  `action_deadline` are pre-existing nullable columns from WO-49). Detail: `docs/plan/plan-a/wo/WO-59-G2.7.md`.

- [x] **WO-60** — `Completed` — G2.10 slice 1: the adjustable submission checklist as DATA (R45),
  a documented PARTIAL harvest. New tenant table `vat_checklist_rules` (key/label/scope/check_type/
  reference/active/sort) backs `app/services/transport/checklist.py`: `seed_default_rules` (idempotent),
  `set_active` (the ONLY writer of `active` — "deactivate a rule ⇒ it disappears from the gate," proven
  verbatim), `submission_checklist` (the evaluator). Only `customer_data`/`bank_account`
  (`check_type="data"`, `scope="customer"`, evaluated against the claimant `IssuerProfile`'s
  registration_number/vat_number/address_line1/iban — no new customer concept, ADR-P3 rule 2) are
  seeded/evaluable — `contract`/`nace`/`trade_register`/`power_of_attorney` (needing a document-
  requirements-with-expiry concept this codebase doesn't have yet, or a new `nace_code` column) are
  explicitly deferred, not silently skipped. The four claim-level items (receipt control, unresolved
  refs, documents attached, period ended) reuse WO-56/58's own pure checks — since a materialized
  `vat_claim_lines` row collapses every unresolved transaction under one `"UNMATCHED"` ref with no
  supplier retained, naming "the missing supplier" re-queries `fuel_transactions` directly (one
  duplicated SELECT, zero duplicated resolution/waivability logic). `status.derive_stage` (G2.7) now
  consults this evaluator, replacing WO-59's own two-check proxy exactly as that order's docstring
  anticipated — `tests/transport/conftest.py::make_entity` gained synthetic registration_number/
  address_line1/iban defaults so every pre-existing "clean claim" test fixture stays clean under the
  new checks (raising fixture completeness, not weakening an assertion). Migration `920cbde1e481`
  (1 new tenant table, RLS in the same migration; up/down/up clean on real Postgres, 11 pg-only
  RLS/concurrency tests re-verified on a fresh scratch cluster). README/`test_docs_truth.py` truth-up
  (71→72 tables, 78→79 revisions, 1394→1403 collected tests). Detail: `docs/plan/plan-a/wo/WO-60-G2.10-slice1.md`.

- [x] **WO-61** — `Completed` — G3.1 slice 1: the per-country supplier legal-entity registry (R21/R22),
  a documented partial harvest of G3.1. New tenant table `supplier_vat_registrations`
  (`(org, supplier, country)` → `vat_number`/`entity_name`/`source`) backs
  `app/services/transport/supplier_entity.py`: `get_registration` (a single exact-key SELECT, R21 —
  marker-only, no fuzzy matching anywhere), `set_registration` (the only admin-curated writer, ALWAYS
  wins over a learned row), `learn_registration` (R22 — seeds a NEW `"capture"` row only when none
  exists; never overwrites an existing row of either source, never touches a `Vendor`/group-primary row,
  never queues a pending-change request — a deliberate contrast with A2.3's vendor-bank-detail dual
  control since this is diagnostic/filing metadata, not a payment-redirection vector). **R20** (capture
  actually reading the seller off a real invoice document — the Eurowag per-country footer, the E100
  anchor) is **explicitly NOT closed** by this slice — that is text/PDF extraction, `G3.2` (the fuel-card
  parser registry, a separate XL-effort, 7-network build, the natural next slice); `learn_registration`
  has no real caller yet, proven correct at the function level with a synthetic "just-captured" input,
  mirroring `is_synthetic()`'s own WO-49 debut with zero consumers wired in. Migration `4ae197627e35`
  (1 new tenant table, RLS in the same migration; up/down/up clean on real Postgres, 11 pg-only
  RLS/concurrency tests re-verified on a fresh scratch cluster). README/`test_docs_truth.py` truth-up
  (72→73 tables, 79→80 revisions, 1403→1412 collected tests). Detail:
  `docs/plan/plan-a/wo/WO-61-G3.1-slice1.md`.

- [x] **WO-62** — `Completed` — G3.2 slice 1: the fuel-card parser registry (R20), scoped down from
  `ARCH_plan.md`'s XL/7-network G3.2 to shared infrastructure + ONE fully-specified network, the same
  slicing discipline WO-56/57/58 used for G2.6. `app/services/transport/fuel_card_parser.py` is the
  deterministic-first registry (`FuelCardParser` ABC, `register`/`select`/`run`, fail-closed — raises
  rather than guessing which network a file belongs to) mirroring the AP-domain `extraction_provider.py`
  PATTERN over a fuel-transaction-shaped output, not its invoice-shaped type; `app/services/transport/
  parsers/eurowag.py` (`EurowagParser`) is the first network — Eurowag, because it is R20's own worked
  example (`BA_fleet_fuel.md` §3.B1): anchors ONLY to lines carrying the literal `"Pārdevējs / Verkoper:"`
  label against the harvested legal-form token set, so the Czech "W.A.G. Issuing Services, a.s." factoring
  entity is structurally unreachable even when an unrelated disclosure sentence naming it sits elsewhere in
  the same document. `app/services/transport/statement_ingest.py::ingest_statement` is the REAL caller
  `fuel_ingest.ingest_transaction` (WO-50) and `supplier_entity.learn_registration` (WO-61) were built for
  but never had: gates on the `transport` entitlement first, resolves EVERY line's EUR figure via
  `app.services.fx.to_eur` in a first pass BEFORE writing anything (a statement with one unconvertible
  line writes ZERO rows, not "all but one" — mirrors `expenses.build_items`'s existing all-or-nothing FX
  precedent), reads the network off the PARSED statement rather than a caller-supplied string (a
  mislabeled upload can't be miscategorized), and a malformed row aborts the whole statement at parse time
  rather than being silently dropped. R22 proven END TO END for the first time through a real caller
  (an admin-curated registration survives an ingest that would otherwise seed a conflicting one). No
  migration — pure service/parser composition over WO-50/WO-61's existing tables. Explicitly NOT
  attempted (named future slices, priority-ordered in the work order): the remaining six networks — E100
  (VAT-inclusive gross, the buyer-VAT-annexe hazard, the OTHER R20 worked example), Q8/Port One (the
  off-invoice rebate that is the entire reason `net_eur_eff` exists as its own column), DKV (5.63% service
  fee), TFC by Moya (hub-only discount), Moeve (6-dp VAT-inclusive maths), BP/Aral (Polish split-payment);
  G3.3 (the two independent validation regimes — line-count tie-out + capture review gate — explicitly
  DEPENDS on G3.2 per `ARCH_plan.md`); a persisted statement review-queue (this slice's review surface is
  the returned `warnings` list only); any `api/routes/transport/*` route. 73 tables, 80 revisions (both
  unchanged — no migration), 1412→1445 collected tests. Detail: `docs/plan/plan-a/wo/WO-62-G3.2-slice1.md`.

- [x] **WO-63** — `Completed` — G3.2 slice 2: the E100 fuel-card parser (R20's second worked example),
  the second network registered into WO-62's `fuel_card_parser` registry. `app/services/transport/
  parsers/e100.py` (`E100Parser`) anchors ONLY to lines carrying the literal `"E100 International Trade"`
  marker string (verbatim, `BA_fleet_fuel.md` §3.B1) — a co-present, unrelated buyer-VAT annexe line
  ("repeats on every annexe page") is never inspected, so it can never enter `parsed.entities` (the direct
  proof this order exists for). This is also the first parser to encounter a structurally DIFFERENT money
  model: E100 supplies only VAT-inclusive `gross_local` + a per-line `vat_rate`, never independently-given
  `net_local`/`vat_local` the way Eurowag's CSV does — `net_local`/`vat_local` are DERIVED by the reverse
  calculation (`net_local = gross_local / (1 + vat_rate/100)`, `vat_local = gross_local - net_local`),
  entirely in `Decimal`, proven numerically (`net_local + vat_local == gross_local`, pre-rounding); a
  `vat_rate` outside `[0, 100]` raises `ValueError` (never silently clamped), and a malformed row (bad
  decimal / out-of-range rate / bad country) aborts the WHOLE statement, unchanged discipline from
  `eurowag.py`. `fuel_card_parser._default_parsers()` gains one line (`E100Parser()`, appended after
  `EurowagParser()`); a registry-level test dispatches a well-formed file of EACH network to the correct
  parser in the same test, proving they coexist without collision. `statement_ingest.ingest_statement`
  needed ZERO changes — proven by re-running WO-62's own `test_g3_2_fuel_card_parser.py` and
  `test_g3_2_statement_ingest.py` byte-for-byte unmodified, and by the new DB-touching suite re-proving R22
  (learning never clobbers a curated registration), the two-phase FX guarantee, module-off inertness, and
  cross-tenant isolation end to end for E100 specifically. No migration — pure parser addition over
  WO-50/WO-61/WO-62's existing tables/services. Explicitly NOT attempted (named future slices, priority
  order unchanged from WO-62's own list, now with E100 struck off): Q8/Port One (the off-invoice
  `net_eur_eff` rebate), DKV (5.63% service fee), TFC by Moya (hub-only discount), Moeve (6-dp VAT-inclusive
  maths, per-line IVA rate), BP/Aral (Polish split-payment); station-colour discount-tier modelling
  (already folded into E100's given gross, per `BA_fleet_fuel.md` §4.2 — not a separate rebate layer);
  semi-monthly cadence enforcement (G3.3); G3.3 itself; a persisted statement review-queue; any
  `api/routes/transport/*` route. 73 tables, 80 revisions (both unchanged — no migration), 1445→1480
  collected tests. Detail: `docs/plan/plan-a/wo/WO-63-G3.2-slice2.md`.

- [x] **WO-64** — `Completed` — G3.2 slice 3: the Q8/Kuwait Petroleum fuel-card parser, the third
  network registered into WO-62's `fuel_card_parser` registry. `app/services/transport/parsers/q8.py`
  (`Q8Parser`) reuses Eurowag's straightforward money model (independently-given `net_local`/`vat_local`/
  `gross_local` — Q8 invoices at LIST price, never VAT-inclusive gross the way E100's is), so no new
  arithmetic was needed; what this order proves for the FIRST time in this codebase is that a single
  statement can legitimately carry lines for more than one country and currency in the same upload
  (`BA_fleet_fuel.md` §5.1's own "per-line country + currency" quirk for Q8 — neither Eurowag's nor E100's
  fixtures ever exercised this before). `Q8Parser` deliberately attempts NO seller-entity detection at all
  — `entities` is unconditionally `[]` with one explanatory warning distinguishing "never attempted" from
  `eurowag.py`/`e100.py`'s "attempted, none found" — because `BA_fleet_fuel.md` gives no footer label or
  anchor marker for Q8 the way it does for Eurowag/E100; an adversarial test plants a "Kuwait Petroleum ...
  VAT: ..."-shaped decoy line in the raw file and confirms it is never picked up (no scan exists to
  accidentally match it). **R20 stays CLOSED at exactly Eurowag and E100** — Q8 is G3.2 progress, not an
  R20 claim. Q8's `net_eur_eff` (the Port One off-invoice-rebate figure) is likewise deliberately left at
  `ingest_transaction`'s existing default (`= net_eur`) and proven so by an explicit test — reconciling
  Q8's list-price statement against a SEPARATE Port One rebate export is a cross-statement merge with no
  worked column layout given anywhere in the harvested spec, and `ARCH_plan.md` already scopes it as its
  own, later board item (G4.2, M5, R49/R50), not a G3.2 slice. `fuel_card_parser._default_parsers()` gains
  one line (`Q8Parser()`, appended third); a registry-level test dispatches a well-formed file of EACH of
  the three networks to the correct parser in the same test. `statement_ingest.ingest_statement` needed
  ZERO changes — proven by re-running WO-62/WO-63's own suites byte-for-byte unmodified, and by the new
  DB-touching suite re-proving the two-phase FX guarantee (including the multi-currency case), module-off
  inertness, and cross-tenant isolation end to end for Q8 specifically. No migration — pure parser addition
  over WO-50/WO-62's existing tables/services. Explicitly NOT attempted (named future slices, priority
  order unchanged from WO-62/WO-63's own list, now with Q8 struck off): DKV (5.63% service fee), TFC by
  Moya (hub-only discount), Moeve (6-dp VAT-inclusive maths, per-line IVA rate), BP/Aral (Polish
  split-payment); the Port One rebate merge itself (G4.2/M5); monthly-per-country cadence enforcement
  (G3.5/G3.3); G3.3 itself; a persisted statement review-queue; any `api/routes/transport/*` route. 73
  tables, 80 revisions (both unchanged — no migration), 1480→1501 collected tests. Detail:
  `docs/plan/plan-a/wo/WO-64-G3.2-slice3.md`.

- [x] **WO-65** — `Completed` — G3.2 slice 4: the DKV Euro Service fuel-card parser + the
  supplier-STATED-EUR money model, the fourth network registered into WO-62's `fuel_card_parser`
  registry and the FIRST (and, per the harvested quirks, last) network to require a deliberate
  extension of the shared parser/ingestion contract. `BA_fleet_fuel.md` §5.1's DKV row — *"SEK/EUR;
  semi-monthly; flat 1.30 SEK/L diesel discount; 5.63% service fee on parking/services; trusts the
  supplier's per-line EUR and pro-rates"* — is a THIRD distinct money model (after Eurowag/Q8's
  independently-given figures and E100's VAT-inclusive reverse-calc): the statement's own per-line
  EUR figure is the conversion's source of truth. `ParsedFuelLine` gained one additive field
  (`stated_net_eur`, default `None` — every prior parser untouched by construction) and
  `statement_ingest._resolve_line` gained the third branch between EUR-identity and cached-ECB:
  `net_eur` = the supplier's figure AS GIVEN (never an ECB recomputation, even when a cached rate
  exists — proven by a test whose seeded fallback SEK rate would have produced a DIFFERENT figure;
  the invoice is what a refund state audits against), `vat_eur` PRO-RATED at the same implied basis
  (`vat_local * stated_net_eur / net_local` — the harvested "and pro-rates" clause), `fx_rate` = the
  implied applied rate (`net_local / stated_net_eur`, 6 dp), `fx_ecb_rate`/`fx_ecb_date` = the
  OFFICIAL reference frozen BEST-EFFORT (NULL when uncached — a stated line NEVER fails on missing
  ECB coverage, the observable difference from the ECB branch, proven with an uncached-currency
  test), `fx_source="stated"` — the platform's pre-existing ADR-0010 enum value
  (`expenses.apply_item_fx` precedent; WO-50's `FX_SOURCE_CHECK` always allowed it, nothing could
  write it until now). Fail-CLOSED: a stated pair whose implied rate is not strictly positive
  (zero/sign-flipped) refuses the WHOLE statement (`fx_stated_inconsistent`) before any write,
  under the unchanged two-phase guarantee; an EUR-currency DKV row must state `net_eur == net_local`
  (a mismatch is a malformed row → whole statement aborts) and rides the untouched identity branch.
  The on-invoice 1.30 SEK/L discount + 5.63% service fee are ALREADY INSIDE the given figures
  (`BA_fleet_fuel.md` §4.2 verbatim) — read, never recomputed (contract-term verification is
  G3.4/M5 territory). Like Q8, `DKVParser` attempts NO seller-entity detection (`entities`
  unconditionally `[]`, the "never attempted" warning; no R20 worked marker exists for DKV) —
  **R20 stays CLOSED at exactly Eurowag and E100**. ONE changed assertion, aligned not weakened:
  WO-64's `test_g3_2_registry_ships_eurowag_e100_and_q8` asserted the exact three-parser list
  (encoding "no fourth network exists") and now asserts membership + relative order, WO-62/WO-63's
  own future-proof registry-test style; the exact four-parser list is asserted by the new DKV suite.
  No migration — pure code addition over existing tables/columns (`fx_source='stated'` was always
  CHECK-allowed). Explicitly NOT attempted (named future slices, priority order unchanged, now with
  DKV struck off): TFC by Moya (hub-only discount), Moeve (6-dp VAT-inclusive maths, per-line IVA
  rate), BP/Aral (Polish split-payment); semi-monthly cadence enforcement (G3.5/G3.3); G3.3 itself
  (now the recommended NEXT M3 item — DKV was the last network whose model touches the shared
  contract, so the two validation regimes can be built against a stable `ParsedFuelLine`/
  `statement_ingest` shape and proven over THREE distinct money models); a persisted statement
  review-queue; any `api/routes/transport/*` route. 73 tables, 80 revisions (both unchanged),
  1507→1537 collected tests (+30: 19 parser + 11 ingest; both endpoints measured live —
  1497→1527 passed + 10 pg-only skips). Detail:
  `docs/plan/plan-a/wo/WO-65-G3.2-slice4.md`.

- [x] **WO-66** — `Completed` — G3.3: the TWO INDEPENDENT VALIDATION REGIMES (R25, P0/L — the
  standing recommendation from WO-65's own report, taken now that the parser/ingestion contract is
  stable over three distinct money models; deps G3.2-partial + C1.1/WO-7 both satisfied). They answer
  different questions and stay structurally separate (`BA_fleet_fuel.md` §2.1a: "Two separate
  regimes"). **Regime 1 — the capture review gate** (`app/services/transport/capture_review.py`,
  pure functions): the harvested nine-rule verdict lattice `ok < warn < error` — invoice number
  present (error) / date `YYYY-MM-DD`, empty passes (warn) / country in the 23-country set (warn) /
  net+vat parse as numbers (error, EARLY RETURN) / `net > 0` (error) / `vat >= 0` (error) /
  `vat <= net` (error) / `net <= 5,000,000` (warn) / VAT-rate coherence within ±0.5pp of a known
  rate, `vat == 0` and unknown countries deliberately SKIPPED (warn); the batch tie-out
  `abs(q2(Σ net+vat) − q2(coversheet_total)) <= 0.02` COMPARED ON DECIMALS (a boundary diff never
  flips on binary-float noise — proven by a test whose float sum WOULD flip); the harvested commit
  gate `can_commit = (errors == 0) and (tie is None or tie.ok)`; WARNINGS NEVER BLOCK. `CapturedLine`
  carries RAW captured strings so rule 4 is real, not vacuously typed away; `review_statement()`
  adapts a typed `ParsedStatement` — ONE rule set for the future review screen and today's wiring
  (the C1.1 lesson; the AP `validation.py` engine is deliberately NOT reused — ADR-P3). Wired into
  `statement_ingest.ingest_statement` (new optional `coversheet_total`) after parse and BEFORE FX: a
  blocked batch raises `capture_review_blocked` naming EVERY error at once, zero rows written; warn
  findings surface in `result.warnings`. `VAT_RATES`: the 23-country count, ±0.5pp window, skip
  rules and the four dual entries (PL 23/8, ES 21/10, EE 22/20, FI 24/25.5) are harvested; remaining
  membership/rates are a DOCUMENTED RECONSTRUCTION from public VAT law (the source table may not be
  copied — master-context §10). **Regime 2 — the engine tie-out** (`FuelTieOutExpectation` /
  `fuel_tieout_expectations`, migration `b3f1c6d2a904` with FORCE RLS in the SAME migration +
  composite `(org_id, entity_id)` FK; service `app/services/transport/tie_out.py`): the
  per-(entity, supplier, period, currency) figures a HUMAN types FROM THE INVOICE PDF (§5.1's
  "fill `expected` from the invoice → PASS = trained" onboarding contract) — `lines` tolerance 0
  (EXACT, always), `gross_local` within a per-row CHECK-bounded [0.02, 0.05] tolerance (default
  0.02), `net_eur`/`gross_eur` 0.05, `diesel_litres` (Diesel product-group only) 0.05 (interpreted —
  no harvested litres tolerance). `close.run_close` evaluates EVERY expectation row FIRST and raises
  ONE `tie_out_failed` naming ALL failures ("the operator sees all failures at once"); the job
  framework's whole-session rollback makes "the hand-off artifact is not written" literal — proven
  through the REAL `enqueue_close` + `jobs.run_once` path (no claim-line rebuild survives).
  Fail-OPEN by absence (an untyped supplier is not checked — the expectation IS the opt-in training
  target), fail-CLOSED once typed; `remove_expectation` is the audited narrow un-halt.
  `set_expectation` upserts (a typo is corrected by retyping; audit keeps old→new), quantizes at the
  service (q2 money / 3-dp litres), and is tenant-opaque (foreign entity → 404-shaped
  `entity_not_found`). The expectation grain's `currency` column is a DOCUMENTED INTERPRETATION
  (WO-64 proved multi-currency statements; §4.14 forbids cross-currency `gross_local` sums — a
  single-currency supplier types one row, byte-equivalent to the harvested behaviour). Aggregation
  in Python over Decimals (never a dialect-coerced SQL SUM). NINE aligned test changes, none
  weakened (each encoded the pre-gate absence): 8 fixture rows across the Eurowag/E100/Q8 ingest
  suites gained a synthetic `invoice_ref` (their subjects — ECB conversion, two-phase FX refusal —
  untouched); the DKV zero-`net_local` test now expects `capture_review_blocked` (rule 5 refuses
  EARLIER than the FX branch's zero-guard, whose ingest coverage moved to the new
  `test_g3_3_stated_zero_eur_still_hits_the_fx_guard_behind_the_gate`); `test_docs_truth`'s table
  count 73→74 (README truth-up: 74 tables, 81 revisions, 1588 collected). Explicitly NOT attempted
  (named board owners): the anti-drift extraction baseline / regression check (>0.02 re-extraction
  drift — G3.3 slice 2, needs a baseline store + a re-extraction caller that does not exist);
  TFC by Moya, Moeve, BP/Aral (G3.2's remaining slices, priority order unchanged); cadence
  enforcement (G3.5); post-capture IBAN/VAT-ID/duplicate checks (G3.4); a persisted statement
  review-queue; any `api/routes/transport/*` route. Postgres 16 gate re-verified on a fresh scratch
  cluster (NOSUPERUSER `appuser`, FORCE RLS + `tenant_isolation` policy live on the new table,
  up/down/up clean, 6/6 pg-only RLS/concurrency tests; cluster torn down). 74 tables, 81 revisions,
  1537→1588 collected tests (+51: 24 pure gate + 7 gate-through-ingest + 14 tie-out + 6 close-halt).
  Detail: `docs/plan/plan-a/wo/WO-66-G3.3.md`.

- [x] **WO-67** — `Completed` — G3.2 slice 5: the TFC BY MOYA fuel-card parser
  (`app/services/transport/parsers/tfc.py`, `TFCParser`), the FIFTH network in WO-62's registry and
  the FOURTH distinct money model — the DERIVED-NET hub-only discount (`BA_fleet_fuel.md` §5.1:
  "−0.205/L only at TFC hubs (Meer −0.19); third-party stations undiscounted. Flat 21% VAT"). The
  statement prints litres, a LIST unit price and a per-line `station_class`; the parser DERIVES
  `net_local = qty × (list_price_eur_l − tier)` (harvested tiers 0.205/`hub`, 0.19/`meer`,
  0/`third_party`), `vat_local` at the flat 21% and `gross_local = net + vat`, pure unrounded
  Decimal, derivation basis in `provenance_note` — the "station-classification concept" WO-62's
  slice list named. Deliberately parser-LOCAL: `ParsedFuelLine`/`statement_ingest`/`capture_review`/
  `tie_out` byte-identical to WO-66's tree (WO-65's contract-stability argument holds); every TFC
  line is EUR on the untouched identity branch; the on-invoice discount enters the figures BY the
  derivation (`net_eur_eff` = default; off-invoice stays G4.2). Fail-closed row refusals (each
  aborts the whole statement): unknown `station_class` (a guessed tier is an invented discount),
  non-EUR currency (the tier constants are EUR/L — the one parser where the currency check is
  load-bearing), non-positive discounted unit price (mis-keyed list price named at the parser).
  FIRST network onboarded against the LIVE G3.3 regimes: the ingest suite proves the
  €0.02-allowed/€0.03-blocked coversheet tie-out over the parser's DERIVED figures (761.695 → q2
  761.70 vs 761.72/761.73) through `ingest_statement` — §5.1's "PASS = trained" against the real
  WO-66 gate, plus the assert-the-absence coherence proof (flat 21% in BE/NL emits no
  `vat_rate_incoherent` warn). Like Q8/DKV: NO entity detection ever (`entities == []`, "never
  attempted" warning, decoy-line adversarial test); R20 stays CLOSED at exactly Eurowag+E100. ONE
  existing assertion aligned, none weakened: the DKV suite's exact-four-list registry test (encoding
  "no fifth network exists") now asserts membership + relative order — the same fix WO-65 applied to
  WO-64's exact-three-list test; the exact five-list moved to the TFC suite. No migration, no
  schema/RLS impact. Explicitly NOT attempted (named owners): Moeve + BP/Aral (G3.2's remaining
  slices, priority order unchanged — Moeve next), G3.3 slice 2 (anti-drift regression check),
  cadence enforcement (G3.5), tier-grant/contract verification (G3.4/M5 contract-audit), a
  persisted review-queue, any `api/routes/transport/*` route. 74 tables, 81 revisions, 1588→1620
  collected tests (+32: 22 parser + 10 ingest). Detail: `docs/plan/plan-a/wo/WO-67-G3.2-slice5.md`.

- [x] **WO-68** — `Completed` — G3.2 slice 6: the MOEVE (ex-Cepsa) fuel-card parser
  (`app/services/transport/parsers/moeve.py`, `MoeveParser`), the SIXTH network in WO-62's registry —
  the per-line-IVA VAT-INCLUSIVE money model (`BA_fleet_fuel.md` §5.1: "ALL amounts VAT-inclusive;
  per-line IVA rate (10% gasoleo / 21% EcoBlue); cash-at-pump nets against transfer; 6-dp internal
  calc"), E100's reverse calculation varied three harvested ways. (1) The IVA rate genuinely varies
  LINE-BY-LINE within one statement — each line is reverse-calculated at ITS OWN printed rate, never
  a statement-wide constant. (2) The harvested 6-dp internal calc: `net_local = q(gross/(1+rate/100),
  6dp)` ROUND_HALF_UP with `vat_local = gross − net` EXACT, so `net+vat==gross` holds identically and
  the implied rate stays inside rule 9's ±0.5pp window; `q2` remains at the ingest boundary ONLY
  (E100's unrounded derivation untouched — the 6-dp step is Moeve's quirk, not a shared convention).
  (3) THE CASH-AT-PUMP DECISION (documented in the WO): a flagged row IS a `ParsedFuelLine` —
  invoiced, VAT-bearing fuel whose VAT is exactly as reclaimable — because "nets against transfer" is
  SETTLEMENT (M4/G3.5 territory, never capture): the per-line `payment` channel
  (`transfer`/`cash_at_pump`, fail-closed on any other value — a settlement channel is never guessed)
  rides `provenance_note` only, NEVER mutates a figure, the batch tie-out ties the INVOICE total (all
  lines, cash included), and the parse surfaces ONE advisory count+gross-sum warning. Rate policy
  provably lives in the WO-66 gate, not the parser: `iva_rate` bounded [0,100] (E100's defensive
  bound), NO {10,21} whitelist, NO product→rate mapping — rule 9's HARVESTED ES dual entry `(21, 10)`
  exists for exactly this network and is REUSED (ingest proves both ways: 10/21 ES lines emit no
  `vat_rate_incoherent`; a 15% ES line warns and still registers — warnings never block).
  Parser-LOCAL by design: `ParsedFuelLine`/`statement_ingest`/`capture_review`/`tie_out`
  byte-identical to WO-67's tree; every fixture line is EUR on the untouched identity branch;
  `net_eur_eff` = default (the ON-INVOICE "PRN off pump PVP" discount is inside the printed gross;
  verifying it is G3.4/M5). Live-gate onboarding pair over the derived figures (Σ gross = 1001.00
  exactly, cash lines included: 1001.02 registers / 1001.03 blocked, zero rows). Like Q8/DKV/TFC: NO
  entity detection ever (`entities == []`, "never attempted" warning, ES all-nines decoy adversarial
  test, allow-list entry landed in the same commit — the WO-67 lesson); R20 stays CLOSED at exactly
  Eurowag+E100. ONE existing assertion aligned, none weakened: the TFC suite's exact-five-list
  registry test (encoding "no sixth network exists") now asserts membership + relative order — the
  WO-65/WO-67 precedent; the exact six-list moved to the Moeve suite. No migration, no schema/RLS
  impact. Explicitly NOT attempted (named owners): BP/Aral (G3.2's last slice — PLN, Polish
  split-payment MPP, ORS toll-fee lines; next), G3.3 slice 2 (anti-drift regression check),
  settlement/transfer modelling (M4), cadence enforcement (G3.5), PRN-discount/product→rate
  verification (G3.4/M5), a persisted review-queue, any `api/routes/transport/*` route. 74 tables,
  81 revisions, 1620→1655 collected tests (+35: 24 parser + 11 ingest). Detail:
  `docs/plan/plan-a/wo/WO-68-G3.2-slice6.md`.

- [x] **WO-69** — `Completed` — G3.2 slice 7: the BP/ARAL (B2Mobility) fuel-card parser
  (`app/services/transport/parsers/bp.py`, `BPParser`, network code `"BP"` per §4.2's supplier
  column), the SEVENTH and LAST network in WO-62's registry — **G3.2 IS CLOSED**: all seven
  `BA_fleet_fuel.md` §5.1 networks (Eurowag, E100, Q8, DKV, TFC, Moeve, BP) now parse
  deterministically into the claim engine. The money model is deliberately the SIMPLE one
  (independently-given net/vat/gross read VERBATIM — Eurowag/Q8's shape; §5.1 gives BP no derivation
  quirk); the network's quirks live elsewhere: (1) the first ALL-PLN network — ingestion's EXISTING
  dated-ECB-rate branch (`fx.to_eur` at each line's own txn_date, `fx_source="ecb"`) is its DEFAULT
  conversion path, and the harvested `month_config.FX` static fallback is deliberately NOT
  reproduced (master-context §4.15 refuse-never-guess wins: `fx_rate_unavailable`, zero rows, the
  two-phase guarantee — proven with a clean EUR line + a zero-coverage ZAR probe line, NEITHER
  written; PLN itself carries a bundled dated snapshot in the platform's rate store). (2) THE
  ORS-FEE-LINE DECISION (documented in the WO): an ORS fee line IS a `ParsedFuelLine` — an ordinary
  VAT-bearing statement line, never a coversheet adjustment, never merged into its toll line (§5.1
  says fee LINES; §4.2 models non-fuel lines; DKV's 5.63% fee is the ON-INVOICE precedent): its 23%
  VAT is exactly as reclaimable, the tie-out ties the INVOICE total fee lines included, and the
  Art. 9 goods-code path stays honest (toll → Toll/Fees → 4, ORS → Service/Other → 10, fuel →
  Diesel → 1, asserted on stored `product_group`); the contracted ~2.5% ratio is NEVER verified at
  capture (G3.4/M5) — ONE advisory warning carries count + per-currency ORS and toll gross sums.
  (3) THE MPP DECISION (documented in the WO): Polish split-payment is SETTLEMENT (the WO-68
  cash-at-pump boundary) — the statutory `MECHANIZM PODZIELONEJ PŁATNOŚCI` literal is scanned at
  statement level; present ⇒ ONE advisory with the per-currency VAT total ("settlement-side only"),
  absent ⇒ ONE fail-OPEN mandatory-network advisory (an absent settlement annotation corrupts no
  captured figure — blocking would invent policy); no figure ever changes, no per-line flag, no
  contract widening. Fail-closed: an unknown per-line `line_type` (`fuel`/`toll`/`ors_fee`) aborts
  the whole statement (a guessed line kind mis-maps the goods code — TFC `station_class` / Moeve
  `payment` discipline). Rule 9's HARVESTED PL dual entry `(23, 8)` coheres the 23/8/23 mix with no
  parser-side rate table (no `vat_rate_incoherent` on the default fixture — the reuse proof).
  Live-gate onboarding pair over DOCUMENT-currency totals (Σ net+vat = 1452.15 PLN exactly, fee
  lines included: 1452.17 registers / 1452.18 blocked, zero rows). Parser-LOCAL by design:
  `ParsedFuelLine`/`statement_ingest`/`capture_review`/`tie_out` byte-identical to WO-68's tree.
  Like Q8/DKV/TFC/Moeve: NO entity detection ever (`entities == []`, "never attempted" warning, PL
  all-nines decoy adversarial test, allow-list entry landed in the same commit — the WO-67 lesson);
  R20 stays CLOSED at exactly Eurowag+E100. ONE existing assertion aligned, none weakened: the
  Moeve suite's exact-six-list registry test (encoding "no seventh network exists") now asserts
  membership + relative order — the WO-65/67/68 precedent; the exact seven-list moved to the BP
  suite. No migration, no schema/RLS impact. Explicitly NOT attempted (named owners): G3.3 slice 2
  (anti-drift regression check — the priority head now G3.2 is closed), split-payment settlement
  modelling (M4), ORS contract verification (G3.4/M5), a `month_config.FX`-style fallback table
  (refused per §4.15), cadence enforcement (G3.5), a persisted review-queue, any
  `api/routes/transport/*` route. 74 tables, 81 revisions, 1655→1689 collected tests (+34: 24
  parser + 10 ingest). Detail: `docs/plan/plan-a/wo/WO-69-G3.2-slice7.md`.

- [x] **WO-70** — `Completed` — G3.3 slice 2: the anti-drift extraction baseline + `regression_check`
  — **G3.3 IS CLOSED** (slice 1 = WO-66's two R25 regimes; this slice = the harvested "Anti-drift"
  paragraph: *"`extraction_baseline` records a confirmed extraction as known-good; `regression_check`
  flags a drift when a re-extraction moves net or vat by more than 0.02"*, `BA_fleet_fuel.md` §2.1a /
  Appendix B). `app/models/transport/extraction_baseline.py` (`FuelExtractionBaseline`,
  `fuel_extraction_baselines`: the known-good per-(statement-SHA-256 × currency) parsed aggregates —
  exact `line_count`, q2'd LOCAL-currency `net_total`/`vat_total`; migration `c7d2e9a41f58`, RLS in
  the same migration, tenancy-parity EXEMPT entry in the SAME commit — the WO-66 CI lesson applied);
  `app/services/transport/extraction_baseline.py` (`DRIFT_TOLERANCE=0.02`; pure `aggregate`/`compare`;
  confirm-time `record`; the explicit re-extraction caller `regression_check` — read-only,
  module-gated, fail-OPEN on a never-baselined digest; and the audited human acts `rebaseline` —
  re-parses, never re-types, the deliberate inversion of the tie-out's human-typed independence —
  and `remove_baseline`, both opaque-404 across tenants). Wired into
  `statement_ingest.ingest_statement` AFTER phase 2 + entity learning (only a CONFIRMED extraction is
  known-good — a capture-gate-blocked or FX-failed statement leaves no baseline): first sight of the
  digest RECORDS; a re-seen digest COMPARES and appends "extraction drift: ..." WARNINGS. Three
  documented design decisions off the harvested spec (recorded in the WO): (1) drift is ADVISORY —
  the harvested verb is "flags" vs the two R25 regimes' block/halt, and WO-66 records anti-drift as
  outside R25's acceptance, so §4.19 semantics apply (never blocks, nothing self-adjusts; doubly
  load-bearing because `ingest_transaction`'s insert-or-no-op makes a drifted re-parse otherwise
  INVISIBLE — the warning is the only surface of the divergence); (2) the threshold is STRICTLY
  `> 0.02` on q2'd Decimals per currency ("moves … by MORE than 0.02"; exactly-0.02 proven NOT
  flagged); (3) the baselined figures are LOCAL-currency per-currency (FX is downstream of extraction
  — an EUR basis would flag rate-cache changes as parser drift; §4.14 forbids the cross-currency sum)
  plus `line_count` as a third EXACT metric (a split/merged line can drift compensatingly with equal
  totals — T-6). Audit: `TRANSPORT_EXTRACTION_BASELINE_SET`/`_REMOVE`, one event per statement,
  old→new. Proven: 20 new tests (13 service + 7 ingest-wiring: the strict 0.02/0.03 boundary,
  per-currency isolation over a two-currency Q8 fixture, currency-set change in both directions,
  cross-tenant independence + opacity, drifted-reingest-succeeds with `fuel_transactions`
  byte-unchanged and the baseline NOT self-adjusted, drift-after-review warning ordering); Postgres 16
  gate green (up/down/up on `c7d2e9a41f58`, FORCE RLS + `tenant_isolation` policy verified on the new
  table, `test_rls.py` set-equality + the concurrency files 8 passed on a NOSUPERUSER role); zero
  existing assertions changed or weakened. Explicitly NOT attempted (named owners): a persisted
  drift/review queue or any `api/routes/transport/*` route (future transport surface), statement-byte
  vaulting so re-extraction can run without the caller's file (capture-automation epic), G3.4
  post-capture checks, G3.5 cadence. 75 tables, 82 revisions, 1689→1709 collected tests (+20).
  Detail: `docs/plan/plan-a/wo/WO-70-G3.3-slice2.md`.

- [x] **WO-71** — `Completed` — G3.4: deterministic advisory post-capture checks (R26), closing the
  board row entirely. `app/services/transport/capture_checks.py` — the harvested module by name
  (`BA_fleet_fuel.md` §3.I7): IBAN ISO 13616 + MOD-97 (severity error) composing `core/bank_id`
  with ONE documented divergence (unknown country prefix = uncheckable = NO finding; the SEPA
  path's fail-closed gate untouched); per-country VAT-ID STRUCTURAL check from the public VIES
  format table (EU-27, EL→GR; allocation ranges deliberately absent — "fail toward not crying
  wolf"); `vies_check` performing NO I/O at all (always `not_checked` — the live lookup is
  deliberately not inline, proven with socket creation monkeypatched to explode); and the
  cross-entity duplicate scan (normalized ref = uppercase+strip-spaces with separators KEPT;
  exact q2-amount + same-currency equality; prior cross-entity registration = error, in-batch
  normalization collision = warn; the current (entity, supplier, period) group excluded so
  insert-or-no-op replays never self-flag; cross-tenant identical invoices never flag — proven).
  `CheckFinding` is deliberately a DIFFERENT type from `capture_review`'s lattice so an
  error-severity ADVISORY finding structurally cannot block — the §4.19 heart, proven end to end
  (entity B ingesting entity A's registered invoice gets the `post-capture check (error)` warning
  AND its rows are written). Wired into `ingest_statement` pre-write; warnings ordering extends
  WO-70's stable contract (parser → review → post-capture → drift, asserted end-to-end). No
  migration, no new table (findings are ephemeral review output — the WO's decision 7); the
  G3.3 guarded suites pass byte-for-byte unmodified. 1699→1718 passed (+19). Detail:
  `docs/plan/plan-a/wo/WO-71-G3.4.md`.

- [x] **WO-72** — `Completed` — G3.5: receipt control (cadence × activity, orphan check, overrides
  survive), closing the board row entirely — the harvested `invoice_control.py` (`BA_fleet_fuel.md`
  §3.J; §2.3: "a missing invoice is un-recoverable VAT — cadence × activity is the only way to know
  what SHOULD have arrived"). `app/models/transport/receipt_control.py` — `VatSupplierCadence` (the
  admin cadence per free-text supplier code, the WO-61 registry precedent, three harvested values
  only) + `VatReceiptControl` (the persisted §3.J grid, natural key org×entity×supplier×period×slot
  ×country with `country=""` never NULL); `app/services/transport/receipt_control.py` —
  `DEFAULT_CADENCES` (§5.1 verbatim: E100/DKV semi-monthly, MOEVE/BP/TFC/PORTONE monthly, Q8
  monthly-per-country; Eurowag deliberately absent), `cadence_for` (admin row → harvested default →
  None = NO expectation, opt-in by absence per the R61/WO-66 discipline), `run_receipt_control`
  (expectation = cadence × ACTIVITY: monthly `M`; semi-monthly `H1`/`H2` split days 1-15/16-end, a
  documented interpretation; per-country one slot per country WITH activity; a slot with no
  transactions is `no_activity` — never chased; cross-control `received_doc`/`received_no_doc`/
  `missing` via the ONE `invoice_match.resolve_invoice_ref` + WO-58's `invoice_ids_with_documents`
  batch seam, one docs query per run), `orphan_transactions` (§3.J item 3 verbatim — transaction-
  grain, read-only, persists nothing), and `set_control_override` — the ONLY writer of `waived`/
  `note` (grep-proven, the R5 structural pattern), so the re-run upsert preserves overrides by NEVER
  writing them ("manual overrides survive re-runs", §3.J item 4, proven through two re-runs incl.
  one that recomputes the status underneath). ADVISORY THROUGHOUT (§4.19 — §3.J's verbs are
  "answers"/"persist"/"chase", never "block"/"halt"): a `missing` slot / a waived slot changes NO
  claim submission outcome (proven end-to-end); a G3.5 slot waiver is a worklist mute, structurally
  distinct from WO-58's claim-level legal waiver (R15) — the boundary is documented on both sides.
  `close.run_close` gained the `run_control` stage (§3.H H4's harvested stage list) after the
  claim-line rebuild: findings never fail the close, the R25 tie-out still halts BEFORE the stage
  (proven: a failed tie-out persists zero control rows). Migration `d8e4f2a61b37` (2 tenant tables,
  FORCE RLS in the same migration, up/down/up verified on scratch Postgres 16 with the 7 pg-only
  files green on a NOSUPERUSER role); tenancy-parity EXEMPT classified in the same commit. 77
  tables, 83 revisions. 1718→1744 passed (+26). Detail: `docs/plan/plan-a/wo/WO-72-G3.5.md`.

- [x] **WO-73** — `Completed` — G2.11: customer lifecycle + per-country activation gates (R44),
  closing the board row's shippable core — the first gate that asks WHO the claim is for
  (`BA_fleet_fuel.md` §3.F F1/F3, §3.E "Activation gates layered on top", §4's state tables; a
  claim is filed in the client's name under a power of attorney — filing for an unactivated
  customer is an unauthorised legal act, not a data bug). `app/models/transport/
  customer_lifecycle.py` — `VatCustomerLifecycle` (F1's `prospect → pending → active → inactive`,
  CHECK-constrained) + `VatCountryActivation` (`(none) → requested → active` per refund country),
  BOTH transport-local tables keyed to `issuer_profiles` via the composite RESTRICT FK (the
  WO-61/WO-72 registry precedent — never lifecycle columns on the shared AP/AR issuer model; the
  harvested `customers.db` was itself a separate store, §4.1). `app/services/transport/
  customer_lifecycle.py` — EXACTLY the harvested edges and nothing else (§10 no-invention):
  `add_prospect` (idempotent, NEVER downgrades a real client of any status — the `company_name`
  idempotency key translated to this codebase's customer identity, the entity row, documented),
  `promote_prospect` (the onboarding handoff), `set_activation` (F1's pending↔active toggle),
  `set_inactive` (§4's churn edge; `inactive` TERMINAL in this slice — no re-onboarding edge is
  harvested, recorded rather than invented), `request_country`/`set_country_activation` (the
  linear country ladder — activating a never-requested country refused); every real transition
  audited old→new (§4.16), idempotent no-ops audit nothing. `enforce_activation` — the ONE gate
  predicate (the `is_synthetic()` centralization discipline), FAIL-CLOSED on absence in both
  halves (an unonboarded entity never out-privileges an onboarded pending one) — wired into
  `lock.submit_claim` AFTER the R8 minimum and BEFORE the R6 duplicate block (D5's engine-gate
  group head per §3.E's "layered on top"); a refused claim never freezes or locks (proven), and
  the gate is UNCONDITIONAL (Fleet Fuel's `gate_activation=False` escape existed for a second
  path whose checklist superseded the coarse flags; here the checklist checks data, never the
  status flag, and R44's acceptance names the ACTIVATION message). R44's acceptance verbatim:
  a prospect's claim → 409 `customer_not_active` with the activation message; pending/inactive/
  no-row refused identically; active + country merely `requested` → `country_not_activated`
  (PoA wording); active + country active submits through the full gate stack. Preparation
  surfaces stay deliberately UNGATED (claim creation, `build_claim_lines`, the checklist,
  `run_close` — F1 scopes the rule to legal/claim GATES; the 1A stage exists to describe an
  incomplete customer's draft claim; run_close proven to rebuild a pending entity's lines).
  F3's `country_requirements` + `country_ready_to_activate` (informational, "not a gate")
  deferred to the customer-document-store slice WO-60 already named — deferred NOT silently
  skipped (the R45 partial-harvest precedent). Migration `e5b9c3d71a24` (2 tenant tables, FORCE
  RLS in the same migration, up/down/up verified on scratch Postgres 16 with the 7 pg-only files
  green on a NOSUPERUSER role); tenancy-parity EXEMPT classified in the same commit. Existing
  submit-path suites raised via the new `conftest.activate_entity` helper (the WO-60
  `make_entity` precedent) — 21 tests across 10 files gained the fixture (+ the pg concurrency
  seed), ZERO assertions weakened, and every pre-R44 gate test (module-off/not-draft/empty-set/
  `period_not_ended`/`below_minimum`) passes byte-unmodified as the gate-order proof. 79 tables,
  84 revisions. 1744→1764 passed (+20). Detail: `docs/plan/plan-a/wo/WO-73-G2.11.md`.

- [x] **WO-74** — `Completed` — G2.12: evidence pack + claim workbook, the two filing
  artifacts of a frozen VAT refund claim and the LAST non-decision-gated M3 service row
  (`BA_fleet_fuel.md` §2.2 line 204 — "the Excel claim workbook (`build_workbook`), the
  evidence pack"; §3.K K6 — the filing bundle under the human-navigable vault tree; §3.M M1 —
  every path segment Windows/SharePoint/FTP-sanitized, `period_label` `Qn`/`Annual`).
  `app/services/transport/claim_pack.py`: ONE loader (`_load_pack`) feeds BOTH renderers —
  the evidence pack embeds a workbook rendered from the SAME loaded pack, so ARCH_plan's
  G2.12 acceptance ("the workbook and the evidence pack agree line-for-line") is structural,
  and a test also proves it cell-for-cell (Lines sheet + TOTAL row) against the bundle-embedded
  copy. Workbook: `Claim` header sheet + `Lines` at the R2 grain (one row per (invoice,
  product code), Art. 9 goods code per line) + a bold TOTAL row equal to the frozen
  `vat_eur`/`vat_local`. Evidence pack: ZIP with the workbook, every vaulted invoice document
  (SHA-256-deduped) and a `manifest.csv` of per-file SHA-256s (the §3.K K4 manifest
  discipline). Refusals, all fail-CLOSED: `claim_not_frozen` (frozen lines only — the
  G2.5/ADR-P3 translation of Fleet Fuel's live-derived lines + separate legal DB),
  `synthetic_line_in_pack` via THE R3 predicate (`claim_gates.is_synthetic` — the workbook
  builder is C2's fourth named consumer and the FIRST blocking consumer wired anywhere;
  grep-test proves no rival predicate), `claim_totals_drift` (the renderer recomputes `q2`
  sums and refuses a frozen header its own lines cannot reproduce, §4.10),
  `claim_currency_mismatch` (defensive §4.14 twin of `freeze._sum_lines`),
  `evidence_document_unavailable` (dangling object-store reference — never an incomplete
  filing bundle). Free text through the ONE shared `core.csv_safety.sanitize_cell`
  (supplier names, invoice numbers, manifest filenames); money cells raw Decimal (a leading
  `-` is a negative amount). Read-only end to end: persists nothing, mutates nothing, audits
  nothing (grep-test), NO new table/migration (the WO-71 decision-7 precedent). Service-only;
  the `api/routes/transport/*` batch serves + permission-gates the bytes later. Follow-up
  recorded (WO-74 design decision 8): `lock.submit_claim` still lacks the R3 synthetic lock
  gate — a synthetic line can freeze but can never produce filing artifacts. 21 new tests
  (refusals incl. cross-tenant 404 + module gate, frozen-figure correctness, deterministic
  order, injection safety, vault-tree shape + segment sanitization, manifest hashes, dedup,
  withdrawn-claim reproducibility, the line-for-line identity proof). 79 tables, 84 revisions
  (unchanged). 1764→1785 passed (+21). Detail: `docs/plan/plan-a/wo/WO-74-G2.12.md`.

- [x] **WO-75** — `Completed` — the R3 synthetic-line refusal as a LOCK-GATE consumer in
  `lock.submit_claim` — the small, precisely-scoped gap WO-74's design decision 8 recorded
  (`BA_fleet_fuel.md` C2 — "A pack containing ANY synthetic line CANNOT be filed. The same
  predicate is used by: the lock gate (`bad = [... if _synthetic(r)]` → 'BLOCKED - unresolved
  invoice refs') ..."; R3 row line 1360). `claim_gates.py` gains the DB-backed pair mirroring
  `document_gate`'s shape: `unfrozen_synthetic_refs` (non-raising, sorted distinct offenders
  among the claim's materialized UNFROZEN lines — exactly the rows the G2.5 freeze would stamp,
  the same validates-what-gets-frozen reasoning as R10) + `enforce_no_synthetic_lines` (409
  `unresolved_invoice_refs` naming every offender, fail-CLOSED). Wired into `submit_claim`
  between R44 (activation) and R6 (duplicate machinery) — the harvested position: D5 names
  "synthetic/duplicate/document" in that order and C9's internal `set_status` sequence puts the
  `bad` gate before `claim_set`/locks/doc-gate/freeze. A refused submit mutates NOTHING (status
  `draft`, no `status_code`, no frozen lines, no `vat_eur`, zero lock rows — the D5 proof
  pattern, asserted). R15 interaction proven: a waived supplier's synthetic `INPUT` transactions
  never became lines (WO-58 "excluded by construction"), so waiving stays the legitimate path
  past this gate; a claim with NO materialized lines passes trivially (R10 semantics). 10 new
  tests (`test_r3_lock_gate.py`: refusal + nothing-mutated, INPUT-vat_id variant, position vs
  R6 and vs R10, waiver interaction, trivial pass, sorted/distinct/org-scoped scan,
  all-offenders-named, structural no-rival-predicate + gate-order). Fixture raises only, zero
  assertions weakened: new shared `register_documented_invoice` conftest helper; 9 pre-existing
  successful-submit tests raised to resolved+documented lines (g1_4 ×1, g2_11 ×2, g2_5 ×2,
  g2_6 submission-gates ×2, g2_6 annual-mop-up ×5 call sites across 5 tests); the g2_12
  frozen-synthetic test now seeds by direct row tamper (defence-in-depth: the pack still blocks
  a corrupted frozen set). No route, no table, no migration. 79 tables, 84 revisions
  (unchanged). 1785→1795 passed (+10). Detail: `docs/plan/plan-a/wo/WO-75-R3-lock-gate.md`.

- [x] **WO-76** — `Completed` — transport routes slice 1: the claim lifecycle over HTTP — the
  head of the M3 route batch (ADR-P3's `api/routes/transport/` file list; this slice ships
  `claims.py` only). NEW package `app/api/routes/transport/` (an aggregating `__init__.router`
  so `tests/test_authz_coverage.py`'s `pkgutil` enumeration keeps the package inside the
  structural-coverage net) with nine thin controllers: `GET/POST /transport/claims` (list +
  R1 idempotent get-or-create — deliberately 200 both calls, the service cannot lie a 201),
  `GET /{id}`, `GET/POST /{id}/lines` (R2 materialization + read), `GET /{id}/checklist` +
  `GET /{id}/stage` (advisory reads — NO commit, so even the evaluator's idempotent
  default-rule seeding is discarded with the request session; reading changes NOTHING, §4.19),
  `POST /{id}/submit` (the D5 chain R7→R8→R44→R3→R6→R15-stamp→R10→freeze→lock→"2") and
  `POST /{id}/withdraw` (R5). Structural authz on the EXISTING WO-49 permissions (no invented
  vocabulary): router-level VAT_READ, per-route VAT_WRITE (create/build-lines), VAT_SUBMIT
  (submit/withdraw — the ACCOUNTANT-books-but-cannot-submit split proven live on the wire).
  Every refusal is the SERVICE's own `AppError` code rendered by the one `app.main` handler
  (`module_not_enabled`, `claim_not_found`, `period_not_ended`, `below_minimum`,
  `customer_not_active`, `unresolved_invoice_refs`, `duplicate_invoice_lock`,
  `invoice_document_missing`, `claim_not_locked`, …) — routes map nothing, §4.20 additive-only;
  a 409 submit provably mutates nothing over HTTP (draft status, zero locks, zero frozen
  lines). `lock.submit_claim`'s `today` test seam deliberately NOT exposed (a client-supplied
  clock could bypass R7). Additive service read accessors (`claim.list_claims`/`get_claim`,
  `claim_lines.list_claim_lines`) keep the module gate + opaque-404 in the service layer —
  zero business logic in controllers. Money rides the wire as pydantic-serialized Decimal
  strings (§4.9, asserted: `"2000.00"`, never a float). Tenancy parity: `vat_refund_claims` +
  `vat_claim_lines` EXEMPT→real HTTP probes (overlapping bodies, opaque 404 both ways);
  remaining transport exemption reasons trued up. 20 new route tests + 2 new parity params;
  0 assertions weakened, 0 pre-existing tests touched. No table, no migration, no new
  permission, no SPA change. 79 tables, 84 revisions (unchanged). 1795→1817 passed (+22).
  Detail: `docs/plan/plan-a/wo/WO-76-transport-routes-1.md`.

- [x] **WO-77** — `Completed` — transport routes slice 2: the admin/config surfaces + the
  filing artifacts over HTTP. 27 more thin controllers on the EXISTING WO-49 permissions (no
  invented vocabulary), all aggregated through the same package `__init__.router`:
  **`claims.py` (+6, claim-scoped)** — waiver `GET/POST/DELETE` (R15; VAT_WRITE, because a
  waiver configures how lines are BUILT and flips no status), `POST /{id}/status-code`
  (R17/R12; VAT_SUBMIT — it is the claim-STATUS surface) and the two G2.12 FILING ARTIFACTS
  `GET /{id}/workbook` (xlsx) + `GET /{id}/evidence` (ZIP), closing `claim_pack.py`'s own
  recorded "no route exists yet"; **`admin.py` (new, org-level)** — the status-code
  VOCABULARY read, checklist-rule list/seed/`set_active` (R45), cadences `GET/PUT/DELETE` +
  the persisted receipt-control grid and its override (G3.5), note→invoice-ref overrides
  `GET/PUT` (R16), tie-out expectations `GET/PUT/DELETE` (R25 regime 2); **`customers.py`
  (new)** — the R44 lifecycle + per-country activation ladder, closing the gap
  `customer_lifecycle.py`'s docstring recorded ("no `api/routes/transport/*` route exists yet,
  so the admin-click requirement lands as the documented intent for that route's permission").
  Five additive service read accessors (`waiver.list_waivers`, `tie_out.list_expectations`,
  `invoice_match.list_note_overrides`, `customer_lifecycle.lifecycle_overview`,
  `status.list_status_codes`) each carry the module gate + opaque-404 fetch, and
  `checklist.list_rules` gains the gate now that it is route-facing (behaviour-preserving —
  its internal callers already gate first). Every refusal on the wire is the SERVICE's own
  code (§4.20 — routes map nothing): `waiver_supplier_has_invoices`, `claim_not_draft`,
  `checklist_rule_not_found`, `status_code_system_controlled`, `unknown_status_code`,
  `claim_not_submitted`, `invalid_cadence`, `invalid_period`/`invalid_currency`/
  `invalid_expected_lines`/`invalid_gross_tolerance`, `tieout_expectation_not_found`,
  `receipt_control_not_found`, `override_note_is_synthetic`/`override_target_not_registered`,
  `not_a_prospect`/`lifecycle_transition_invalid`/`invalid_country`/`country_not_requested`/
  `country_transition_invalid`, `claim_not_frozen`/`synthetic_line_in_pack`/
  `claim_totals_drift`/`evidence_document_unavailable`. THREE recorded judgment calls: the
  artifact downloads are VAT_READ (a read-only rendering of data `/lines` already serves —
  `EXPORT_RUN` guards the different accounting-ledger hub); `seed_default_rules` needed its
  own COMMITTING route precisely because the claim checklist GET never commits; and the
  status-code surface is the one VAT_SUBMIT verb here. TWO scopes deliberately NOT built and
  recorded rather than invented (§9/§10): no note-override DELETE (no removal FUNCTION was
  harvested — R16's lifecycle is CASCADE-on-de-registration) and no `STATUS_LABELS` read
  (Fleet Fuel's label map was never harvested as data — the route returns the ACTUAL
  `AUTO_CODES`/`MANUAL_CODES` vocabulary); `run_receipt_control`/`orphan_transactions` stay
  unrouted (R60 — the close never runs inline in a request). Artifact tests parse the REAL
  bytes: openpyxl asserts the workbook TOTAL row equals the frozen `vat_eur`, zipfile
  re-hashes every bundle entry against its `manifest.csv` SHA-256. Tenancy parity: EIGHT
  EXEMPT rows converted to real HTTP probes (`vat_receipt_waivers`, `vat_checklist_rules`,
  `vat_supplier_cadences`, `vat_receipt_controls`, `vat_note_invoice_overrides`,
  `fuel_tieout_expectations`, `vat_customer_lifecycles`, `vat_country_activations`); the four
  remaining transport exemption reasons trued up. 26 new route tests + 8 new parity params;
  0 assertions weakened, 0 pre-existing tests touched. No table, no migration, no new
  permission, no SPA change. 79 tables, 84 revisions (unchanged). 1817→1853 passed (+36).
  Detail: `docs/plan/plan-a/wo/WO-77-transport-routes-2.md`.

- [x] **WO-78** — `Completed` — transport UI slice 1: the VAT claims workspace. The M3 **UI
  batch opener** — the WO-76 claim lifecycle and WO-77 filing artifacts, until now reachable
  only with `curl`, become two SPA pages composed from the EXISTING ui primitives, TanStack
  Query and Tailwind (no new library, state manager, styling system or test framework).
  **`pages/VatClaims.tsx`** — the claims list (entity · refunding country · reference period ·
  status + workflow code · frozen VAT total) with real loading / empty / error states via
  `QueryState`, and a VAT_WRITE-gated create form on the R1 grain whose button reads "Open or
  create" because `get_or_create_claim` is idempotent. **`pages/VatClaimDetail.tsx`** — the
  filing workspace: the grain + status header, the R2-grain lines table (unresolved refs
  badged), the ADVISORY checklist panel (a failing item NEVER disables Submit — §4.19), the
  stage/status-code ladder built from `GET /transport/status-codes` (the service's OWN
  vocabulary — no label map is invented, WO-77 decision 5 respected), the totals exactly as
  the service froze them, the lifecycle actions and the two artifact downloads.
  **THE SUBMIT UX IS THE POINT:** every D5 refusal code is mapped in a pure, testable module
  (`lib/transportClaims.ts::claimRefusal`, 23 codes read off the services) to a sentence that
  says what is wrong AND what to do next, with the server's own `detail` (which names the
  suppliers / refs / period) rendered underneath as the specifics — the raw slug reaches the
  screen NOWHERE, asserted per code. `below_minimum` additionally surfaces the
  `override_minimum` path the `ClaimSubmitIn` schema already carries, VAT_SUBMIT-gated like
  the submit itself and stated to be recorded on the claim. **Money never round-trips through
  a float:** `format.decimalMoney` formats the wire Decimal STRING by string surgery (no
  `Number()`, no arithmetic, no rounding); a null total renders as an em dash, never `0.00`
  ("not frozen yet" ≠ zero). **The UI computes no total** (§4.10) — proven by a fixture whose
  lines deliberately do not sum to the frozen header. Permission gating mirrors
  `authz.ROLE_PERMISSIONS` cosmetically (`roles.hasVatPerm`) so no dead button is rendered —
  explicitly NOT a boundary, the server still refuses. Nav: a "Transport" group gated on the
  `transport` module AND a new optional `perm` flag on `LiveNavItem` (its absence leaves every
  existing item's filtering byte-identical). TWO limitations recorded rather than invented
  around (§9/§10): the claim-line grain carries NO supplier column, and no route enumerates
  fuel transactions (`fuel.py` does not exist), so the submit dialog's
  `(supplier, invoice_ref, fuel_transaction_id)` set is operator-supplied, pre-seeded from the
  non-synthetic line refs. 29 new Playwright specs in the repo's existing `page.route`-mocked
  live-app harness, added to the `test:e2e` script CI runs: 31→60 frontend e2e passing.
  ZERO backend change — no route, no schema, no permission, no migration; the backend suite is
  unchanged at 1853 passed / 10 skipped. 45→47 SPA pages.
  Detail: `docs/plan/plan-a/wo/WO-78-transport-ui-1.md`.

- [x] **WO-79** — `Completed` — the fuel-transaction READ surface + the submit pick-list it
  unlocks. Closes both limitations WO-78 recorded, and one the tenancy suite had carried since
  WO-50. **The gap:** `fuel_transactions` — the typed line item every claim is built from —
  had existed since WO-50 with `fuel_ingest.ingest_transaction` as its only writer and NO code
  path that returned one (`grep -rn "FuelTransaction" app/api` was empty). Consequences:
  `test_tenancy_parity.py` carried it as an EXEMPT row whose own reason read "Still no route
  RETURNS these rows"; and the WO-78 submit dialog had to ask an operator to TYPE a supplier
  and a fuel-transaction UUID, because the `(supplier, invoice_ref, fuel_transaction_id)`
  tuples `lock.submit_claim` keys its locks on had no enumerable source.
  **`services/transport/fuel.py::list_fuel_transactions`** — the additive read accessor in the
  transport-standard entry-point order, failing CLOSED: module entitlement → org-scoped
  `issuer.get_by_id` (opaque 404 `entity_not_found`, §4.4) BEFORE any transaction row is
  touched → period resolution. Required `entity_id`+`period`, optional `supplier`/`country`
  (country matters: `build_claim_lines` scopes a claim's transactions by country of supply, so
  a pick-list ignoring it would offer rows the claim provably excludes). `period` takes the
  model's own `YYYY-MM` **or** a claim reference period, expanded through the EXISTING shared
  `claim_lines.period_months` — guarded by `claim.validate_ref_period` first, because that
  helper is deliberately trusting and would otherwise read `"2026-13"` as Q3. Pagination
  reuses the `InvoiceListOut` envelope with the large-list bounds of expenses/email (100/500);
  `total` and the page come from the SAME filter set. **`schemas/transport_fuel.py`** — every
  amount and `qty` typed `Decimal`, so they cross the wire as exact strings (§4.9), with the
  FX provenance quadruple carried verbatim (§4.15 is worthless without it).
  **`api/routes/transport/fuel.py`** — one thin controller, router-level VAT_READ (ADR-0024
  structural). The permission is a RECORDED judgment: `TRANSPORT_READ` exists and stays
  reserved for the derived analytics/excise slices, while these rows ARE the claim's evidence
  base — the same set `/claims/{id}/lines` already serves aggregated under VAT_READ; both
  permissions have byte-identical role coverage, pinned by a test so a future matrix split has
  to revisit this gate deliberately. No permission member added. Read-only by construction: no
  POST/PATCH/DELETE, so no audit event and no SoD question. **Tenancy:** `fuel_transactions`
  EXEMPT → a real HTTP probe over identical overlapping data in both orgs; the three remaining
  transport exemptions' reason text trued up to state what WO-79 did NOT route.
  **The pick-list (WO-78 deviation 2, closed):** the submit dialog reads
  `GET /transport/fuel-transactions` at the CLAIM'S OWN grain and each ticked row contributes
  its own tuple — supplier and UUID never typed again; the invoice reference stays editable
  because that column is nullable by design while `SubmitInvoiceIn` requires a non-empty one.
  The typed path survives as "Add a row manually" and is the fallback (pre-seeded exactly as
  WO-78 did) when the period is empty or the fuel read fails — derived at render, not pushed
  by an effect. Money/litres still render with no `Number()`/`parseFloat`; the pick-list adds
  no gate and never disables File claim (§4.19); the page still computes no total (§4.10).
  **WO-78 deviation 1 (a supplier column on the claim-line table) is deliberately NOT built**
  and the page docstring + the WO doc record why: a claim line carries the RESOLVED AP invoice
  number while a transaction carries the RAW statement note (`invoice_match` exists precisely
  because those differ), `FuelTransaction.invoice_id` is never populated by any service, and
  an `UNMATCHED` line aggregates every unresolved supplier — there is no unambiguous link on
  the wire, and a guessed supplier on a filing surface is worse than an absent one. The honest
  fix is a backend one (carry the supplier through `build_claim_lines`), proposed as the next
  slice. 11 new route tests + 1 new tenancy-parity probe param; 10 new Playwright specs
  (60→70 frontend e2e passing). No migration, no model change, no new SPA page.
  Detail: `docs/plan/plan-a/wo/WO-79-fuel-read-surface.md`.

- [x] **WO-80** — `Completed` — transport UI slice 2: the admin/config workspace. Closes the
  gap WO-78's own anti-scope clause named: `api/routes/transport/admin.py` (14 routes) and
  `customers.py` (7 routes) were live, gated and tested, and `grep -rn "checklist-rules|
  cadences|receipt-controls|note-overrides|tie-out-expectations|transport/customers"
  frontend/src` returned NOTHING — WO-78 consumed exactly one of them (`GET
  /transport/status-codes`). Two of the claim workspace's own refusal sentences
  (`customer_not_active`, `country_not_activated`) told an operator to do something that had
  no screen. **`pages/VatAdmin.tsx`** — one tabbed page (`/vat-admin`, the existing
  `Tabs`/`TabPanel` primitives, no new navigation pattern) with six panels, each reading only
  its own route when its tab is open: checklist rules (list · the COMMITTING seed · per-key
  active toggle), the persisted receipt-control slot grid + its mute/annotate override,
  cadences (assign from the harvested closed set · drop back to the default), note→invoice-ref
  mappings (list · set), tie-out expectations (list · upsert · delete by natural key) and the
  status-code vocabulary as a REFERENCE panel that links to the claim rather than duplicating
  the VAT_SUBMIT action. **`pages/VatCustomers.tsx`** — `/vat-customers`: the R44 lifecycle
  ladder and every per-country activation row, the state named in words (a `null` status reads
  "Never onboarded" — the real state the gate refuses, never blank and never an error), and
  only the transitions legal from that state offered. **`pages/VatClaimDetail.tsx`** gains the
  claim-scoped R15 waiver panel — the one WO-77 surface that is claim-scoped, so it belongs on
  the claim, not on the configuration page. **The advisory/gate distinction is carried in the
  COPY and asserted as text** (§4.19): the receipt-control board states it "blocks no claim,
  halts no close and changes no figure" and names its mute as a worklist mute rather than
  R15's legal waiver, while the tie-out panel states the opposite — "These stop the monthly
  close" — because that one really does (R25 regime 2). **Nothing the backend lacks was
  invented** (§10): no note-override DELETE (no service function — WO-77 decision 6, the
  absence is asserted by a test), no receipt-control RUN trigger (R60), no orphan view, no
  status labels, no entity name on a transport surface (the issuer registry is a convenience
  on a DIFFERENT permission that degrades to a typed id). Fifteen WO-77 refusal codes joined
  the ONE refusal map, each read off the service that raises it, so `RefusalNotice` renders
  the new screens unchanged; every mutating control is hidden without the mirrored VAT_WRITE
  and the server's 403 still renders. No figure is parsed, summed or re-formatted: a 16-digit
  tie-out gross renders and re-posts with its exact digits, untyped optional figures post as
  `null` (not zero), and the single integer field is a line COUNT. 47 new Playwright specs
  (70→117 frontend e2e passing) across the new `e2e/vat-admin.spec.ts` and the claims spec;
  two pre-existing pick-list selectors SCOPED to the submit dialog (a strengthening — no
  assertion weakened). ZERO backend change: 1865 passed / 10 skipped, unchanged.
  Detail: `docs/plan/plan-a/wo/WO-80-transport-ui-2.md`.

- [x] **WO-95** — `Completed` — **G2.9/R13: fee freezing on the contingency model — the LAST
  M3 *service* row, and the first code ever to write `vat_refund_claims.fee_pct`/`fee_min`/
  `fee_eur` (present but empty since WO-49).** Unblocked by the owner decision of 2026-08-08
  (`docs/DECISIONS-NEEDED.md`): **a contingency fee on recovered VAT, no-win-no-fee** — with
  the percentage and any minimum **explicitly left open**, which is what this order is
  designed around. `app/services/transport/fee.py`: C11's formula verbatim
  (`max(pct% x base, min)` returning C11's own `(fee, basis)` pair, pure and synchronous so
  R40's *"reusing the same fee function the real claim uses"* costs no second implementation;
  the EXACT TIE belongs to `percent` because a percentage equal to the minimum has not
  *"fallen below"* it, asserted on both sides one cent apart) and C11's resolution chain
  *"per-(customer, country) override -> customer default"* widened by the org-level STANDARD
  rung R40 names (*"Standard fee is admin-editable; a per-client fee overrides it"*) and the
  decision names again. New tenant table `vat_fee_rates` (migration `d4c7b1e93f27`, FORCE RLS
  in the same migration): three rungs in one table, uniqueness by a plain constraint for the
  two customer rungs PLUS a **partial unique index `WHERE entity_id IS NULL`** — SQL treats
  NULLs as distinct, so a plain UNIQUE would store two org standards and force the resolution
  walk to pick one arbitrarily. **THE GOVERNING CONSTRAINT — no invented rate.** C11's
  terminal `(0, 0)` rung is replaced by a **refusal** (`fee_rate_not_configured`) and
  Appendix B's `pricing_fee_pct 15%` is not used: a frozen `fee_eur = 0.00` is a positive
  assertion that a filing earns nothing, which nobody made, and under no-win-no-fee a silent
  zero either forfeits the vertical's entire revenue or is later "corrected" by rewriting a
  frozen figure — exactly what R13 exists to prevent. The excise placeholder precedent
  deliberately does NOT transfer (that rate is advisory, labelled indicative on every surface,
  and belongs to a member state; this one is ours and binding). An explicitly typed `(0, 0)`
  IS accepted and audited — the refusal is about ABSENCE, and a typed zero is a decision.
  **BEHAVIOUR CHANGE, stated loudly:** an org with the module enabled and no configured rate
  can no longer submit a claim (409 `fee_rate_not_configured`, message naming what to
  configure). In `lock.submit_claim` the work is split on purpose: `resolve_fee_rate` is a
  PURE READ running as the **LAST gate** — after every statutory gate, before the freeze — so
  a missing rate refuses while the session is still unmutated (this function's own contract,
  *"nothing is mutated before the LAST gate passes"*, holds exactly) and a legal problem is
  always reported ahead of a commercial one (asserted against both R7 and R10, not assumed);
  `freeze_fee` then stamps the three columns from the base `freeze_claim_lines` just froze, in
  the SAME flush as the locks and the status flip, because C10 names the VAT base and the fee
  in one sentence. R13's acceptance line proven both ways — changing the rate after submission
  changes nothing, and neither does DELETING every rate. The claim-identity blocker
  `DECISIONS-NEEDED.md` §10 recorded (*"no mapping from a claim to a billable customer"*) was
  **stale, not solved by invention**: WO-73 had already shipped `VatCustomerLifecycle`, keyed
  `(org, entity_id)`, literally named for the customer, and gating every submission. **D7
  answered from the spec and pinned:** withdrawal does NOT clear a frozen fee — D7 enumerates
  the locks and `status_code` and nothing else, `withdraw_claim` leaves `vat_eur` standing
  too, and a withdrawn claim never returns to `draft` (WO-94) so the fee can never be
  re-frozen or contradicted; `withdraw_claim` is untouched. **Partial rejection is NOT built**
  — a documented seam only, per the owner-confirmed §13 follow-up. Audit: the freeze rides the
  existing `transport.claim_submit` event with old->new for all three columns plus the BASIS
  and the RUNG (WO-94's one-event-per-lifecycle-moment precedent, and a test asserts no
  separate `transport.fee_freeze` action exists); the rate CRUD carries its own audited
  old->new with an idempotent no-op. **R39 (WO-93) re-proven, not weakened:** all three WO-93
  files pass **byte-for-byte unmodified** — verified by `git diff` — and the shared
  `conftest.enable_transport` now seeds the org's standard rate (the WO-73 `activate_entity`
  fixture-raising precedent applied at the one place every transport fixture org passes
  through), so their previously-VACUOUS wire scan now runs over a claim carrying a real frozen
  fee; a new WO-95 file proves that de-vacuuming explicitly, re-asserts the absence over the
  populated portfolio with a seeded-violation self-test, and adds a second structural ban (the
  client surface may not even IMPORT the fee module). No route and no SPA change: the
  operator-facing claim schema has exposed the three fields since WO-49, and the rate has no
  admin screen because the number it holds is still an open owner decision — `vat_fee_rates`
  is classified EXEMPT in the tenancy-parity board with that reason, in its own commit.
  Detail: `docs/plan/plan-a/wo/WO-95-fee-freezing.md`.

---

## M5 — In Progress

- [x] **WO-81** — `Completed` — G4.3/R38: the cash-recovery analytics service + its read
  route. The first transport surface that answers a question about the PORTFOLIO rather than
  about one claim — *"how much money can we still recover this refund year, and what is
  stopping each euro of it?"* `app/services/transport/recovery.py::recovery_dashboard` buckets
  every claim of a year into the six harvested readiness states (`ready · deadline · missing ·
  below · submitted · paid`, `BA_fleet_fuel.md` §2.4) and totals the north-star euros:
  recovered, awaiting, claimable, the deadline-risk count and the median days-to-refund.
  **R38's binding constraint is honoured literally — nothing computes a figure of its own:**
  the claim set comes from `claim.list_claims` (which gains an ADDITIVE `year` keyword, so the
  ONE listing query stays one), a draft's stage from `status.derive_stage`, its VAT base from
  `freeze.preview_vat_base` (the same preview `submit_claim` gates R8 on), the Art. 17
  threshold from `minimum.below_minimum` and the time-bar from `deadline.deadline_status` —
  the pure functions `deadline.py`'s own docstring said "a future dashboard (G4.3)" would
  consume. FOUR interpretations the spec does not settle are documented in the module and the
  rule row: stage `1B` folds into `ready` (no seventh bucket is invented); a waiver-only `1C`
  is `ready`, not `below` (only a threshold caveat is a threshold problem); `deadline` means
  "otherwise fileable with the clock running", so a blocked claim keeps its BLOCKING bucket and
  is still counted in the SEPARATE `deadline_risk_claims`; and `withdrawn`/`rejected` are
  reported in an `excluded` block by reason, with `Σ buckets + Σ excluded == total_claims`
  asserted. **§4.14 over multi-country claims:** every euro is the single-currency `vat_eur` —
  `vat_local` and the currency-ambiguous `paid_amount` are never read (an AST assertion pins
  that absence) — and a draft whose lines span currencies is caught PER CLAIM: it buckets
  `missing`, contributes `0.00`, and increments `currency_mismatch_claims`, so one bad claim
  never blanks a year and no foreign amount is ever labelled EUR. §4.9 throughout, including an
  exact-`Decimal` median so no float can arrive via `statistics`. `GET /api/v1/transport/
  recovery-dashboard?year=` is one thin controller on `TRANSPORT_READ` — the permission WO-79
  explicitly RESERVED for this derived-analytics slice — with Decimal-as-string on the wire,
  200-with-zeroes on an empty year and 422 `invalid_year` otherwise. Read-only: no write, no
  audit row, no commit, no migration, no new permission member, and no tenancy-parity exemption
  changes (the response is aggregates only — no row, no object id). TWO deviations recorded
  rather than faked: the `overcharges` euro needs G4.5's absent `contract_audit`/`overcharge`
  service, so the field is OMITTED (a zero would read as "we found no supplier breaches"); and
  nothing writes `submitted_date`/`paid_date` yet (G2.9, decision-gated), so the median ships
  with a `days_to_refund_sample` beside it and `null` reads as "no claim has both dates". Also
  records `docs/DECISIONS-NEEDED.md` §11 (claim-line supplier attribution) — stated, not
  decided. Detail: `docs/plan/plan-a/wo/WO-81-recovery-analytics.md`.

- [x] **WO-82** — `Completed` — G4.5/R41: supplier overcharge detection + the claim-back
  lifecycle, and the north star it feeds. The order that CLOSES WO-81's deviation 1 — the
  dashboard's `overcharges` euro, which that order deliberately OMITTED rather than emit as a
  misleading zero ("we found no supplier breaches" is a different and false statement).
  **(1) DETECTION** (`app/services/transport/contract_audit.py`, READ-ONLY over
  `fuel_transactions`): the harvested contract audit, `BA_fleet_fuel.md` §2.5 verbatim — the
  *"two term types only"* (`expected_discount_eur_l`, a rebate in €/L; `max_net_eur_l`, a
  contracted NET price ceiling in €/L) stored on §4.4's own `supplier_discounts` grain
  (`supplier × country × station_like × product_group`, `active`); the two flag strings verbatim
  (`"short discount"` when `applied < expected − tol`, `"over ceiling"` when `eff_l > max + tol`)
  at the harvested **`TOLERANCE = 0.005 €/L`**; `recover_eur = gap × litres`, *"dropped if ≤ 0"*.
  §2.5's closing sentence is honoured as a CONSTRAINT — **no volume-tier / stepped-rebate /
  annual-bonus / card-fee modelling** — so a term the model cannot express is stated, never
  approximated. BASIS **NET EUR/L, final — VAT excluded, rebates applied** (§3.G G1 / R49,
  verified against the spec rather than assumed): the discount ACTUALLY applied is
  `net_eur/qty − net_eur_eff/qty`, which is §4.2's own two-tier discount model read as an
  identity; the basis string AND R53's *"Money the supplier owes"* framing ride the result so no
  surface can render the euro without them. §4.9: comparisons on UNROUNDED `Decimal` quotients so
  a boundary can never flip on a rounding — the EXACT-boundary case (applied == expected,
  `eur_l_eff` == max) yields NOTHING, proven on both sides one 0.0001 step apart — with the gap
  quantized once to 4 dp and the euro once through `money.q2`. §4.14: EUR-only with no coercion
  anywhere (both price columns are EUR by construction, so a supplier month spanning EUR and PLN
  totals natively in EUR); the three document-currency amount columns are NEVER read (asserted
  structurally by name) and a line's own currency rides each finding as provenance that is never
  totalled. Three fail-safe readings, documented: exactly ONE term applies per line (most
  specific wins — two overlapping terms would DOUBLE-COUNT real money); **no configured term ⇒ no
  finding at all**, counted as `lines_without_terms` (never a false positive); a `qty <= 0` promo
  line is skipped, never divided by. Detection writes nothing — proven structurally and by a
  column-for-column before/after comparison of every fuel transaction. **(2) THE CLAIM-BACK**
  (`app/services/transport/overcharge.py`): §4.5's chain drawn LITERALLY — `detected → packaged →
  claimed → recovered | rejected | written_off`, the three outcomes terminal, no shortcut edge
  invented (the WO-73 `inactive`-is-terminal precedent). An illegal edge is 409
  `overcharge_transition_invalid` with NOTHING mutated (asserted column-for-column); every real
  move is audited old→new in the same transaction (§4.16). The euro is FROZEN at `open_claim`
  (the G2.5 reasoning applied to a demand letter), `open_claim` is idempotent on
  `(org, supplier, period)` and refuses 422 `no_overcharge_detected` when nothing was found, and
  `recovered_eur` is bounded to `(0, detected_eur]` (§4 invariant 13 — a north-star total
  unbounded by its own evidence is not a measurement). **(3) THE NORTH STAR**:
  `recovery.recovery_dashboard` now carries `overcharges_eur`, obtained by CALLING
  `overcharge.recovered_total(year=…)` — R38's never-a-forked-query clause honoured; it is §2.4's
  BOOKED-CASH reading (*"`recovered_total()` = the booked-cash north star"*), not the €-exposure
  detected, and it sits deliberately OUTSIDE the `recovered + awaiting + claimable` VAT
  reconciliation, which is unchanged. **(4) THE ROUTE**:
  `app/api/routes/transport/overcharges.py` — the term admin, the audit read, the worklist, the
  total and the two lifecycle verbs on router-level `TRANSPORT_READ` (the reservation `fuel.py`
  recorded names this module by name) with writes overriding to `VAT_WRITE` (the `admin.py`
  `_WRITE` pattern; `VAT_SUBMIT` stays reserved for lock-acquiring VAT-claim actions). No
  permission member invented, and the split is load-bearing: an AUDITOR reads the worklist and
  cannot drive it. Migration `a7c2e9f14b58` (2 tenant tables, FORCE RLS in the same migration,
  up/down/up verified on a scratch Postgres 16 with the pg-only files green on a NOSUPERUSER
  role); both tables classified as REAL tenancy-parity HTTP probes in the same commit that
  created them — never EXEMPT. 81 tables, 85 revisions. **DEFERRED here, SHIPPED in WO-83:** R41's two
  send-ready ARTIFACTS (the Excel evidence packet and the formal PDF claim letter with a 30-day
  credit/refund demand, *"built from the SAME line source"*) were a named follow-up slice of
  G4.5 — `contract_audit.audit()` already IS that single line source, which is exactly what made
  the *"identical lines and totals"* acceptance structural rather than coincidental (the G2.12
  `claim_pack` precedent). Detail: `docs/plan/plan-a/wo/WO-82-overcharge-claimback.md`.

- [x] **WO-83** — `Completed` — G4.5/R41 + R53: R41's two send-ready ARTIFACTS, off the ONE line
  source. The follow-up slice WO-82 named in its own out-of-scope section and this board's M5
  cell recorded as the recommended next one — **R41 is now CLOSED**.
  `app/services/transport/overcharge_pack.py` renders the Excel EVIDENCE PACKET
  (`build_evidence_packet`) and the formal PDF CLAIM LETTER (`build_claim_letter`) from
  `contract_audit.audit()` — the single line source R41 names, and the same call
  `overcharge.open_claim` snapshots. **R41's acceptance is proven twice.** STRUCTURALLY, three
  times over: one `_load_packet()` (loaded once, rendered twice), one `_COLUMNS` spec both
  renderers project through the same accessors over the same `Breach` objects, and two SYNC
  renderers that take no `AsyncSession` and therefore cannot reach a second source even by
  accident. Then CELL-FOR-CELL: the generated bytes are really parsed (openpyxl over the
  `Evidence` sheet, pypdf over the letter text) and both compared against the SAME hand-computed
  Decimals — the G2.12/`claim_pack` precedent applied to the surface `claim_pack`'s own docstring
  said it was standing in for. **The packet**: the breach lines with flag, agreed/actual €/L,
  gap, litres and recoverable EUR, a bold TOTAL row, and workbook-only LINEAGE columns (claimant
  entity, invoiced/effective €/L, document currency, transaction id) that a one-page A4 letter has
  no room for. **The letter**: our letterhead from the existing `IssuerProfile` registry (resolved
  READ-ONLY — `list_issuers`/`get_by_id`, never `get_or_create`, which COMMITS a row and would make
  a read-only artifact a writer), the supplier's own per-country legal entity (R20/R21, marker-only
  via `supplier_entity.get_registration`; an unregistered country prints the supplier code and
  invents NOTHING), the SAME table, and §2.4's demand verbatim — a **credit note or refund within
  30 days** (`DEMAND_DAYS = 30`, harvested twice at §2.4 lines 221 and 236), with the due date
  printed as letter date + 30. **R53 carried, not paraphrased**: both artifacts PRINT
  `contract_audit.LEGAL_FRAMING` and `PRICE_BASIS` — the same constants the JSON API returns — so
  a framing cannot drift from surface to surface; R53 gets its first real consumer and its own
  ledger row. **FOUR fail-CLOSED refusals, each because the alternative is a MISLEADING document**:
  `no_overcharge_detected` (422 — an empty packet reads as *"we found nothing owed"*);
  `overcharge_evidence_drift` (409 — the live line source no longer reproduces the FROZEN
  `detected_eur`, so the demand and its own enclosure would disagree: the
  `claim_pack.claim_totals_drift` twin, §4.10, with the missing re-snapshot edge RECORDED in
  `docs/DECISIONS-NEEDED.md` §13 rather than invented); `overcharge_claim_closed` (409, LETTER
  ONLY — a live 30-day demand must not assert a debt the ledger records as
  `recovered`/`rejected`/`written_off`, while the PACKET stays reproducible in every state per
  WO-74's *"reproducing what WAS filed is audit-trail behaviour"*); and
  `issuer_profile_incomplete` (409, letter only, naming the missing Art. 226 fields). **The
  routes**: `GET /transport/overcharges/{id}/packet` and `.../letter` on the SAME router-level
  `TRANSPORT_READ` — generation is a READ (nothing persisted, mutated, audited or committed),
  which is why an AUDITOR downloads both and still cannot advance the worklist; correct media
  types, `content_disposition` filename and `nosniff`, the WO-77 artifact-download precedent.
  **NO new table, NO migration, NO new permission, NO new dependency** (openpyxl and reportlab
  are already pinned; degradation mirrors `invoice_pdf.PdfUnavailable` as a 503
  `pdf_renderer_unavailable` `AppError` so the route stays a thin controller). Building both
  artifacts leaves the claim-back and every fuel-transaction column byte-identical and writes no
  audit row — asserted, not promised. Detail:
  `docs/plan/plan-a/wo/WO-83-overcharge-artifacts.md`.

- [x] **WO-84** — `Completed` — G4.2/R50: the OFF-INVOICE rebate merge into `net_eur_eff` and its
  SOURCE GUARD. **The recon this order opened with is the finding:** `net_eur_eff` had exactly ONE
  writer (`fuel_ingest.ingest_transaction`'s `= net_eur` default) and no production caller ever
  passed a value — `statement_ingest` omits the argument and all seven G3.2 parsers say so in as
  many words — so it was an exact COPY of `net_eur` on every stored row, while
  `contract_audit._breach_for` already read it as though a merge had happened. Its
  `applied = eur_l_doc − eur_l_eff` term was therefore identically `0.0000`, and every line
  governed by an `expected_discount_eur_l` term flagged `short discount` for the FULL contracted
  rebate — a euro `overcharge.open_claim` FREEZES and WO-83's claim letter PRINTS in a 30-day
  payment demand. The platform was demanding money that a supplier paying off-invoice had already
  paid, which is exactly why this order had to follow WO-82/WO-83 rather than precede them: the
  wrong number had become client-reachable. **The merge** (`app/services/transport/rebate.py` +
  `vat_off_invoice_rebates`, grain `(org, supplier, country, period, source_ref)`) implements §4.2's
  two-tier discount model verbatim — an on-invoice discount is *"already inside `net_eur`"*, an
  off-invoice rebate *"lands ONLY in `net_eur_eff`"* — with the ONE thing the spec does not supply,
  the allocation formula, stated as a DOCUMENTED INTERPRETATION rather than guessed (the
  `contract_audit._specificity` precedent): **pro-rata by litres**, because §5.1's rebate vocabulary
  is uniformly €/L, because it makes `applied` a CONSTANT €/L (the shape a €/L term is compared
  against), and because a value-weighted alternative would manufacture findings on the expensive
  lines. Rounding is cumulative-then-quantize so the shares sum EXACTLY to the recorded euro — the
  10.00-over-three-lines case (3.33/3.34/3.33) is asserted, where independent quantizing would have
  silently lost a cent onto a price surface. **Idempotent by construction**: the effective net is
  always recomputed from the AS-INVOICED `net_eur`, never from the column's current value, so a
  re-close writes nothing and audits nothing (asserted as an ABSENCE — no second audit row) and a
  corrected rebate document self-heals instead of compounding a delta. **The ENGINE owns the write
  (§3.H)**: `record_rebate` is web-reachable and touches no transaction (also asserted as an
  absence, over HTTP); the merge is the FIRST `close.run_close` stage, every changed figure audited
  old→new (§4.16), a refusal riding `jobs.run_once`'s whole-session rollback. **THE SOURCE GUARD,
  BOTH HALVES OF §4.2's HAZARD** (*"swapping in the raw file silently loses the rebate layer"*):
  (1) a rebate is never INFERRED — `merge_period` reads recorded rows and has no derivation path,
  and `record_rebate` refuses a blank or WHITESPACE `source_ref`/`source_party` fail-CLOSED before
  any query (`rebate_source_required`), repeated as database `CHECK`s so no raw path bypasses it;
  (2) a rebate layer never silently DISAPPEARS — a question about a period with NO row, answered by
  `missing_source_warnings`, which learns the expectation from the registry's own HISTORY exactly as
  §2.5's "Expected rebate" prescribes (that row's rationale names this very case) and rides
  `ContractAuditResult.source_warnings` additively (§4.20), ADVISORY per §4.19 — R50's acceptance is
  *"fails **or** warns loudly"*, so this WARNS at the analytics surface and FAILS wherever a wrong
  figure would be written (`rebate_has_no_transactions`, `rebate_no_litres_to_allocate`,
  `rebate_exceeds_net`, each two-phase so a refusal leaves ZERO rows changed). It is deliberately
  SILENT for a supplier that never had a layer — proven in both directions. **§4.15 is live**: a
  non-EUR rebate converts through `fx.to_eur` at the document's own date (ECB units per 1 EUR, so
  converting DIVIDES) and is REFUSED with no row when the cache has no rate; there is deliberately
  no `stated` branch, because a rebate invoice states an amount and never a rate. The merge sums
  `amount_eur` only, so §4.14 holds structurally. **Consumer impact proven, not asserted**: the same
  term over the same line yields a €50.00 short-discount demand BEFORE the merge and NO finding
  after it, while a genuinely short rebate still reaches WO-82's own €150.00; `contract_audit`'s
  arithmetic is BYTE-UNCHANGED and both WO-83 artifacts quote the post-merge figure by construction
  (one line source, never forked). ONE new tenant table with FORCE RLS in the same migration and a
  real HTTP tenancy probe in the same commit that created it; `TRANSPORT_READ` reads /`VAT_WRITE`
  writes, NO permission member invented, NO SPA change. 82 tables, 86 revisions. Detail:
  `docs/plan/plan-a/wo/WO-84-net-eur-eff-merge.md`.

- [x] **WO-85** — `Completed` — G4.1/R51: **the canonical query registry**
  (`app/services/transport/queries.py`) and the structural proof that a future consumer cannot
  silently fork one. **The recon is again the finding**: R38's *"never a forked query"* clause had
  been honoured by HAND since WO-81, and hand-discipline had already slipped once. Eighteen call
  sites built a row-selection predicate over the two money-bearing transport tables, and among them
  sat ONE byte-identical fork in the claim-building path — `claim_lines.build_claim_lines` (what a
  claim's lines are BUILT from) and `checklist._unresolved_suppliers` (what the checklist REPORTS as
  blocking that same claim) carried the same four predicates written out twice, with nothing
  stopping one from acquiring a fifth: a drift there files a claim short (VAT forfeited at the
  30-Sep time-bar) or chases a supplier who was never in scope. A second shape was written three
  times — "the claim's currently-unfrozen lines", the set `lock.submit_claim` is about to freeze,
  re-typed by R3's synthetic-ref gate, R10's document gate and G2.5's freeze/preview; `claim_gates`'
  own docstring named the hazard (*"never two independent line-scans that could drift"*) and then
  mirrored the shape by hand. A FOURTH writer of that same cut was the `DELETE` inside
  `build_claim_lines` — the dangerous one, because a drift there removes rows rather than merely
  misreporting them, so the registry exposes it as bare criteria (`vat_claim_line_criteria`) rather
  than leaving it outside. Plus fourteen hand-typed `org_id ==` filters, each individually correct
  and each an independent chance to omit the one thing whose absence returns another tenant's rows
  with a **200** (§4.1/§4.4). **The registry**: six named, pure, org-scoped `Select` builders — no
  `AsyncSession`, no `await`, no `Decimal`, asserted structurally — under a stated charter *"the
  registry owns WHICH ROWS (the WHERE clause); the consumer owns HOW THEY ARE READ"*, so projection
  (`with_only_columns`), ordering, grouping and pagination stay at the call sites where their own
  docstrings already explain them. The module NAME is the spec's own vocabulary (`queries.q_savings`
  §2.4, `queries.q_ledger` §N10); the `q_` prefix is a Fleet Fuel stylistic detail and this
  codebase's naming convention governs instead — recorded as an interpretation, the WO-82/WO-84
  tie-break precedent. **Behaviour preserved where the tree was inconsistent, and reported rather
  than "cleaned up"**: three call sites treated a falsy `supplier`/`country` as "every"
  (`if supplier:`) and one treated it as a literal (`is not None`), so the registry filters on
  `is not None` and the falsy-tolerant sites bridge with `or None` — unifying them on one truthiness
  rule would have silently changed one of them, and `""` reaching `missing_source_warnings` is the
  one place where a migration WOULD have moved a figure. `fuel`'s `country.upper()` likewise stays
  at its call site: a registry that normalised would change what every other consumer matches.
  **The real deliverable is the guarantee, not the file**: an AST scan over
  `app/services/transport/` **and** `app/api/routes/transport/` refuses any `select()` over
  `FuelTransaction`/`VatRefundClaimLine` and any `<Model>.org_id` filter outside the registry, ships
  a seeded-violation self-test (template rule 6 — a scan that cannot fail proves nothing), and was
  demonstrated against the real tree by re-introducing the `checklist.py` fork and watching it named
  by file and line. R51's own acceptance is asserted both ways: *"no duplicate implementation
  exists"* by the scan, *"rename a canonical function ⇒ every consumer breaks"* by a no-orphan check
  over every registry entry. **PARTIAL HARVEST, documented, not silently skipped**: R51's
  materialised-metric half (*"a drift check that recomputes through the same code path… an
  un-materialized period still renders via a live fallback"*) has NO subject — all seventeen
  `app/models/transport/*` tables are sources of record, none a rollup — so building a drift check
  over nothing would be invented functionality (§10); its trigger is named (the first transport
  rollup table). `queries.q_savings`/`q_ledger` themselves belong to G4.7 and the export hub and are
  deliberately not invented here. Read-only refactor: NO table, NO migration, NO route, NO SPA
  change, NO permission, and not one pre-existing test file edited. 82 tables, 86 revisions. Detail:
  `docs/plan/plan-a/wo/WO-85-canonical-query-registry.md`.

- [x] **WO-86** — `Completed` — transport UI slice 3: **the recovery intelligence workspace**
  (`frontend/src/pages/RecoveryDashboard.tsx`, `Overcharges.tsx`, `Rebates.tsx`). WO-80's own
  closing note named what it left open — *"what remains of the UI batch is the ANALYTICS surface,
  which has no backing service yet"* — and WO-81/WO-82/WO-83/WO-84 then built that service half.
  **The recon is the gap**: `grep -rn "recovery-dashboard\|contract-terms\|overcharges\|rebates"
  frontend/src` returned NOTHING, so twelve live, structurally-gated routes across three modules
  were reachable only with `curl` — including the two send-ready artifacts whose whole purpose is
  to leave the building, and the rebate form without which a demand letter asks a supplier for
  money it has already paid. **Three screens, and the two figures that must never be a zero.**
  `/recovery` renders the six readiness buckets in the service's own order (all six always,
  including the empty ones) with `deadline_risk_claims` deliberately OUTSIDE the table, because
  WO-81 interpretation 3 refused to make it a seventh bucket — the bucket says WHAT TO DO, the
  count says HOW URGENT, and a claim inside the 60-day window keeps both. A null
  `median_days_to_refund` reads **"Not yet measurable"** with its `days_to_refund_sample` beside it,
  never `0`, for the service's own reason (*"0 would claim refunds arrive the same day they are
  filed"*); a non-zero `currency_mismatch_claims` gets a NAMED notice stating that those drafts
  contribute €0.00 to every euro rather than being summed across currencies (§4.14), because that
  exclusion is exactly why a claimable total can look short. `overcharges_eur` renders as a SECOND,
  separate cash stream — folding supplier credits into the recovered+awaiting+claimable identity
  would make that identity false. `/overcharges` carries the read-only detection (breach lines with
  their flags, gap, litres and recoverable euros, plus `price_basis` and `legal_framing` rendered
  VERBATIM off the response so R53's framing cannot be flattened by an SPA re-wording), the
  claim-back ladder driven from a verbatim mirror of `overcharge.TRANSITIONS` (a terminal state
  offers nothing; only a `recovered` move accepts an amount), and both artifact downloads.
  `/rebates` records the DOCUMENT — the form has no EUR field at all, because `RebateIn` has none
  and the server resolves the euro at the document's own date. **Two boundaries stated in the copy
  and asserted as text**: §3.H (recording a rebate changes no figure until the close runs — and
  since WO-84 shipped no preview endpoint, **no preview is faked** and no merge/apply verb exists,
  §10) and §4.15 (`fx_rate_unavailable` reads "nothing was recorded", because "it failed" and "it
  quietly stored something approximate" are the two readings an operator must be able to tell
  apart). **The advisory/blocking line is drawn in words on every surface** (§4.19): detection
  "changes no figure, blocks no claim and halts no close" and `source_warnings` "blocks nothing";
  the artifact refusals BLOCK, and `overcharge_evidence_drift` — the one that fires in the window
  between a claim-back freezing its demand and a rebate merge changing what the same lines audit to
  — gets the longest sentence in the refusal map, naming the rebate merge, the fact that NO document
  is produced, and the fix (a fresh audit; the frozen demand is never silently re-snapshotted).
  18 refusal codes added, each read off the service that raises it; the raw slug reaches the screen
  nowhere. Permissions mirror the routes control by control: reads on the new `transport.read`
  member (a real fourth member, not an alias for `vat.read` — `TRANSPORT_READ` is what these three
  route modules declare, and mirroring it under its own name is what stops the two collapsing into
  synonyms in the SPA), mutations on `vat.write`, and the artifact DOWNLOADS left visible to a
  read-only role because the router serves them as reads. Money is string-exact end to end: no
  arithmetic on any figure, proven both by rendering `99999999999999.99` character-for-character and
  by a source grep in the suite refusing `parseFloat`, `Number(`, `toFixed` and `Math.`. ZERO
  backend change — no route, no schema field, no permission member, no error code, no migration; the
  gaps stay reported rather than invented. 54 new Playwright specs; SPA pages 49 → 52.
  Detail: `docs/plan/plan-a/wo/WO-86-transport-ui-3.md`.

- [x] **WO-87** — `Completed` — **G4.7: the overpay / benchmark analyses** — the fifth M5 row, and
  the order R53 was the load-bearing constraint of. **The recon is three promises the tree had
  never kept.** `grep -rn "q_savings"` returned exactly two hits and both were IOUs
  (`queries.py:89-93` — *"`q_savings` is the same-day overpay grain (board G4.7) … they belong in
  this module when their boards land"* — and `rules.md:50`); `rules.md:48` recorded R53's second
  framing as **STILL OPEN** in as many words while WO-83 had made the FIRST framing client-reachable
  as a 30-day payment demand on a client's own letterhead; and `WO-84-net-eur-eff-merge.md:79`
  recorded §2.5's *"Expected rebate"* as a documented PARTIAL harvest (WO-84 took only the
  per-(supplier, country) EXISTENCE expectation, so nothing in the tree knew what a pair's rebate
  usually looked like and nothing could flag the one line that quietly lost it). **Three analyses,
  each complete, each strictly per its harvested definition.** (1) **Avoidable overpay (same-day)**
  — `litres × (this supplier's eff €/L − the cheapest same-day, same-country RIVAL's eff €/L)`,
  diesel only, ≥2 suppliers that day, positive deltas only, attributed to the country of supply and
  the supplier that charged the premium; "rival" excludes the supplier itself, so the day's cheapest
  compares against the SECOND cheapest and drops out on the sign test. An **exact tie is not an
  overpay** (compared on the unrounded quotients, so the boundary cannot move on a presentation
  rounding) and a **day with one supplier yields nothing**, counted in `days_without_a_rival` —
  never a false positive, never a silent zero reading as "you were competitive". (2) **Internal
  benchmark** — `Σ_supplier qty × (supplier_eff − best_eff)` per country × month, `best_eff`
  INCLUDING the supplier measured, so the best one stays on the sheet at a zero gap because it is
  the supplier the volume would be routed TO. **R52 is proven on ONE fixture**: two suppliers
  alternating cheapest across two days give **200.00** on the same-day grain and **0.00** on the
  month grain, and a test asserts they differ — *"they will not reconcile; that is correct"*. The
  two euro fields are named differently (`avoidable_eur` / `benchmark_gap_eur`) so nothing can add
  them, and each result carries its grain string. (3) **Expected rebate** — the median applied €/L
  learned per (supplier, country) from all history, with `abs(rebate) < 0.005` lines flagged; a
  MEDIAN because one freak line would otherwise set an expectation no line could meet, learned only
  from rebate-BEARING lines because including the zeroes would drag the typical toward zero in
  exactly the situation the analysis detects, and with **no minimum-sample constant invented**
  (§2.5 states none and WO-84 forms an expectation from a single prior period) — `learned_from_lines`
  rides every finding instead. **R53's second framing, made STRUCTURAL rather than editorial.** An
  overpay figure is not a debt: nobody agreed a supplier would match the cheapest rival on the day,
  so there is no term, no breach and nothing owed, and presenting it as a claim would be a false
  assertion to a counterparty. Four asserted ABSENCES hold it apart from the claim-back family —
  different framing constants each stating what they mean; **no field name** on any result
  dataclass, wire schema or route path containing `recover`/`owed`/`owes`/`claim`/`demand`/`due`/
  `debt`/`payable` (scanned with a seeded-violation self-test, so there is no `recoverable_eur` for
  a client to render as a demand); an **AST import scan in BOTH directions** proving no claim-back
  service or route imports `savings` and vice versa, so no overpay euro can reach
  `overcharge.detected_eur` — the figure the demand letter prints — even by a future accident; and
  **no write verb at all** on the router (`methods == {"GET"}`, a POST is a 405 on the wire), because
  there is nothing to open, freeze, package or send. **§4.14/§4.15 enforced, not assumed** — and the
  second recon finding: `contract_audit`'s *"a EUR figure exists for every stored row or the row does
  not exist"* argument holds for `statement_ingest` but **not for the row writer**
  (`fuel_ingest.ingest_transaction` takes `fx_source` as an optional argument defaulting to `None`
  and never checks it against `net_eur`; `FuelTransaction.fx_source` is nullable with `"unknown"`
  among its legal values). So the analyses CHECK: a row with `fx_source == "unknown"`, or a non-EUR
  currency with no recorded conversion at all, makes them **REFUSE** (`fx_rate_unavailable`) rather
  than excluding — a comparison set is not a list of independent objects, and silently dropping one
  supplier's line changes the cheapest rival for every OTHER supplier that day. A EUR line with a
  NULL provenance passes (EUR is the identity, no rate involved), which is what keeps every
  `fuel_ingest`-written line in scope. Every row-selection goes through the WO-85 registry:
  `price_comparison_transactions` (the spec's `q_savings`, named per this codebase's convention) plus
  a `product_group` dimension on `fuel_transactions`, and the cut deliberately takes **no `supplier`
  argument** — filtering the rows would change who the rival was. **DOCUMENTED INTERPRETATIONS**
  (the `contract_audit`/`rebate` precedent): both overpay grains restricted to Diesel (a blended €/L
  across Diesel + AdBlue + Toll measures product MIX, not price); a supplier's price in a grain cell
  volume-weighted `Σ net_eur_eff / Σ qty`; `expected_rebate_eur = typical €/L × litres` an advisory
  magnitude, never a claim. **PARTIAL HARVEST, DOCUMENTED:** §2.5 lists nine analyses and this order
  builds three COMPLETELY — the peer benchmark (R55) needs a cross-entity cohort policy decision, the
  margin report needs §3.H H5's `my_prices`/`wholesale_prices` tables, supplier reliability needs an
  append-only `advertised_prices` table, anomalies (R54) are six rules and an order of their own, and
  the FX markup trend needs a market-wide markup series; each is recorded as a follow-up slice WITH
  its blocker rather than half-built (§10). Read-only: NO table, NO migration, NO permission member,
  NO SPA change, NO new dependency, and not one pre-existing test file edited. 82 tables, 86
  revisions. Detail: `docs/plan/plan-a/wo/WO-87-overpay-benchmark.md`.

- [x] **WO-88** — `Completed` — **FX provenance consistency at the row writer** — the G4.7 follow-up
  that closes WO-87's own recon finding, and R56's first ledger row. **The recon, verified in the
  code rather than trusted:** `fuel_ingest.ingest_transaction` declared `fx_source: str | None =
  None` and passed it straight to the model without ever comparing it to `net_eur`, `currency` or
  anything else — so a `fuel_transactions` row could assert BOTH *"no exchange rate was available"*
  (`fx_source='unknown'`, which `app/models/fx.py` defines as *"EUR figure is NULL, never a guessed
  number"*) AND `net_eur = 1400.00`; and a non-EUR line with `fx_source IS NULL` was a foreign amount
  labelled EUR with no recorded conversion at all (§4.14). `ck_fuel_transactions_fx_source`
  constrained only the VALUE DOMAIN, never the combination, so both rows satisfied every constraint
  on the table. WO-87 refused them at ONE read boundary (`savings._require_eur_basis`, three
  analyses); `contract_audit`'s demand-letter euro, the claim lines that become a filed refund, the
  tie-out, the close and the recovery dashboard all summed the same columns with no such check —
  and `contract_audit.py:63` argued from *"ingestion refuses a line it cannot convert"*, true of
  `statement_ingest` and false of the writer underneath it. **Two findings beyond the brief:** no
  STORED row anywhere violates the invariant (zero rows in the dev DB, no migration inserts one,
  `seed.py` writes none, and `statement_ingest` always supplies `eur`/`stated`/`ecb`) — but SIX live
  test fixtures did, repeatedly (`test_g3_3_tie_out.py`'s helper built every line as
  `currency="SEK", net_eur=90.00` with no provenance; the same shape in the freeze, submission-gate,
  contract-audit, overcharge-artifact and canonical-query suites); and the OTHER money-bearing
  transport table, WO-84's `vat_off_invoice_rebates` (`amount_eur` NOT NULL, `> 0`), shipped with
  the FX quadruple and **no `fx_source` constraint of any kind** — not even the value-domain one
  every other FX-bearing table has carried since WO-8. **The fix is two layers, both kept:**
  `_require_fx_provenance` refuses both combinations at the one writer with the tree's existing
  `fx_rate_unavailable` code (verified in `statement_ingest`/`rebate`/`savings` before reuse — no
  slug invented), running before the entity fetch so a refused call provably writes no row and no
  audit event; and `ck_fuel_transactions_fx_provenance` + `ck_vat_off_invoice_rebates_fx_source` +
  `ck_vat_off_invoice_rebates_fx_provenance` state the same invariant in SQL, so a script, a
  fixture, a repair job or a future writer cannot create what the service refuses. The EUR/NULL
  identity carve-out is deliberate and shared with `savings` (EUR involves no rate), which is what
  keeps every EUR line ever written valid. Portable SQL — no `IS DISTINCT FROM` (SQLite 3.39+),
  `upper()` because it is immutable on both dialects — and the `net_eur IS NULL` disjunct kept
  deliberately so the constraint still means the right thing if an EUR column ever becomes nullable.
  **The migration inspects before it constrains** (the WO-8 precedent) but does not pretend it can
  correct: the rate does not exist, the column is NOT NULL, and deleting transaction history is a
  business decision (§9) — so it prints every offending row and **RAISES**, asserted by seeding one
  at the pre-WO-88 head and by the clean-tree `[WO-88] 0 violating rows`. **WO-87's refusal is not
  weakened** — its two §4.15 tests keep their names and their code assertion, with the writer's
  refusal as the new first layer and the unmodified guard driven by a row storage can no longer
  supply. Verified on BOTH dialects: SQLite's batch rebuild preserves the natural key, both
  pre-existing CHECKs and all three indexes, `downgrade → upgrade` round-trips, `alembic check`
  reports no drift; PostgreSQL 16 rejects the same two inserts by name. **Out of scope, named:** a
  non-EUR row claiming `fx_source='eur'` (a wrong provenance, not a missing one — no writer can
  produce it) and the AP/AR core, where the invariant already holds by construction
  (`invoices.total_eur` is nullable and `fx.eur_total` returns `(None, "unknown")`). 82 tables, 87
  revisions. Detail: `docs/plan/plan-a/wo/WO-88-fx-provenance-consistency.md`.
- [x] **WO-89** — `Completed` — **FX provenance honesty: the wrong-provenance rule** — the G4.7
  follow-up WO-88 deliberately scoped out, and R56's SECOND enforcement consumer. **The recon
  corrected the brief twice.** (1) The brief said WO-88 found a live fixture instance, so the shape
  is reachable — WO-88 did, and it fixed it in the same order (`test_g3_4_capture_checks.py:85` now
  keys its provenance off the currency), so the fixture evidence was historical. (2) Reachability is
  nevertheless real and WORSE than a fixture: the shape is reachable through the PRODUCTION WRITER.
  Proven by executing it rather than reading it — a throwaway probe drove
  `fuel_ingest.ingest_transaction` with `currency="PLN", fx_source="eur", net_eur=1400.00` and the
  service STORED the row (`RECON fuel_transactions: STORED PLN eur 1400.00`). `fx_source='eur'` is
  the IDENTITY provenance, `app/models/fx.py`'s *"the amount was already EUR (identity, rate 1)"* —
  a zloty amount was not. WO-88's gate passed it (its two clauses test `unknown` and a NULL
  provenance), WO-88's CHECK passed it (`fx_source IS NOT NULL` satisfies the second conjunct), and
  WO-87's `savings._require_eur_basis` passes it too — so a fabricated conversion reached the VAT
  claim lines, `contract_audit`'s demand-letter euro, the tie-out, the close and the recovery
  dashboard with nothing in its way. This is strictly worse than the shape WO-88 closed, which no
  production caller could produce. **Findings beyond the brief:** only TWO of the four `fx_source`
  tables carry the `(currency, fx_source, EUR amount)` quadruple — `expense_items` has NO EUR column
  at all (its converted `amount` is denominated in the REPORT currency, which need not be EUR), so
  the rule as stated does not even typecheck there and a CHECK would enforce a DIFFERENT invariant;
  and no stored row, seed, migration or fixture exhibits the shape, verified with an UNBOUNDED sweep
  over all 118 `fx_source` occurrences in `backend/tests` (WO-88's own recorded lesson — its first
  pass truncated a grep at 30 lines), so **this order raises no fixture, and that is a finding
  rather than a skipped sweep**. **The fix is the same two layers, extended not forked:**
  `_require_fx_provenance` grows a THIRD clause in the same pure function at the same place in the
  gate order (module entitlement → FX → entity), so a refused call still writes no row and no audit
  event; `ck_fuel_transactions_fx_provenance` and `ck_vat_off_invoice_rebates_fx_provenance` grow a
  third conjunct (`upper(currency) = 'EUR' OR fx_source <> 'eur'`) under their EXISTING names,
  because each constraint always meant *"this row's euro does not contradict its own provenance"*
  and a second same-shaped constraint beside it would be the storage-layer form of the
  rival-predicate mistake WO-85 and R3 already paid for. **The code is DISTINCT** —
  `fx_provenance_inconsistent`, after the tree's own `fx_stated_inconsistent` — because every
  `fx_rate_unavailable` message in the tree ends in an instruction to go and obtain the rate, and
  that would send an operator to the wrong fix here: the rate is probably cached and what is broken
  is the claim that none was needed. WO-88's two refusals keep `fx_rate_unavailable`, asserted by a
  test that maps all five refused tuples to their codes in one dict. **The migration DROPS before it
  creates**, so its pre-flight scans all THREE combinations rather than only the new one (a database
  restored from before WO-88, or one through this revision's own downgrade, can hold either older
  shape), it refuses rather than corrects for WO-88's reasons, and a FAILED run is asserted to leave
  the OLD constraint in place — a half-applied run must never leave the table unprotected. The
  downgrade restores WO-88's exact expressions, so a rollback lands on the WO-88 invariant rather
  than on no invariant at all. **WO-88's SECOND follow-up assessed and CLOSED BY ANALYSIS:** the
  AP/AR core needs no constraint, but WO-88 reached that verdict from the wrong evidence (a nullable
  `total_eur` is the MISSING-provenance argument and says nothing about a wrong one). The correct
  evidence is branch structure — `fx.eur_total` returns `'eur'` on exactly one branch
  (`if currency == "EUR"`, after `.upper()`) and is the only writer of `invoices.fx_source`
  (`InvoiceCreate` carries no such field); `expenses.apply_item_fx` stamps `eur` only when
  `ccy == report_ccy == "EUR"` and overwrites any client-supplied value on every one of its
  branches. Both tables nevertheless remain representable at the STORAGE layer — a platform-level
  gap, reported rather than smuggled into a transport order. **WO-87's and WO-88's layers are not
  weakened**: the writer keeps both earlier clauses and their code, the value-domain CHECKs are
  untouched, and `savings._require_eur_basis` is not edited at all (deliberately — after WO-89 no
  wrong-provenance row can exist in storage, so a widened clause there could never fire; its
  unchanged behaviour, INCLUDING the fact that it passes the wrong-provenance row, is re-asserted so
  the decision is visible). Verified on BOTH dialects: SQLite's batch rebuild preserves every other
  CHECK, both unique keys, both composite FKs and all three indexes, `downgrade → upgrade`
  round-trips and `alembic check` reports no drift; PostgreSQL 16 on a NOSUPERUSER role rejects the
  PLN/`eur` insert, its lower-case twin, WO-88's two shapes and the tampering UPDATE — each BY
  CONSTRAINT NAME — while accepting PLN/`ecb`, EUR/`eur` and `eur`/`eur`. 82 tables, 88 revisions.
  Detail: `docs/plan/plan-a/wo/WO-89-fx-wrong-provenance.md`.

- [x] **WO-90** — `Completed` — transport UI slice 4: **the savings / negotiation-evidence
  workspace** (`frontend/src/pages/Savings.tsx`). WO-86 closed the analytics UI *"for every built
  transport route"* — true on the day, and untrue the moment WO-87 landed three more. **The recon
  is the gap:** `grep -rn "transport/savings" frontend/src` returned NOTHING, so the three
  `TRANSPORT_READ` GETs WO-87 shipped (`/same-day`, `/internal-benchmark`, `/expected-rebate`) were
  reachable only with `curl` — and their whole value is being SAID OUT LOUD at a supplier meeting.
  **One screen, three panels, and one governing constraint.** R53's second framing is what this
  order is really about: WO-83 had already made the FIRST framing client-reachable as a formal
  letter with a payment deadline, and a UI is exactly where the separation gets flattened — one
  "send to supplier" button, one "recoverable" column heading, one link into the other flow, and the
  platform asserts a debt nobody agreed to, on the client's own letterhead. So the four structural
  absences WO-87 built into the backend were carried into the SPA and ASSERTED rather than
  described: (1) `legal_framing` and `price_basis` render VERBATIM off each response on each panel —
  one string, so no SPA re-wording can soften it; (2) no identifier, string or comment in
  `pages/Savings.tsx` or `lib/transportSavings.ts`, and no FIELD NAME in the eight new `lib/types.ts`
  interfaces, carries `recover`/`owed`/`owes`/`claim`/`demand`/`due`/`debt`/`payable` — scanned at
  source at WORD BOUNDARIES (catching `recoverable_eur` while not firing on the "owes" inside
  "lowest") with a **seeded-violation self-test**, because a scan that cannot fail proves nothing;
  (3) the page names no path into the contract-breach flow and no link inside its `<main>` points at
  one (source AND DOM); (4) there is no mutating control at all — no form, and every button on the
  surface is asserted to be a tab. **R52 became page text, not a docstring:** each overpay panel
  prints the service's own `grain` string beside a sentence stating the two totals measure different
  things over the same rows, why (different comparison, different denominator) and that neither is
  to be added to the other — and the two euro totals are proven never to appear together. **The
  honest non-zero:** `days_without_a_rival` is a named count with its reason (*"no rival price to
  compare against and no finding was produced… that is not the same as a zero"*), never a €0.00
  line — the WO-86 honest-null discipline applied to a different failure of nerve. Money is the
  server's string end to end: `decimalMoney` for euros, €/L and litres rendered as received, and
  `parseFloat`/`Number(`/`toFixed`/`Math.` grep-proven absent, asserted on a `99999999999999.99`
  fixture an IEEE-754 round-trip would destroy. Loading/empty/error/refusal on every panel, module
  gating, and the permission pair (an AUDITOR sees the destination, an EMPLOYEE holding neither
  VAT_READ nor TRANSPORT_READ sees no nav entry). **ZERO backend change** — no route, schema field,
  permission member, constant or refusal entry; all four codes these routes raise
  (`module_not_enabled`, `invalid_period`, `invalid_country`, `fx_rate_unavailable`) already had
  sentences. 36 Playwright specs; the only pinned docs-truth number moved is README's SPA page count
  52 → 53, in the same commit that adds the page.
  Detail: `docs/plan/plan-a/wo/WO-90-savings-ui.md`.

- [x] **WO-91** — `Completed` — **G4.6: the diesel excise-duty refund** (R42 + R53's THIRD
  framing). **The recon is the gap, twice over.** `grep -rn "excise" backend/app` returned exactly
  ONE hit — `app/core/authz.py:69`, `TRANSPORT_READ = "transport.read"  # fuel/toll analytics,
  excise (advisory)`: a permission reserved for a surface nobody ever built — while
  `api/routes/transport/__init__.py` named the missing module by file name (*"Future slices
  (`excise.py` …) include themselves HERE"*) and `app/api/router.py` said *"claims today;
  fuel/recovery/excise later"*. `BA_fleet_fuel.md` meanwhile gives excise its own money-flow branch
  (§1.3), its own external party (§1.2, **customs authorities**), its own surface row (§2.4), its
  own legal row (§6.1, ETD 2003/96 + national law) and its own requirement (R42) — a second
  recoverable-cash stream over litres the client has ALREADY paid to have captured.
  **The analysis.** `excise_report` sums the period's validated DIESEL litres EXACTLY per
  (entity × country) — R42's own grain — and applies ONE `money.q2` to `litres / 1000 × rate`, so
  1,234.567 L at the harvested EUR 30.0000/1,000 L is EUR 37.04 and never a figure that inherited a
  rounded litre total. The predicate is a new canonical-registry cut (`queries.excise_transactions`),
  deliberately NOT `price_comparison_transactions` with an extra argument: that function's own
  docstring forbids a scope parameter because an overpay comparison is RELATIVE (scoping changes who
  the cheapest rival was), while excise is ABSOLUTE (a cell's litres are its own) — two scoping
  semantics, two named cuts, one `fuel_transactions` predicate underneath.
  **The rate is an override over a placeholder, and the difference is on every surface.** §2.4 and
  Appendix B both call EUR 30.00/1,000 L an explicit **PLACEHOLDER** in a reported EUR 25-33 band,
  and §9.2 item 13 files *"who owns the real per-country statutory rates"* as an OPEN owner
  question — so the default is a code constant, `vat_excise_rates` is only the operator's typed
  override (new tenant table, FORCE RLS in its creating migration, composite `(org_id, id)`, a real
  tenancy-parity probe in the same commit, audited old→new), and `is_override` / `rate_caveat` ride
  every response and the workbook's own "Rate source" column. `set_rate` accepts ONLY the harvested
  seven states (422 `excise_country_not_supported` — a documented interpretation, fail-CLOSED:
  storing a rate for an eighth would assert a refund regime exists where the spec records none) and
  refuses a non-positive rate (422 `invalid_excise_rate` + a DB CHECK), because the absence of the
  regime is already expressed by holding NO rate. Hence `rate_for` returns **`None`, never `0`** —
  a state outside the seven yields **NO ROW**, reported honestly in `skipped_countries` with its
  litres and deliberately WITHOUT a euro field, since *"we hold no rate for this state"* and *"this
  state refunds you nothing"* are different facts.
  **The governing constraint — the eligibility limitation — is STRUCTURAL, not a caveat someone can
  drop.** §3.L: *"**Asserts NO eligibility** (vehicle >=7.5t / carrier registration not modelled)"*;
  §9.2 item 14 files who confirms it as an open owner question. Four mechanisms, each with a test
  and each scanner with a **seeded-violation self-test**: (1) ONE server-side
  `ELIGIBILITY_STATEMENT` naming both conditions and denying the entitlement reading in words
  (*"excise you may be able to reclaim IF you qualify, never as excise you are owed"*), rendered by
  every result shape, every response schema and BOTH sheets of the customs workbook; (2) a REQUIRED
  literal `eligibility_asserted: false`, because a boolean survives a surface that truncates prose;
  (3) no field name anywhere in the service or the schemas carrying a claim word — the euro is
  `indicative_excise_eur`, the qualification inside the identifier where a renderer cannot lose it —
  scanned against WO-87's `CLAIM_WORDS` **imported** rather than re-typed so the two R53 surfaces
  cannot drift apart; (4) an AST import scan in BOTH directions proving no excise euro can reach
  `overcharge.detected_eur`, the figure WO-83's 30-day demand letter prints.
  **§4.14/§4.15 land differently here and are stated rather than inherited:** this module reads
  `qty` and NO currency amount at all (asserted structurally, by column name), so nothing is
  converted and nothing is summed across currencies — and unlike `savings.py` an
  `fx_source='unknown'` row does **not** refuse, because a litre count is not arithmetic on euros
  and refusing would drop real litres from a customs packet for a reason that has nothing to do with
  litres.
  **The packet** (R42's *"Excel packet for customs"*) renders from the SAME `excise_report` through
  ONE `_COLUMNS` spec by a **sync** function holding no session — the WO-74/WO-83
  one-source-two-renderers rule, asserted three ways AND cell-for-cell over the parsed workbook —
  and REFUSES rather than emitting an empty document (422 `no_excise_findings`), because a customs
  packet with no lines looks like a filing and supports nothing. Both sheets carry the caveats and
  the cover states the un-rated litres; free text is CWE-1236-safe, numbers stay numbers.
  **Routes** on the RESERVED `TRANSPORT_READ`, with the two rate writes on the EXISTING `VAT_WRITE`
  that `overcharges.py` already gates contract terms with — **no permission member invented**.
  **And WO-90's reported defect, found wider than reported:** `invalid_period` is ONE stable wire
  code raised by SEVEN services carrying THREE different sentences, mapped in the SPA to the CLAIM
  instruction only — so FOUR month-shaped pages (Savings, Overcharges, Rebates, VAT admin) told an
  operator to type `2026-Q2` into a field that only accepts `2026-04`, and these excise routes would
  have been the fifth. Split ADDITIVELY (§4.20): no wire slug, message or backend test changed; a
  `periodShape` selector picks the instruction, the shape-independent fallback now names NEITHER
  shape rather than the wrong one, and BOTH sentences are asserted in Playwright.
  Deliberately NOT built (§10): an `/excise` SPA page (a named follow-up UI slice), an excise claim
  LIFECYCLE (no state machine is harvested anywhere), real statutory rates (§9.2 item 13) and
  eligibility itself (§9.2 item 14).
  Detail: `docs/plan/plan-a/wo/WO-91-excise-refund.md`.

- [x] **WO-92** — `Completed` — transport UI slice 5: **the diesel-excise screen**
  (`frontend/src/pages/Excise.tsx`). WO-91 shipped G4.6's whole backend and named its own
  missing half in as many words (*"An `/excise` SPA page … the page is a follow-up UI slice
  with the WO-90 precedent"*). **The recon is the gap:** `grep -rn "transport/excise"
  frontend/src` returned NOTHING, so five routes — the analysis, the customs packet and the
  rate registry — were reachable only with `curl`. The deliverable a haulier actually needs is
  the packet: one spreadsheet per period to hand to a customs authority, formula-injection-safe
  and reconciling cell-for-cell with the JSON, and no operator could obtain it. The rate was
  worse: the shipped EUR 30.00 is an explicit PLACEHOLDER and `set_rate` existed with nowhere
  to type into, so every figure the platform held was computed from a placeholder nobody could
  correct.
  **One screen, two panels, and one governing constraint.** R42's acceptance line —
  *"The UI shows the indicative-rate and eligibility caveats on every surface that shows the
  number"* — is a criterion ABOUT A UI that had no UI to be true of, and a UI is exactly where
  WO-91's structural non-assertion would be undone: one "Recoverable" column heading, one
  "€0.00" in a country we hold no rate for, one paraphrase that shortens the statement into a
  footnote, and the platform asserts that a customs authority is holding money for a haulier
  under conditions (vehicle >= 7.5 t, carrier registration) the product deliberately does not
  model. So the backend's four mechanisms were carried into the SPA and ASSERTED rather than
  described: (1) `eligibility`, `rate_caveat`, `legal_framing`, `filed_with` and `litre_basis`
  render VERBATIM off the wire — on the page header AND again inside each panel, because a
  panel scrolled away from the header is its own surface — and a spec walks EVERY file under
  `frontend/src/` proving the SPA holds none of the five strings, so a re-wording in the UI is
  impossible rather than discouraged; (2) `eligibility_asserted: false` is STATED
  ("Eligibility asserted by this figure: none"), which is the entire reason the boolean rides
  beside the prose; (3) no identifier, string or comment in `pages/Excise.tsx` or
  `lib/transportExcise.ts`, and no FIELD NAME in the five new `lib/types.ts` interfaces, uses
  the vocabulary — WO-87's `CLAIM_WORDS` plus `entitle`, word-boundary matched, with a
  seeded-violation self-test so the scan cannot quietly stop working; (4) `skipped_countries`
  is its own table with litres and a line count and NO euro column — the wire shape carries no
  euro field, so the €0.00 that would mean *"this state refunds you nothing"* cannot be
  rendered even by accident, and the copy says so in words.
  Every rate on both panels shows its SOURCE in the customs workbook's own two words
  (*verified override* / *indicative default*), so the placeholder is never presented as a
  statutory figure. The two rate controls mirror `vat.write` — the permission
  `routes/transport/excise.py`'s `_WRITE` actually declares; the packet is a READ and is
  offered to anyone who can see the figures. No arithmetic anywhere: euros through
  `decimalMoney` (string surgery), rates and litres as received, grep-proven, and a
  `99999999999999.99` fixture a double could not hold. Three refusal rows added additively for
  the codes no page had yet rendered (`excise_country_not_supported`, `invalid_excise_rate`,
  `no_excise_findings`); the surface's other three were already mapped and are reused with
  `periodShape="month"`. 39 Playwright specs; 1 pre-existing assertion SCOPED (never weakened)
  where the new nav label collided with a bare `getByText("diesel")`; the only pinned
  docs-truth number moved is README's SPA page count 53 -> 54, in the same commit that adds the
  page. ZERO backend files touched.
  Deliberately NOT built (§10): an entity picker (the report already carries `entity_name`, and
  resolving ids needs `GET /issuer/registry` on a DIFFERENT permission a `transport.read`-only
  role need not hold), any hint of modelling eligibility (§9.2 item 14), a rate table of our own
  (§9.2 item 13), an excise lifecycle or a "file this" verb, and any chart.
  Detail: `docs/plan/plan-a/wo/WO-92-excise-ui.md`.

- [x] **WO-93** — `Completed` — **the client claim-status portal** (G4.4 / R39) —
  `app/services/transport/client_status.py`, `app/api/routes/transport/claim_status.py`,
  `app/schemas/transport_client_status.py`, `frontend/src/pages/ClaimStatus.tsx`.
  **The recon is the gap:** `grep -rn "claim-status\|client_status" backend/app frontend/src`
  returned NOTHING in any layer, while `docs/transport/rules.md` carried no R39 row — the rule
  was entirely unharvested. What existed was the vocabulary to translate FROM
  (`status.AUTO_CODES`/`MANUAL_CODES`) and `status.list_status_codes` stating in as many words
  that this codebase has NO label mapping at all. So a client logging in today either saw
  nothing about their own claims, or saw the operator's internal vocabulary: `/recovery` renders
  the readiness slugs beside their labels and `/vat-claims` renders `status_code` verbatim.
  **The governing constraint is R39's acceptance line, which is entirely an ABSENCE** — *"a
  client-role session cannot see a status code or a fee anywhere"* — so it is enforced
  structurally rather than by careful template-writing, the WO-87/WO-90/WO-92 way. Three
  families are banned and two positive properties asserted beside them (a page can satisfy every
  ban by rendering nothing): (1) no leaf string of a real response EQUALS any internal workflow
  code — equality, not containment, because `"2"` is a code and `"2026-Q2"` is a period the
  client needs — with the vocabulary IMPORTED from `status.py` so a code added there is covered
  without touching the test; (2) no field name in the service dataclasses or the wire schemas
  carries code, fee or action vocabulary, and the service is AST-asserted never to READ
  `fee_pct`/`fee_min`/`fee_eur` (nor the currency-ambiguous `vat_local`/`paid_amount`); (3) no
  string the service OWNS reads as an instruction; (4) `CLIENT_STAGES` is the spec's own
  vocabulary verbatim — `prep · ready · filed · awaiting · refunded · needs_attention`, §3.D's
  order, no seventh and no friendlier synonym — and all six always render; (5) the
  plain-language LABELS are server-owned and cross the wire, so the SPA cannot re-word them, and
  a spec walks every file under `frontend/src/` proving the six sentences live nowhere in it.
  Every scan ships a seeded-violation self-test.
  **The mapping is a documented INTERPRETATION** (the spec names the stages and the fifteen codes
  but never assigns one to the other), stated in full in the module docstring and asserted as a
  literal dict: 1A -> needs_attention (blocked on something a human must supply), 1B/1C -> prep
  (the client is deliberately not shown WHICH caveat), 1E -> ready, 2/2A -> filed, 2B/3B/3C/3D ->
  needs_attention (a request with a deadline, or an adverse outcome), 3 -> awaiting (the
  `filed`/`awaiting` split is at the DECISION, not the money — otherwise the spec's five-step
  ladder is four facts), and 4/4A/5 -> refunded (all three are engine `paid`; what they actually
  describe is the fee ladder, which is exactly what must not be shown). Dispatch is on the ENGINE
  STATUS FIRST, then the code — which makes the surface immune to a real defect this order found
  and deliberately did not fix (§4.20): `lock.withdraw_claim` leaves `status_code` populated while
  §3.D **D7** says withdrawal also NULLs it. A withdrawn claim never reaches the code map, and a
  test pins the immunity so a future G2.7 fix cannot silently change the portal.
  Every stage is proven by a claim GENUINELY CONSTRUCTED in it (`lock.submit_claim` for `filed`,
  `status.set_status_code` for each manual code, a real unregistered invoice for 1A, a real EUR
  2.10 line for 1C), never by stubbing the mapper. Nothing is forked: the claim set is
  `claim.list_claims(year=)`, the stage `status.derive_stage`, the figure
  `freeze.preview_vat_base` or the frozen column, and an AST test asserts the module holds no
  `select()` of its own. `vat_eur` is `Decimal | None` — a draft whose lines span currencies has
  no single-currency base to state (§4.14), and `null` says so where `0.00` would be a wrong
  number in front of a client; the page renders it as a dash. Claims in an engine state outside
  the ladder are COUNTED (`Σ stages + not_shown == total`) without naming the state.
  **Permission: the EXISTING `VAT_READ`** — no member invented. `Role.READ_ONLY` (stored
  `user_free`), which is §1.2's *"the client, read-only base"*, already holds it; APPROVER and
  EMPLOYEE hold no VAT permission at all. Chosen over `TRANSPORT_READ` on WO-79's own reservation
  wording: this returns CLAIM ROWS, not the portfolio aggregates that reservation is for.
  22 Playwright specs; the `ready` label was renamed *"Ready for filing"* when the spec found it
  collided with `lib/transportRecovery.ts`'s operator bucket label *"Ready to file"* (the two mean
  different things); the only pinned docs-truth number moved is README's SPA page count 54 -> 55,
  in the same commit that adds the page. No table, no migration, no permission member.
  Deliberately NOT built (§10): `action_deadline` on the wire (the spec does not name it on this
  surface, and its own field name is in the banned family), a claim-detail drill-down or any link
  into `/vat-claims`, any control at all, and the G2.7 withdraw defect above.
  Detail: `docs/plan/plan-a/wo/WO-93-client-claim-status.md`.

- [x] **WO-94** — `Completed` — **two known defects, each with its evidence** (G2.7 §3.D **D7**
  + backlog **N3**). Neither was speculative: both were found by earlier orders in this
  programme, recorded with a source, and deliberately left. Each was re-verified independently
  before a line changed, and both turned out to be real.
  **D7 — withdrawal left a stale status code.** `BA_fleet_fuel.md` §3.D line 545:
  *"Only `withdraw_claim` releases, and it also NULLs `status_code`."* The release shipped in
  WO-51; the clear never did, so every withdrawn claim kept the `"2"` `submit_claim` stamps —
  or whatever `status.set_status_code` last wrote — and read as *submitted* / *under appeal*
  beside a `withdrawn` engine status on `/vat-claims` and in any export of the claim record.
  The proof was already a GREEN test: WO-93's own
  `test_wo93_a_withdrawn_claim_is_not_shown_and_its_stale_code_is_never_read` asserted
  `withdrawn.status_code == "2"`, labelled *"the stale code this surface must not read"*.
  Fixed at the transition that owns the withdrawal: both columns move in the SAME flush as the
  lock deletion, so a rollback still discards the release, the status and the code together,
  and the existing `transport.claim_withdraw` event's `meta` goes from `None` to old→new under
  `set_status_code`'s own field names (§4.16 — one meta shape per column, not two). It is
  deliberately NOT put in `set_status_code`, which already refuses a withdrawn claim
  (`claim_not_submitted`) and so can neither reach the state nor undo it. **Stale data was
  assessed rather than assumed**: rows already carrying the inconsistent pair are repaired by
  the data-only revision `f2a91c07d4e6`, which counts and PRINTS what it changes and is
  idempotent. It WRITES where the two FX-provenance revisions REFUSE, and the difference is the
  reason it is allowed to: D7 states the one correct value for every matching row and it is a
  constant, nothing is derived or guessed, and no euro is touched (nothing computes an amount
  from `status_code`). `downgrade()` is a documented no-op. Proven end to end on a seeded legacy
  row — `[('withdrawn','3B'), ('submitted','2')]` → *"clearing status_code on 1 withdrawn
  claim(s)"* → `[('withdrawn', None), ('submitted','2')]`. **WO-93's pinned test keeps its name
  and its meaning and now proves MORE**: it asserts the fix, then writes a stale code back onto
  the row by hand — the shape a pre-WO-94 database still holds — and asserts the portal still
  shows nothing. 0 assertions weakened.
  **N3 — the upload size cap was defined twice, and the configurable one was not the one
  enforced.** The harm was reproduced through the real HTTP path in BOTH directions before any
  fix: with `max_upload_mb = 50` a 20 MB PDF still got `413 "File too large (max 15 MB)"`, and
  with `max_upload_mb = 1` a 5 MB PDF passed the route and was refused downstream as `415` — a
  size problem reported as a type problem. **The sweep found the backlog row understated it**:
  SEVEN hard-coded caps in SIX route modules (the constant was at line 73, not 55). Three
  duplicated the configured default; two were deliberately tighter policy; and two —
  `_ATTACH_MAX = 25 MB` in `invoice_review.py` and `issued.py` — were **DEAD**, because
  `reject_active_content` already capped those paths at the configured 15 MB, so both routes
  advertised in their own 413 message a limit the gate behind them made unreachable.
  `filesec.max_bytes(purpose=None)` is now the one definition, `too_large_message()` renders the
  sentence from the SAME number so no caller can quote a figure it does not enforce, and
  `PURPOSE_MB` keeps the two tighter caps (receipt 5 MB, logo 2 MB) as named policy CLAMPED by
  the general cap — so lowering `MAX_UPLOAD_MB` takes effect everywhere and a purpose can only
  ever tighten. **BEHAVIOUR CHANGE, stated rather than slipped in:** (1) raising `MAX_UPLOAD_MB`
  now takes effect on `POST /invoices/upload`, `/expenses/import/bank-statement` and
  `/reconciliation/import` — at the default of 15 the accepted set is byte-identical, above it
  these three accept more than they did, which is the fix N3 asks for; (2) a size refusal that
  came back as 415 from `filesec` now comes back as 413 from the route (the two former 25 MB
  attachment paths for 16–25 MB files, and any path where an operator LOWERED the cap) — same
  accept/reject decision, correct status, and a message quoting the number actually enforced.
  No cap is loosened at its default. The deliverable is the STRUCTURAL guarantee
  (`tests/test_wo94_upload_cap.py`): an AST scan over the WHOLE `app/` package — not just
  routes, because a service growing its own constant forks the truth just as well — flagging a
  megabyte-scale literal or a byte-length gate not reading `filesec.max_bytes()`, with three
  seeded-violation self-tests including one carrying NO megabyte literal at all (a settings-read
  fork, which signal 1 alone cannot see) and a NEGATIVE self-test proving it does not shout
  about `len(parts) >= hops` / `len(items) >= limit` / `len(msg_id) > MSG_ID_MAX`, all three of
  which are real lines in this tree and none of which is a byte cap.
  No new permission, no new tenant table (so no RLS/parity entry), no route added, no SPA change
  (`grep -rn "15 MB\|25 MB\|MAX_UPLOAD" frontend/src frontend/e2e` returns nothing).
  Detail: `docs/plan/plan-a/wo/WO-94-known-defects.md`.

---

## M2 — In Progress

- [x] **WO-47** — `Completed` — Quota/usage-limit model now keys off the org's `plan`
  (`app.services.plans.PLANS`), not the acting user's role (the plan flagged this as must-fix
  "before the first invoice, not after") — every member of an org shares one org-wide cap;
  `role_policies`→`plan_policies`. Preserves the never-lose-a-document-on-limit guardrail (every
  quota check still runs before anything is persisted; block-at-the-cap, since auto-charge overage
  needs live billing, still owner-blocked). Detail: `docs/plan/plan-a/wo/WO-47-H13.md`.
- [x] **WO-48** — `Completed` — Dogfood fallback (H1.6): `app.services.platform_billing` invoices
  InvoiceIQ's own paying tenants through the platform's own AR module (issuer registry, gap-free
  numbering, PDF/XML, send, dunning — all pre-existing, zero new delivery code) once per calendar
  month, whenever no live billing provider is configured. Off by default (`platform_org_id` unset);
  applies a 0% VAT placeholder pending the seller-of-record decision (§2/§2b). Revenue is no longer
  blocked on Stripe/EveryPay credentials landing. Detail: `docs/plan/plan-a/wo/WO-48-H16.md`.

### M2 — Blocked on owner/business decisions (not code-blocked; tracked in `docs/DECISIONS-NEEDED.md`)

- [ ] **Stripe live** — Checkout, Billing Portal, signed webhook, Billing Meter. Needs production
  Stripe credentials from the owner. **Fallback shipped (WO-48):** AR-module dogfood invoicing —
  revenue is not blocked on this; activation is an operational config step, `docs/DECISIONS-NEEDED.md`
  §2b.
- [ ] **Seller-of-record VAT process** — Stripe Tax vs. an explicit alternative; a finance decision.
- [ ] **Plan ladder reconciliation (H1.2)** — code implements trial/starter/pro/enterprise
  (€0/€29/€99/custom); the pricing hypothesis doc proposes a different Free/€39/€99/€249/Enterprise +
  Practice ladder. They conflict; the owner must pick one. WO-47's quota fix already uses whichever
  ladder is live in code today (indicative defaults, sysadmin-overridable) — this decision changes
  only `plans.py::PLANS`, not the enforcement mechanism. `docs/DECISIONS-NEEDED.md` §2a.

---

## M1 — Completed (WO-12…46)

Epics F1.1 (master-data/document screens) · C1.5–C1.9 (currency/dimension registries, multi-currency
reporting, dead-state removal, reclaimable-VAT fix) · I1.1–I1.3/I1.5 (composed dashboard, grouped nav
IA, honest cash-position label, report writers) · A1.5 (8 business roles reachable) · E1.1–E1.7
(capture-review UI, line-item provenance, hash re-upload detection, Mailgun adapter, extraction
learning loop) — all shipped, tested, documented. Full list: `docs/plan/plan-a/wo/WO-12*.md` through
`WO-46*.md`.

### 4-agent SaaS review-board audit (R1–R19) — Completed except 2 open

| Item | Status | Closed by |
|---|---|---|
| R1 — CSV formula-injection across 3 exports | ✅ Completed | WO-29 |
| R2 — Credit-note creation had no row lock (over-crediting race) | ✅ Completed | WO-26 |
| R3 — Seed data self-contradicted (Cash Position vs Invoices) | ✅ Completed | WO-28 |
| R4 — Expense-decision had no concurrency guard | ✅ Completed | WO-30 |
| R5(b) — Enterprise self-upgrade-for-free billing bypass | ✅ Completed | WO-31 |
| R5(a) — Self-serve billing collects zero real payment | 🔶 **Owner-blocked** | → M2 (Stripe live) |
| R6 — Reimbursement payout had no maker≠checker SoD | ✅ Completed | WO-32 |
| R7 — ClamAV fail-closed branch had no test coverage | ✅ Completed | WO-33 |
| R8 — OIDC discover/JWKS had no SSRF guard | ✅ Completed | WO-37 |
| R9 — Duplicate CSV-sanitization helper (3×) | ✅ Completed | WO-36 |
| R10 — `LocalStorage._path` bare-`startswith` containment | ✅ Completed | WO-42 |
| R11 — Stale SSO `client_secret` TODO comment | ✅ Completed | WO-41 |
| R12 — Stale README/ARCHITECTURE.md counts | ✅ Completed | WO-10 + ongoing truth-up (verified count now in README) |
| R13 — `test_refresh_owner_only_and_graceful` didn't test "owner only" | ✅ Completed | WO-38 |
| **R14** — No application-owned backup/restore tooling | 🔴 **Decision-gated** | Needs an owner/ops decision (infra-level DR runbook vs. app-level capability) before any code — see `docs/audit/remediation-roadmap.md` R14 detail |
| R16 — AR Void/Write-off had no confirmation dialog | ✅ Completed | WO-34 |
| R17 — Payment-run Cancel had no confirmation | ✅ Completed | WO-39 |
| R18 — Billing downgrade silently disabled modules | ✅ Completed | WO-35 |
| **R15** — No load/concurrency/large-dataset perf harness | ⚪ **Backlog (P3)** | Standalone build, not started — larger effort, own future work order |
| **R19** — No guided onboarding/setup-wizard checklist | ⚪ **Backlog (P3)** | Standalone build, not started — larger effort, own future work order |

### UX/UI redesign audit — Phase 1 complete, implementation started

- [x] **Audit** — `Completed` — `docs/design/UX-AUDIT.md`. Verdict: the WO-17 grouped sidebar nav is
  already good, do not rebuild; two CRITICAL findings (silent-failure async states on 26 pages;
  unlabeled form controls, WCAG 1.3.1/4.1.2) and one HIGH (design system built but ~unused —
  migration, not new-build).
- [x] **WO-45-UX1** — `Completed` — `QueryState`'s error branch now renders `ErrorState`
  (`role="alert"`, retry via `onRetry`) instead of `EmptyState` — the fix that upgrades every
  current and future `QueryState` consumer at once. Adopted `QueryState`+`PageHeader` on all eight
  money-bearing pages (`Invoices`, `Expenses`, `PaymentRuns`, `InvoiceDetail`, `CashPosition`,
  `IssuedReports`, `Receipts`, `Review`) — each independently-failing region gets its own
  `QueryState` (e.g. `Expenses.tsx`'s "awaiting my approval" vs "my reports" panels; `IssuedReports`'
  4 tabs); `PageHeader` hoisted above the loading/error branch on every page, collapsing
  `Expenses.tsx`/`IssuedReports.tsx`'s duplicate `<h1>`s. `CashPosition.tsx`'s WO-18 honesty copy
  moved verbatim into `PageHeader`'s `description` — `e2e/cash-position.spec.ts` passes unmodified.
  Unclipped the Invoices table (`overflow-hidden` → `overflow-x-auto`, Invoices.tsx only, per scope).
  Added a focus ring to the legacy `btn` `@utility` — using `ring-brand-500` (the WO's `ring-brand-400`
  does not exist as a theme token; adding one was explicitly out of scope, so this order used the
  nearest real token rather than inventing one, flagged in the commit). New
  `frontend/e2e/error-states.spec.ts` (7 tests: 500/empty/403/retry on Invoices, partial-failure on
  Expenses, single-region failures on Review/PaymentRuns) + `nav.spec.ts` extended with a single-`<h1>`
  guarantee across all eight routes + an invoice-detail route. All 5 "must pass unmodified" specs
  (`cash-position`, `dashboard`, `smoke`, `masters`, `upload-duplicate`) pass byte-identical; visual
  regression (`test:vr`) shows **zero** snapshot diffs (none of the `/design` showcase fixtures
  exercise a focused button or a query-error state, so this is the correct, verified outcome, not a
  missed change). Zero backend files touched. Detail:
  `docs/plan/plan-a/wo/WO-45-UX1-async-state-and-page-header.md`.
- [ ] Further UX slices (design-system migration across remaining pages, form-label pass, nav collapse
  rail/group-collapse/breadcrumbs, orphaned-route wiring for `/issuer` and `/reimbursements`) —
  `Backlog`, scoped in `docs/design/UX-AUDIT.md`'s phased plan, to be written up as WO-48+ in turn.

---

## M0 — Completed (WO-1…11)

Structural authorization + CI coverage gate · vendor bank-detail dual control (the IBAN fraud vector)
· partners router lockdown · per-request org-suspension + session revocation · mandatory inbound-email
secret · PII quarantine (tree + full-history CI scan) · one validation engine · one FX convention (the
SEPA wrong-currency bug) · payment-run maker≠checker/export-once/MsgId · docs truth-up + ADRs + the
tenancy-parity probe · `users.org_id`→memberships (B1.5). Full detail: `docs/M0-exit-gate.md`.

---

## Historical note

Everything below this line is the original 2026-07-27 audit snapshot, preserved for traceability. Every
item on it is now closed or reclassified above — do not treat it as current; the tables above supersede
it entirely. The original per-item detail sections it links to remain live in `docs/audit/`.

<details>
<summary>Original 2026-07-27 board (click to expand — superseded)</summary>

This board is seeded from the Phase 1-11 independent 4-agent SaaS review board audit (see
`docs/audit/`, run on branch `claude/bidit-invoice-data-analytics`, 2026-07-27). It reflects the
**debate-adjusted** priorities in `docs/audit/remediation-roadmap.md`. Every P0/P1 item starts as
**Approved** (ready for a work order); every P2 starts as **Backlog**; P3/P4 items are also
**Backlog** (lower priority, schedule opportunistically). No disputed/rejected findings occurred in
this audit round — see `docs/audit/agent-debate.md`'s "Disputed / rejected findings" section.

Statuses: `Backlog` · `Approved` · `In Progress` · `Blocked` · `Testing` · `Review` · `Completed` · `Rejected`

Implementation of these items is explicitly **out of scope for this pass** — each item becomes its own
future work order (WO-26+), reviewed one change at a time, matching the WO-1..WO-25 pattern already used
in this repo (see `git log` / `docs/plan/`).

### P0 — blocks any pilot (Approved)

- [x] **R2** — Credit-note creation has no row lock, violating the codebase's own non-negotiable
  invariant on over-crediting (reproduced live). Evidence: `docs/audit/functional-audit.md` §2.1,
  `docs/audit/agent-debate.md` §1.
- [x] **R3** — Demo/seed data self-contradicts: Cash Position/Payment Runs show €0 owed while
  Invoices lists >€1M. Evidence: `docs/audit/commercial-readiness.md` §3, `docs/audit/agent-debate.md` §8.

### P1 — blocks general (self-serve) release (Approved)

- [x] **R1** — CSV formula-injection sanitization inconsistently applied across 3 financial exports.
  Evidence: `docs/audit/functional-audit.md` §3.1, `docs/audit/security-findings.md` §2.4.
- [x] **R4** — Expense-approval decision has no optimistic-concurrency guard or row lock.
  Evidence: `docs/audit/test-baseline.md` finding #2.
- [ ] **R5** — Self-serve billing collects zero real payment today; Enterprise tier is self-upgradable
  for free even with billing wired (`price_eur=None` bypass). Split: the free-upgrade bypass closed
  (WO-31); the "collects zero real payment" half is owner-blocked, tracked under M2 above.
  Evidence: `docs/audit/commercial-readiness.md` §7.

### P2 — should fix before general release (Backlog)

- [x] **R6** — Reimbursement payout had no maker≠checker (SoD) control.
- [x] **R7** — ClamAV fail-closed malware-scan branch had zero test coverage.
- [ ] **R14** — No application-owned backup/restore tooling exists; decision-gated. Still open —
  tracked above.
- [x] **R16** — AR "Issue" screen: destructive actions had no confirmation dialog.
- [x] **R18** — Billing downgrade silently disabled modules with no confirmation.

### P3 — backlog / hardening (Backlog)

- [x] **R8** — OIDC `discover()`/`fetch_jwks()` had no SSRF guard.
- [x] **R9** — Duplicate CSV-sanitization helper implemented 3x.
- [x] **R13** — `test_fx.py::test_refresh_owner_only_and_graceful` didn't actually test "owner only."
- [ ] **R15** — No load/concurrency/large-dataset performance testing harness. Still open — tracked above.
- [x] **R17** — Payment-run "Cancel" button fired with no confirmation.
- [ ] **R19** — No guided onboarding/setup-wizard checklist. Still open — tracked above.

### P4 — informational / doc hygiene (Backlog)

- [x] **R10** — `LocalStorage._path` containment check used bare `startswith`.
- [x] **R11** — Stale `# TODO: secret store` comment on `SsoConnection.client_secret`.
- [x] **R12** — Root `README.md`/`ARCHITECTURE.md` were stale.

### Verified controls — no action required (not tasks; recorded for traceability)

These were raised during the audit (some at P1) but resolved through adversarial debate as
**confirmations of existing strength**, not defects — see `docs/audit/agent-debate.md` and
`docs/audit/remediation-roadmap.md`'s "Verified controls" section:

- Tenant isolation (query filter + ORM guard + Postgres RLS with FORCE) — independently reproduced
  live against a real Postgres cluster twice.
- Structural, CI-gated route authorization (`test_authz_coverage.py`) — recommend keeping this a
  required, unfiltered CI gate.
- Upload/attachment security gate (`filesec.py`) — covers all 8 intake paths, live exploit tests pass.
- `docs/plan/plan-a/ARCH_plan.md`'s prior risk claims (vendors/partners authz, route-level
  `_reconcile`, hardcoded EUR) were stale/false against source at audit time — since superseded by the
  banner fix (2026-07-28); the document is current again.

*Backlog items predating this audit, if any existed at the repo root, are preserved in
`docs/BACKLOG.md` (pre-existing) — this file is the audit-derived task board and does not duplicate or
supersede that doc; see `docs/BACKLOG.md` for other in-flight work not covered by this audit round.*

</details>
