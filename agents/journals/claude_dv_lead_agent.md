# Journal: claude_dv_lead_agent

- **Agent**: dv_lead (Opus 5 lead)
- **Charter**: agents/charters/dv_lead.md
- **Format**: v1 — entry grammar in agents/PROTOCOL.md §4

This file is APPEND-ONLY. Content may only ever be added after the last line;
nothing above it is ever edited. Enforced by scripts/agent_commit.sh and CI.

---

## [J-dv_lead-0001] 2026-08-02T00:28:00Z | task:WO-0003 | Testability review of the 108 Phase-1 REQs: 55 TESTABLE, 49 AMBIGUOUS, 4 UNTESTABLE; countersignature withheld pending 16 spec diffs

### Trigger
Orchestrator spawn under work order WO-0003 (ISSUED at 02e38e7), spawn short-id
`WO-0003/2026-08-02T00:25Z`. First activation of the verification function. The
architect proposed and the orchestrator accepted that this review land *before*
the `P1-spec-freeze` checklist opens, so my objections arrive as spec diffs
rather than as gate blockers. This entry records the review that is supposed to
make my later freeze countersignature (charter §3, PROTOCOL §7) an honest
signature rather than a ceremonial one.

### Inputs
- `agents/charters/dv_lead.md`; `agents/PROTOCOL.md` (whole, working from §4
  grammar, §6 scopes, §7 gates, §10 independence).
- `agents/handoffs/WO-0003_requirements-testability-review.md` (at 02e38e7);
  `agents/handoffs/README.md` (packet forms).
- **Review target: `docs/specs/requirements.md` at 08899d3.** Verified unchanged
  between 08899d3 and HEAD 81acc2c before reviewing it (command in Evidence).
- Context at 08899d3: `docs/specs/architecture.md`, `docs/specs/SPEC-TEMPLATE.md`,
  `docs/specs/traceability.md`.
- `docs/adr/ADR-0004-toolchain-lane.md`, `docs/adr/ADR-0005-build-environment.md`,
  `README.md`, `ORG_CHART.md`.
- For the feasibility note only: `agentic_fpga.opam`, `dune-project`,
  `test/hardcaml_ethernet/dune`, the `.github/workflows/` file listing.
- **No RTL was read.** `libs/**` was never opened and `rtl_snapshots/**` was never
  opened. Independence discipline per PROTOCOL §10 and charter §8: every
  disposition below derives from specification text alone.

### Reasoning
The unit of work was a judgement call repeated 108 times, so what matters here is
the standard I applied and the standards I rejected.

**The reader I reviewed for.** I did not ask "is this row clear to someone who has
read all 108 rows and both companion documents". I asked "can a tb_writer who
receives *this excerpt and nothing else*, and who is deliberately denied RTL
(PROTOCOL §10), build the right bench". That is a stricter test and it is the one
that matches how the work will actually be delegated. It is what produced four of
the ten cross-cutting findings: "receive path" is quantified over but never
defined (X-1), the frame-length convention is never stated (X-2), §0's claim to be
the *sole* test-derivation basis is false because latency constants and module
pairings live elsewhere (X-3), and latency measurement points are named nowhere
(X-6). None of those would have surfaced from a whole-document read.

**A defective Verification cell is a spec diff, not something to route around.**
This was the central methodological decision and it drives roughly a third of the
findings. The alternative I rejected was tempting and cheaper: where the stated
method is wrong, simply build the bench I know is right and leave the document
alone. I rejected it because `traceability.md` binds each REQ to the tests
covering it and the auditor checks my tests against the Verification column — so
silently substituting my own method makes either the matrix or my signature
false, and does it invisibly. REQ-802 is the proof case: its cell commissions "one
directed test per field", two of its twelve fields have no behavioural
requirement anywhere in the document, and had I routed around that, the matrix
would have read `COVERED` with no record anywhere that two fields were untestable.
The same logic applies to methods that cannot detect their own violation
(REQ-008's silent-discard prohibition tested only via declared strobes, REQ-019's
constant-latency evidence which a constant-but-deep buffer passes, REQ-004's
"no backpressure asserted" which cannot fail when no `tready` exists, REQ-015's
monitor watching a tautology). The WO asked for exactly this class and I treated
it as first-class rather than as commentary.

**Severity ladder.** I graded each finding blocking / should-fix / editorial.
Rejected: calling every divergence blocking — thirty of fifty-three non-TESTABLE
rows are blocking as it is, and inflating that would have made the must-fix list
unusable and dishonest about relative cost. Also rejected: only flagging things
that would break a conformant design — that would have let the unfalsifiable
methods through, which is precisely the failure mode the countersignature exists
to prevent. The line I settled on: blocking iff I cannot determine pass/fail for a
conformant design, or the REQ has no DV observable, or the method provably cannot
detect the violation it prohibits.

**Consolidation.** Thirty blocking rows became sixteen spec diffs, because most
share a root cause. That was deliberate: the architect has to *apply* these, and
sixteen grouped diffs with affected-REQ lists is actionable where thirty bullets
is a backlog.

