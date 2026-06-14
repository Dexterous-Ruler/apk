# 📱 APKSHIELD — GenAI Fraudulent-APK Forensics & Risk Scoring

### ▶ Try it live — no install, one click on Google Colab

[![Open In Colab](https://colab.research.google.com/assets/colab-badge.svg)](https://colab.research.google.com/github/Dexterous-Ruler/apk/blob/main/APKShield_Colab.ipynb)

**Live dashboard:** https://colab.research.google.com/github/Dexterous-Ruler/apk/blob/main/APKShield_Colab.ipynb

> Open the notebook → **Runtime → Run all** → click the URL it prints. Then upload an APK
> (or click a bundled sample) for an instant risk score, and **"Run deep analysis"** for the
> GenAI reverse-engineering + dynamic-sandbox showcase. Runs offline (template mode) or at full
> power with free API keys. Setup details: [HOW_TO_RUN.md](HOW_TO_RUN.md) · pitch content: [SOLUTION_APPROACH.md](SOLUTION_APPROACH.md)

---

*Generative AI-Based Automated Analysis and Risk Scoring of Fraudulent APKs — static + dynamic
+ reverse engineering + risk scoring, with GenAI doing the interpretive heavy lifting.*

## Problem statement (as given in `../Topic.pdf`)
Fraudsters distribute malicious APKs via WhatsApp/SMS/email/phishing to steal
credentials and perform unauthorized transactions. Build a **GenAI-powered malware
analysis system** that automatically analyzes suspicious APK files: static + dynamic
analysis of permissions, APIs, embedded code, runtime activity, and network
communications; GenAI for reverse engineering, pattern recognition, code
interpretation, and threat summarization. Output: malware-pattern detection, threat
severity classification, **0–100 risk scores**, and detailed investigation reports
with actionable recommendations.

> **No dataset is provided for this topic** — we supply our own APK samples
> (benign + malicious). See §6 of the playbook for sources (Drebin, CICMalDroid 2020,
> AndroZoo, MalwareBazaar).

## Key documents
| File | What |
|---|---|
| `Topic1_APK_Fraud_GenAI_Playbook.md` | **The strategy doc** — full execution-ready blueprint: winning thesis, layered architecture (static → impersonation → threat-intel → ML → GenAI report), verified repos, datasets, honest-eval rules, hour-by-hour plan |
| `research/research_digest_apk.txt` | Raw verified research sweep (APK sections only): 15 verified repos, techniques, datasets, judging criteria, pitfalls |

## Status: BUILT, AUDITED & hardened
Full pipeline works end-to-end in <1s/APK. Crafted fake-bank samples score
87–89 CRITICAL; benign apps 0–5 MINIMAL; **4 real in-the-wild Hook banking
trojans** (MalwareBazaar) score 85 CRITICAL — analyzed **in-memory** (never
written to disk, never executed). Live Claude report + VirusTotal/MalwareBazaar
threat intel are wired and verified. Dashboard verified headless (zero console
errors). See `outputs/REPORT.md` for live eval numbers and `DEMO_RUNBOOK.md`
for the pitch script.

**Adversarial audit (`outputs/AUDIT_REPORT.md`):** a 24-agent code+benchmark
audit graded this a *genuine industrial-grade prototype, not demo-ware*. The
gaps it found have been fixed: (1) ML CV is now **StratifiedGroupKFold** over
identical vectors — disclosed 51.7% duplicates, dedup-safe PR-AUC **0.9967**
(was 0.9984, so the metric was robust and is now honest); (2) the impersonation
layer no longer false-positives benign apps ("INDIE Music Player", "piggybank",
the genuine bank app) or emits a false "impersonates Google" — boundary/token
matching with a self-test of FP negatives; (3) the DEX parser is bounds-checked
(a malformed/packed secondary dex no longer aborts the report); (4) GenAI has
prompt-injection delimiters + host-aware IOC grounding; (5) demo endpoints are
exception-wrapped with path-traversal guards. Remaining roadmap: dynamic
analysis (MobSF/Frida), real pinned bank certs, one cross-corpus generalization
number.

### Full problem-statement coverage (see `outputs/PROBLEM_STATEMENT_COVERAGE.md`)
All clauses of *"GenAI for Automated Reverse Engineering, Static and Dynamic
Analysis, and Risk Scoring of Fraudulent APKs and Malwares"* are now delivered:
- **Reverse engineering** — `deep_analysis.py` builds an in-memory call-graph (real malware never on disk), and Claude **reads the decompiled smali** and reconstructs the logic (`reverse_engineer.py`). On a real Cerberus sample it recovered the AES-encrypted SMS command channel + C2 `cerberusapp.com`.
- **Dynamic analysis** — real sandbox runtime behavior via VirusTotal multi-sandbox detonation (hash-only) + self-hosted **Frida** (`tools/frida_hooks.js`) / **MobSF** harness (`dynamic_analysis.py`). The sandbox **confirms the C2 the RE found** — static→dynamic cross-validation.
- **Behavioral taint** — source→sink data-flows (SMS→network = OTP exfil) over the call graph.

These run as an on-demand **Deep Analysis** step (~20–40s) so the fast verdict
stays instant. The GenAI report is generated **asynchronously** — the verdict
renders immediately and the report fills in after.

### The threat-intel scoring layer (key design point)
The static ML model is Drebin-era and scores *modern* obfuscated trojans near
zero (their payload loads at runtime — invisible to static features). Threat
intel is therefore a **scoring layer, not just a panel**: multi-vendor AV
consensus (VirusTotal) or a MalwareBazaar catalogue hit **escalates** the risk
score (raise-only — absence of a detection is never treated as safe). This is
why the real Hook samples land at CRITICAL despite ML ≈ 0, and it's the
strongest argument for the layered design over a pure-ML classifier.

## Quick start
```powershell
cd C:\Users\tanis\hackathon\apk
pip install -r requirements.txt

# (optional) live Claude report + threat intel — works without them via fallback
$env:ANTHROPIC_API_KEY = "sk-ant-..."     # else a deterministic template report runs
$env:VT_API_KEY  = "..."                  # VirusTotal (hash-only lookups)
$env:MWB_API_KEY = "..."                  # MalwareBazaar (auth.abuse.ch)

python server.py                          # -> http://127.0.0.1:8800  (mule uses 8700)
```
Then open **http://127.0.0.1:8800**, drag in an APK (or click a bundled
sample chip) → 0–100 risk gauge + evidence tabs + GenAI investigation report.

CLI (no server): `python src/pipeline.py data\samples\crafted\fake_sbi_yono_rewards.apk`

To rebuild the model / report / samples:
```powershell
python analysis\train_model.py        # 5-fold CV over Drebin-215 -> outputs/apk_model_bundle.joblib
python analysis\build_report.py       # regenerate outputs/REPORT.md with live numbers
python tools\build_fake_bank.py       # rebuild the crafted demo APKs
python analysis\fetch_real_samples.py # pull real MalwareBazaar samples, analyze in-memory
```

## Folder layout (built)
```
apk/
├── README.md  ·  Topic1_APK_Fraud_GenAI_Playbook.md  ·  DEMO_RUNBOOK.md
├── requirements.txt
├── server.py                              # Flask backend, port 8800 (independent of mule/)
├── src/
│   ├── apk_static.py        # Androguard + APKiD static extractor -> evidence + Drebin vector
│   ├── dexparse.py          # fast DEX string/class/method-ref table parser
│   ├── drebin_map.py        # maps an APK onto the 215 Drebin features
│   ├── impersonation.py     # bank typosquat + package/cert/icon mimicry -> 0-100 score
│   ├── risk.py              # fuses ML + impersonation + capability combos -> 0-100 risk
│   ├── genai_report.py      # Claude investigation report + grounding check + template fallback
│   ├── threat_intel.py      # VirusTotal + MalwareBazaar (hash-only, cached) — a SCORING layer
│   ├── deep_analysis.py     # in-memory call-graph: behavioral taint + RE target+smali extraction
│   ├── reverse_engineer.py  # Claude READS the decompiled bytecode -> RE report (grounded)
│   ├── dynamic_analysis.py  # VT sandbox runtime behavior + self-hosted Frida/MobSF harness
│   ├── pipeline.py          # end-to-end orchestration (path or in-memory bytes)
│   ├── bank_allowlist.json  # official Indian bank/UPI app identities
│   └── drebin_features.json # the 215 feature names
├── tools/                   # axml.py + dexgen.py + build_fake_bank.py (crafts harmless demo APKs)
│                            #   + frida_hooks.js (live-detonation hooks) + bin/jadx (optional decompiler)
├── data/
│   ├── training/drebin215.csv         # ML training set (5,560 mal / 9,476 benign)
│   └── samples/
│       ├── {benign,crafted}/          # test APKs (benign + our harmless fake-bank builds)
│       └── real_encrypted/            # real MalwareBazaar samples, kept AES-ENCRYPTED on disk
│                                      #   (decrypted only in memory at analysis time — never run)
├── analysis/                # train_model.py, build_report.py, _ui_test.py, screenshots
├── outputs/                 # apk_model_bundle.joblib, metrics, REPORT.md, scans/, caches
├── web/                     # APKSHIELD dashboard (index.html, styles.css, app.js) — "Carbon Signal"
└── research/                # APK-only research digest
```

## The 6-layer target architecture (from the playbook)
1. **[A] Static analysis** — Androguard (permissions, intents, API calls, cert, URLs) + APKiD (packer detection)
2. **[B] Impersonation check** *(the fake-BANK differentiator)* — typosquat distance, package-keyword heuristics, official Indian bank package+cert allowlist, icon perceptual hash, SHA-256 vs official binaries
3. **[C] Threat intel** — VirusTotal, MalwareBazaar, Play Integrity (sideload/tamper)
4. **[D] ML risk model** — RandomForest/XGBoost on Drebin-style features → fused 0–100 risk score
5. **[E] GenAI layer** — LLM explanation/triage: plain-language verdict, MITRE ATT&CK mapping, multilingual scam explanation, hallucination grounding check
6. **[F] Investigation report** — severity + evidence + recommendations + CERT-In takedown evidence kit

Stretch: **[G] dynamic analysis** (MobSF + Frida in a sandbox).

## How the 0–100 risk score is built
Three independent layers are fused (weights ML 45 / impersonation 35 / static 20),
so no single bypassed signal collapses the verdict:
- **ML** — LightGBM on 215 Drebin static features (selected over RF/XGBoost by OOF PR-AUC). Live APK → feature vector via our own Androguard + DEX-table extractor.
- **Impersonation** — typosquat name distance, official-bank package/cert/icon mimicry, lure keywords, junk-certificate detection → 0–100, targeting a named bank.
- **Static capability combos** — accessibility+overlay+SMS (the SOVA/Anubis OTP-theft pattern), dropper, persistence, packer — combinations score, single permissions don't.

The GenAI layer (Claude) sits on top as the **interpretation** layer only, with a
grounding check that strips invented IOCs and a template fallback for offline use.

## Non-negotiables (from the research) — all implemented
- **Working end-to-end demo beats accuracy numbers** — upload APK → verdict + reasons in <30 s, with a recorded fallback video.
- **Honest evaluation**: precision/recall/F1/FPR at ~90% benign ratio, dedup repacked APKs, time-aware (TESSERACT) split — never quote accuracy alone.
- **Never execute malware on the demo machine** — static IOC extraction only; sandbox/VM for anything dynamic.
- **Don't tell the LLM "this is malware"** (it biases every function as suspicious); judge maliciousness separately, and demo a caught hallucination.