**Checking arithmetic instead of trusting it.** I chose to actually compute the
two CRC constants against an independent implementation rather than accept them.
Both are wrong: REQ-303's check value is 0xCBF43F26 where CRC-32/ISO-HDLC gives
0xCBF43926, and REQ-304's residue is stated as 0xC704DD7B where REQ-301's own
parameterisation (reflected in and out, final XOR) yields 0x2144DF1C —
0xC704DD7B being the same residue in the non-reflected register convention. The
second is the instructive one: it is a real, widely published Ethernet constant,
so it survives any amount of careful reading; only computation catches it. Both
would have been hard-coded into the FCS bench, both would have failed against
correct RTL, and both would have produced a CRITICAL `BUG-` against rtl_lead for
a defect living in the specification. I am adopting this as standing practice for
every numeric constant in the per-module specs.

**Walking the line-rate arithmetic instead of accepting it.** Same reasoning
applied to §0's claim that a minimum frame occupies 84 octets and arrives every
10.5 cycles. Walking the XGMII lanes cycle by cycle reproduces the 10/11
alternation *only* if the terminate character is counted inside the 12-octet
inter-frame gap — but REQ-204 requires 12 *idle* octets after the terminate
character, the opposite convention, under which the minimum spacing becomes 11
and 11. REQ-204's own expected answer (88 octets start-to-start) is insensitive to
the difference because of lane-0 rounding, which is exactly why it hides. Left
unfixed, every line-rate stress bench in Phase 1 would have under-driven every
receive-path module by about ten percent while reporting green forever. This is
D-3 and it is the finding I would have most regretted missing.

**The latency definition (D-4).** REQ-005 asks for "the delay from a word entering
a module to that word leaving it", which names no event at a realigning module
because one input word's octets appear in two output words; and REQ-111 demands a
constant "independent of start lane", which no design can satisfy, since a lane-4
start needs one more input word before the first output word can be assembled. I
considered keeping a per-word measurement with a start-lane exemption and rejected
it: it leaves REQ-019 with no observable at all. The per-octet formulation I
propose instead is well-defined across realignment and both start lanes, gives
REQ-019 a real ceiling test once architecture §4's allocation table is imported,
and — the reason I like it most — makes REQ-005's evidence a by-product of the
REQ-004 stress run, so the constant-latency claim gets ten thousand frames of
evidence instead of six, at no extra cost. One scoreboard then discharges REQ-004,
REQ-005/111 and (with D-6's conservation counts) REQ-008.

**Feasibility.** I concluded Cyclesim carries the 10 000-frame stress comfortably
(~110 000 cycles per bench) and refused to force the Verilator lane early. The
rejected option was adopting `hardcaml_verilator` now "to be safe": it front-loads
a CI system-binary dependency onto the first bench when it actually belongs to
REQ-901 co-simulation and the Phase-2 replay. The real constraints are waveform
capture (must be off at this cycle count) and expect-block content (summary, not
trace), not simulator throughput. Because ADR-0005 means I cannot measure anything
locally, I labelled the figures as estimates and proposed a cheap CI cost probe as
their falsification point rather than presenting them as measurements.

**What I deliberately did not raise.** Several rows where the correct reading is
not genuinely in dispute — REQ-014's `tstrb` differential, REQ-016's idle-cycle
counts, REQ-509's multicast example, REQ-406's tie-breaking — I recorded as
editorial or as coverage notes for my own attack plans rather than as spec diffs.
Keeping the must-fix list to things that actually block is what makes it worth
acting on. Likewise I did not edit `docs/specs/**`: it is outside my write scope
(PROTOCOL §6) and R7 would reject the commit, which is the correct outcome —
findings are requests to the architect, not edits by the adversary.

### Actions
- Dispositioned every one of the 108 REQs individually, no sampling, grouped by
  the ten blocks, with a one-paragraph summary per block.
- Wrote `agents/handoffs/WO-0003_testability-findings.md`: ten cross-cutting
  findings (X-1 … X-10), ten per-block sections, the REQ-004/REQ-005 bench
  feasibility section (verdict, arithmetic, five-layer bench architecture,
  toolchain gaps), and the verdict with sixteen must-fix spec diffs (D-1 … D-16)
  plus a non-blocking recommendation list.
- Verified the two CRC constants against an independent implementation.
- Walked the REQ-004 XGMII arrival pattern lane by lane to check the 10.5-cycle
  claim against REQ-204's stated gap convention.
- Cross-checked the deliverable's REQ id set against `requirements.md` and
  recomputed the per-block disposition counts mechanically.
- Appended the RETURNED entry to WO-0003's Return log.
- Wrote nothing under `test/`, `tools/`, `libs/`, `docs/specs/` or `docs/gates/`.

### Evidence
All commands runnable from a repo checkout at this SHA (PROTOCOL §4.1 form (a)).

1. Review target unchanged before review —
   `git diff --stat 08899d3 HEAD -- docs/specs/requirements.md` → no output
   (empty diff); `git log --oneline -1 -- docs/specs/requirements.md` →
   `08899d3 WO-0002: Phase-1 requirements (108 REQs), architecture, spec template, traceability`.

2. Full coverage, no sampling —
   `grep -cE '^\*\*REQ-[0-9]+ — ' agents/handoffs/WO-0003_testability-findings.md`
   → `108`; and the id sets are identical:
   `diff <(grep -oE '^\| \*\*REQ-[0-9]+\*\*' docs/specs/requirements.md | grep -oE 'REQ-[0-9]+' | sort -u) <(grep -oE '^\*\*REQ-[0-9]+' agents/handoffs/WO-0003_testability-findings.md | sed 's/^\*\*//' | sort -u)`
   → no output.

3. Disposition counts —
   `grep -oE '^\*\*REQ-[0-9]+ — (TESTABLE|AMBIGUOUS|UNTESTABLE)' agents/handoffs/WO-0003_testability-findings.md | awk '{print $3}' | sort | uniq -c`
   → `49 AMBIGUOUS`, `55 TESTABLE`, `4 UNTESTABLE` (total 108). Blocking rows:
   `grep -cE '^\*\*REQ-[0-9]+ — .*\(blocking' …` → `30`. Per-block counts
   (T/A/U): invariants 6/13/2, XGMII rx 4/9/0, XGMII tx 6/4/0, CRC 4/2/0,
   Ethernet 5/5/0, ARP 6/5/1, IPv4 9/3/0, UDP 5/4/0, top level 6/2/1, process
   4/2/0 — block totals 21/13/10/6/10/12/12/9/9/6, matching `traceability.md`'s
   counts table exactly.

4. CRC constant defects (Python 3.11.15, `zlib.crc32` is exactly REQ-301's
   parameterisation) —
   ```
   python3 - <<'EOF'
   import zlib, struct
   print("%08X" % (zlib.crc32(b"123456789") & 0xFFFFFFFF))
   m = bytes(range(60)); c = zlib.crc32(m) & 0xFFFFFFFF
   print("%08X" % (zlib.crc32(m + struct.pack("<I", c)) & 0xFFFFFFFF))
   print("%08X" % int('{:032b}'.format(0x2144DF1C ^ 0xFFFFFFFF)[::-1], 2))
   EOF
   ```
   → `CBF43926` (REQ-303 states `CBF43F26`), `2144DF1C` (REQ-304 states
   `C704DD7B`), `C704DD7B` (showing REQ-304's constant is the same residue in the
   non-reflected register convention). The residue was `2144DF1C` for every
   message length tried (9, 46, 60 octets) with the FCS appended
   least-significant-octet-first, and varied per message otherwise — which is what
   pins the FCS wire octet order in the REQ-202 finding.

5. **No build or test evidence is claimed.** ADR-0005 makes CI the authoritative
   build environment and no Hardcaml toolchain is installable in this container;
   this unit of work compiled nothing and ran no bench. The §13 feasibility
   figures are explicitly labelled engineering estimates in the deliverable, with
   a proposed CI cost probe named as their falsification point.

### Outcome
DoD of WO-0003 met. All 108 REQs dispositioned with no sampling; every AMBIGUOUS
and UNTESTABLE finding carries the quoted wording, the reading I would enforce,
and a concrete spec-diff request the architect can apply without asking me
anything; the REQ-004/REQ-005 feasibility note is delivered with the bench
architecture in prose and the toolchain gaps named; no RTL, no test code and no
golden model were written; nothing was touched outside `agents/handoffs/**` and
this journal. Handoff: `agents/handoffs/WO-0003_testability-findings.md`, with
WO-0003's Return log moved to RETURNED. **Verdict: testability countersignature
withheld pending sixteen spec diffs (D-1 … D-16); I would sign a post-diff
revision.** Fifty-five rows I would hand to a worker unchanged today.

### Open-questions
1. **X-9 — executor of the emitted-Verilog inspections.** Six REQs (001, 017, 018,
   306, 808, 903) are verified by inspecting `rtl_snapshots/` or `libs/`. My
   position is that reading a *build product* to check a port list is not deriving
   a test from RTL, and I will own these as scripts under `tools/` run in CI — but
   that should be a ratified decision, not my unilateral reading, since the auditor
   samples my Inputs sections for exactly this.
2. **Toolchain**: `hardcaml_step_testbench` is absent from `agentic_fpga.opam` and
   gates the first per-module benches; `hardcaml_verilator` plus a `verilator`
   binary in the CI image are needed for REQ-901 but not before it.
3. **Cost probe**: one throwaway CI bench measuring Cyclesim cycles-per-second on
   this runner, before the DV plan commits to 10 000-frame stress at `nic_top`.
   If it comes back badly, reducing the frame count is an E2 with numbers
   attached, not a silent narrowing.
4. **Sequencing**: D-1 … D-4 and D-10 change what benches *do*. They should land
   before Batch B (M03/M04) specs are written, since M03 is the module they most
   affect.
5. **Re-review**: my countersignature must be against the post-diff text. I expect
   a short follow-up work order to re-check the sixteen diffs before the
   `P1-spec-freeze` checklist opens; flagging it so it is scheduled rather than
   assumed.

### Files-in-this-commit
- agents/handoffs/WO-0003_testability-findings.md
- agents/handoffs/WO-0003_requirements-testability-review.md
