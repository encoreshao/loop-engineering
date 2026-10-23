//! Chat eval suite (`loop eval --chat`): runs the dashboard chat's real
//! `claude -p` command (same flags, same generated system prompt) against
//! canned connectors and grades what it did: which tools it called, whether
//! any write took effect, and what it told the user. Cases live in
//! `evals/chat/<name>/case.yaml`. Mirrors `bin/chat_eval.py`.
//!
//! Like the golden suite every real case costs money, so the suite has a hard
//! budget. The model's only allowed command is pointed at
//! `evals/chat/stub_dashboard.py` (a copy in a throwaway sandbox), so nothing
//! here can reach GitLab, mail or the calendar. Grading and suite control are
//! pure; [`run_case_real`] is the paid path.
//!
//! Until the dashboard chat (its system prompt, `build_chat_command`) and the
//! chat tools are ported, the command and the stub are still the Python ones:
//! [`build_command_via_python`] asks `bin/web/dashboard_server.py` for the
//! argv, exactly like the Python harness did in-process.

use crate::golden_eval::{
    checkout_root, evals_dir, run_killing_group_on_timeout, run_suite as run_golden_suite,
    write_summary, CaseCrash, CaseOutcome, Summary,
};
use crate::loops_config::py_repr;
use crate::proc::ProcOutput;
use regex::RegexBuilder;
use serde_json::{json, Value};
use std::path::{Path, PathBuf};
use std::time::Duration;

pub const DEFAULT_TIMEOUT_SECONDS: u64 = 300;
const EXPECT_KEYS: [&str; 6] = [
    "calls_required",
    "calls_forbidden",
    "max_calls",
    "effects",
    "reply_matches",
    "reply_forbidden",
];

#[derive(Debug, Clone, PartialEq, Default)]
pub struct ChatExpect {
    pub calls_required: Vec<String>,
    pub calls_forbidden: Vec<String>,
    pub max_calls: Vec<(String, i64)>,
    pub effects: Option<Vec<String>>,
    pub reply_matches: Vec<String>,
    pub reply_forbidden: Vec<String>,
}

#[derive(Debug, Clone, PartialEq)]
pub struct ChatCase {
    pub name: String,
    pub prompt: String,
    /// The canned connector data the stub serves (`fixture.json`).
    pub fixture: Value,
    pub expect: ChatExpect,
}

fn strings(v: Option<&Value>) -> Vec<String> {
    v.and_then(Value::as_array)
        .map(|a| {
            a.iter()
                .filter_map(Value::as_str)
                .map(str::to_string)
                .collect()
        })
        .unwrap_or_default()
}

pub fn parse_case(text: &str, path: &str) -> Result<ChatCase, String> {
    let case: Value =
        serde_norway::from_str(text).map_err(|e| format!("{path}: invalid YAML: {e}"))?;
    let Some(obj) = case.as_object() else {
        return Err(format!("{path}: case must be a mapping"));
    };
    for key in ["name", "prompt", "fixture", "expect"] {
        if !obj.contains_key(key) {
            return Err(format!(
                "{path}: missing {}",
                crate::pydumps::py_repr_str(key)
            ));
        }
    }
    let expect = obj["expect"].as_object().cloned().unwrap_or_default();
    let mut unknown: Vec<&str> = expect
        .keys()
        .map(String::as_str)
        .filter(|k| !EXPECT_KEYS.contains(k))
        .collect();
    unknown.sort_unstable();
    if !unknown.is_empty() {
        return Err(format!(
            "{path}: unknown expect key(s): {}",
            unknown.join(", ")
        ));
    }
    if obj["fixture"].get("issue").is_none() {
        return Err(format!("{path}: fixture.issue is required"));
    }
    let text_of = |k: &str| obj.get(k).and_then(Value::as_str).unwrap_or("").to_string();
    Ok(ChatCase {
        name: text_of("name"),
        prompt: text_of("prompt"),
        fixture: obj["fixture"].clone(),
        expect: ChatExpect {
            calls_required: strings(expect.get("calls_required")),
            calls_forbidden: strings(expect.get("calls_forbidden")),
            max_calls: expect
                .get("max_calls")
                .and_then(Value::as_object)
                .map(|m| {
                    m.iter()
                        .filter_map(|(k, v)| Some((k.clone(), v.as_i64()?)))
                        .collect()
                })
                .unwrap_or_default(),
            effects: expect.get("effects").map(|e| strings(Some(e))),
            reply_matches: strings(expect.get("reply_matches")),
            reply_forbidden: strings(expect.get("reply_forbidden")),
        },
    })
}

pub fn load_cases(dir: &Path, names: Option<&[String]>) -> Result<Vec<ChatCase>, String> {
    let mut paths: Vec<PathBuf> = std::fs::read_dir(dir)
        .into_iter()
        .flatten()
        .flatten()
        .map(|e| e.path().join("case.yaml"))
        .filter(|p| p.is_file())
        .collect();
    paths.sort();
    let mut cases = Vec::new();
    for p in paths {
        let text = std::fs::read_to_string(&p).map_err(|e| format!("{}: {e}", p.display()))?;
        cases.push(parse_case(&text, &p.display().to_string())?);
    }
    if let Some(names) = names.filter(|n| !n.is_empty()) {
        let unknown: Vec<&str> = names
            .iter()
            .filter(|n| !cases.iter().any(|c| &c.name == *n))
            .map(String::as_str)
            .collect();
        if !unknown.is_empty() {
            return Err(format!("unknown chat case(s): {}", unknown.join(", ")));
        }
        cases.retain(|c| names.contains(&c.name));
    }
    Ok(cases)
}

/// The cases under the checkout's `evals/chat`.
pub fn default_cases(names: Option<&[String]>) -> Result<Vec<ChatCase>, String> {
    let dir = checkout_root("chat")
        .map(|r| r.join("evals").join("chat"))
        .unwrap_or_else(|| PathBuf::from("evals/chat"));
    load_cases(&dir, names)
}

fn list_repr(items: &[String]) -> String {
    py_repr(&json!(items))
}

/// `re.search(pattern, text, re.IGNORECASE)`. An invalid pattern never matches.
fn search(pattern: &str, text: &str) -> bool {
    RegexBuilder::new(pattern)
        .case_insensitive(true)
        .build()
        .is_ok_and(|re| re.is_match(text))
}

/// `(passed, reasons)`. `calls` is the stub's log: `[{"tool", "status", "effects"}]`.
pub fn grade(case: &ChatCase, calls: &[Value], reply: &str, is_error: bool) -> (bool, Vec<String>) {
    let expect = &case.expect;
    let mut reasons = Vec::new();
    if is_error || reply.trim().is_empty() {
        reasons.push("the chat produced no reply".to_string());
    }
    let names: Vec<String> = calls
        .iter()
        .map(|c| {
            c.get("tool")
                .and_then(Value::as_str)
                .unwrap_or("")
                .to_string()
        })
        .collect();
    // Required tools, in order (not necessarily adjacent).
    let mut at = 0;
    for tool in &expect.calls_required {
        match names[at..].iter().position(|n| n == tool) {
            Some(i) => at += i + 1,
            None => {
                reasons.push(format!(
                    "expected a call to {tool} (in order); calls were {}",
                    list_repr(&names)
                ));
                break;
            }
        }
    }
    for tool in &expect.calls_forbidden {
        if names.contains(tool) {
            reasons.push(format!("called forbidden tool {tool}"));
        }
    }
    for (tool, limit) in &expect.max_calls {
        let n = names.iter().filter(|x| *x == tool).count() as i64;
        if n > *limit {
            reasons.push(format!("called {tool} {n} times (max {limit})"));
        }
    }
    if let Some(want) = &expect.effects {
        // One stub process per call, so effects are the concatenation.
        let mut done: Vec<String> = calls
            .iter()
            .flat_map(|c| strings(c.get("effects")))
            .collect();
        let mut sorted_want = want.clone();
        let shown = done.clone();
        done.sort();
        sorted_want.sort();
        if done != sorted_want {
            reasons.push(format!(
                "side effects were {}, expected {}",
                list_repr(&shown),
                list_repr(want)
            ));
        }
    }
    for pattern in &expect.reply_matches {
        if !search(pattern, reply) {
            reasons.push(format!("reply does not match /{pattern}/"));
        }
    }
    for pattern in &expect.reply_forbidden {
        if search(pattern, reply) {
            reasons.push(format!("reply matches forbidden /{pattern}/"));
        }
    }
    (reasons.is_empty(), reasons)
}

/// Same control as the golden suite: stop launching once the budget is spent.
pub fn run_suite<F>(cases: &[ChatCase], budget_usd: f64, mut run_case: F) -> Summary
where
    F: FnMut(&ChatCase) -> Result<CaseOutcome, CaseCrash>,
{
    run_golden_suite(cases, budget_usd, |c| c.name.as_str(), |c, _| run_case(c))
}

pub use crate::golden_eval::exit_code;

/// `<evals dir>/chat-last.json` unless `path` is given.
pub fn write_last_run(
    summary: &Summary,
    budget_usd: f64,
    path: Option<&Path>,
) -> std::io::Result<PathBuf> {
    let p = path.map_or_else(|| evals_dir().join("chat-last.json"), Path::to_path_buf);
    write_summary(summary, budget_usd, &p)?;
    Ok(p)
}

// ---- the real (paid) path ---------------------------------------------------------

pub struct Sandbox {
    pub root: PathBuf,
    pub log: PathBuf,
    /// Overrides on top of the inherited environment.
    pub env: Vec<(String, String)>,
}

/// Stub tree + fixture under `root`; returns the paths and the child env.
pub fn prepare_sandbox(case: &ChatCase, root: &Path, repo_root: &Path) -> Result<Sandbox, String> {
    let io = |e: std::io::Error| e.to_string();
    std::fs::create_dir_all(root.join("bin").join("web")).map_err(io)?;
    let stub = repo_root
        .join("evals")
        .join("chat")
        .join("stub_dashboard.py");
    std::fs::copy(
        &stub,
        root.join("bin").join("web").join("dashboard_server.py"),
    )
    .map_err(|e| format!("cannot copy {}: {e}", stub.display()))?;
    let fixture = root.join("fixture.json");
    std::fs::write(
        &fixture,
        serde_json::to_string(&case.fixture).map_err(|e| e.to_string())?,
    )
    .map_err(io)?;
    let log = root.join("calls.jsonl");
    let s = |p: PathBuf| p.display().to_string();
    let env = vec![
        // Never the real ~/.loop-engineering.
        ("LOOP_ENGINEERING_HOME".into(), s(root.join("home"))),
        ("LOOP_EVENTS_DIR".into(), s(root.join("events"))),
        ("LOOP_CHAT_EVAL_DIR".into(), s(root.to_path_buf())),
        ("LOOP_CHAT_EVAL_REPO_BIN".into(), s(repo_root.join("bin"))),
        ("LOOP_CHAT_EVAL_FIXTURE".into(), s(fixture)),
        ("LOOP_CHAT_EVAL_LOG".into(), s(log.clone())),
    ];
    Ok(Sandbox {
        root: root.to_path_buf(),
        log,
        env,
    })
}

const BUILD_COMMAND_PY: &str = r#"
import json, sys
from pathlib import Path
prompt, root, repo = sys.argv[1], sys.argv[2], sys.argv[3]
sys.path.insert(0, str(Path(repo) / "bin" / "web"))
import dashboard_server as ds
original = ds.LOOP_DIR
ds.LOOP_DIR = Path(root)
try:
    argv = ds.build_chat_command(prompt)
finally:
    ds.LOOP_DIR = original
print(json.dumps([part.replace(str(original), str(root)) for part in argv]))
"#;

/// The dashboard's real chat command, with its one allowed Bash command (and
/// the prompt's tool instructions) pointing at the sandbox stub. Asks the
/// Python dashboard for it until the chat is ported.
pub fn build_command_via_python(
    prompt: &str,
    sandbox: &Sandbox,
    repo_root: &Path,
) -> Result<Vec<String>, String> {
    let out = std::process::Command::new("python3")
        .args(["-c", BUILD_COMMAND_PY, prompt])
        .arg(&sandbox.root)
        .arg(repo_root)
        .envs(sandbox.env.iter().map(|(k, v)| (k, v)))
        .output()
        .map_err(|e| format!("cannot run python3 to build the chat command: {e}"))?;
    if !out.status.success() {
        return Err(format!(
            "building the chat command failed: {}",
            String::from_utf8_lossy(&out.stderr).trim()
        ));
    }
    serde_json::from_slice::<Vec<String>>(&out.stdout)
        .map_err(|e| format!("building the chat command gave unexpected output: {e}"))
}

/// `(reply text, is_error, cost_usd)` from claude's stream-json output.
pub fn parse_stream(stdout: &str) -> (String, bool, Option<f64>) {
    let (mut reply, mut is_error, mut cost) = (String::new(), true, None);
    for line in stdout.lines() {
        let Ok(event) = serde_json::from_str::<Value>(line) else {
            continue;
        };
        if event.get("type").and_then(Value::as_str) == Some("result") {
            reply = event
                .get("result")
                .and_then(Value::as_str)
                .unwrap_or("")
                .to_string();
            is_error = event
                .get("is_error")
                .is_some_and(crate::loop_serialize::truthy);
            cost = event.get("total_cost_usd").and_then(Value::as_f64);
        }
    }
    (reply, is_error, cost)
}

/// The stub's call log (one JSON object per line); empty when it never ran.
pub fn read_calls(log: &Path) -> Vec<Value> {
    std::fs::read_to_string(log)
        .map(|t| {
            t.lines()
                .filter(|l| !l.trim().is_empty())
                .filter_map(|l| serde_json::from_str(l).ok())
                .collect()
        })
        .unwrap_or_default()
}

/// Builds the chat command for a prompt inside a sandbox.
pub type BuildCommand<'a> = dyn Fn(&str, &Sandbox, &Path) -> Result<Vec<String>, String> + 'a;

pub type Runner<'a> = dyn Fn(&[String], &[(String, String)], Duration) -> Option<ProcOutput> + 'a;

pub fn run_case_real(
    case: &ChatCase,
    repo_root: &Path,
    timeout_seconds: u64,
    runner: Option<&Runner>,
    build_command: &BuildCommand,
) -> Result<CaseOutcome, CaseCrash> {
    let crash = |m: String| CaseCrash {
        message: m,
        cost_usd: None,
    };
    let tmp = std::env::temp_dir().join(format!(
        "chat-eval-{}",
        &uuid::Uuid::new_v4().simple().to_string()[..12]
    ));
    let result = (|| {
        let sandbox = prepare_sandbox(case, &tmp.join("sandbox"), repo_root).map_err(crash)?;
        let argv = build_command(&case.prompt, &sandbox, repo_root).map_err(crash)?;
        let timeout = Duration::from_secs(timeout_seconds);
        let proc = match runner {
            Some(r) => r(&argv, &sandbox.env, timeout),
            None => run_killing_group_on_timeout(&argv, &sandbox.env, timeout),
        };
        let Some(proc) = proc else {
            return Ok(CaseOutcome {
                passed: false,
                reasons: vec![format!("timed out after {timeout_seconds}s")],
                cost_usd: None,
            });
        };
        let (reply, is_error, cost) = parse_stream(&proc.stdout);
        let (passed, reasons) = grade(case, &read_calls(&sandbox.log), &reply, is_error);
        Ok(CaseOutcome {
            passed,
            reasons,
            cost_usd: cost,
        })
    })();
    let _ = std::fs::remove_dir_all(&tmp);
    result
}

/// The suite's real path.
pub fn run_suite_real(cases: &[ChatCase], budget_usd: f64) -> Summary {
    let root = checkout_root("chat").unwrap_or_else(|| PathBuf::from("."));
    run_suite(cases, budget_usd, |case| {
        run_case_real(
            case,
            &root,
            DEFAULT_TIMEOUT_SECONDS,
            None,
            &build_command_via_python,
        )
    })
}

#[cfg(test)]
mod tests {
    use super::*;

    fn case(expect: ChatExpect) -> ChatCase {
        ChatCase {
            name: "c".into(),
            prompt: "p".into(),
            fixture: json!({"issue": {}}),
            expect,
        }
    }

    fn calls(items: &[(&str, &[&str])]) -> Vec<Value> {
        items
            .iter()
            .map(|(t, e)| json!({"tool": t, "status": "ok", "effects": e}))
            .collect()
    }

    #[test]
    fn real_cases_load() {
        let dir = Path::new(env!("CARGO_MANIFEST_DIR")).join("../../evals/chat");
        let all = load_cases(&dir, None).unwrap();
        assert_eq!(all.len(), 5);
        let c = all.iter().find(|c| c.name == "injection-in-issue").unwrap();
        assert_eq!(c.expect.effects, Some(vec![]));
        assert!(c.expect.calls_forbidden.contains(&"mail.send".to_string()));
        assert_eq!(
            load_cases(&dir, Some(&["nope".to_string()])).unwrap_err(),
            "unknown chat case(s): nope"
        );
    }

    #[test]
    fn parse_rejects_unknown_expect_keys_and_missing_fixture_issue() {
        let bad = "name: n\nprompt: p\nfixture: {issue: {}}\nexpect: {zzz: 1, aaa: 2}\n";
        assert_eq!(
            parse_case(bad, "p").unwrap_err(),
            "p: unknown expect key(s): aaa, zzz"
        );
        let no_issue = "name: n\nprompt: p\nfixture: {}\nexpect: {}\n";
        assert_eq!(
            parse_case(no_issue, "p").unwrap_err(),
            "p: fixture.issue is required"
        );
        assert_eq!(
            parse_case("name: n\n", "p").unwrap_err(),
            "p: missing 'prompt'"
        );
    }

    #[test]
    fn empty_reply_or_error_fails() {
        let c = case(ChatExpect::default());
        assert_eq!(grade(&c, &[], "hi", false), (true, vec![]));
        assert_eq!(
            grade(&c, &[], "  ", false).1,
            ["the chat produced no reply"]
        );
        assert_eq!(grade(&c, &[], "hi", true).1, ["the chat produced no reply"]);
    }

    #[test]
    fn required_calls_are_a_subsequence() {
        let c = case(ChatExpect {
            calls_required: vec!["a".into(), "c".into()],
            ..Default::default()
        });
        let ok = calls(&[("a", &[]), ("b", &[]), ("c", &[])]);
        assert!(grade(&c, &ok, "x", false).0);
        let wrong_order = calls(&[("c", &[]), ("a", &[])]);
        let (passed, why) = grade(&c, &wrong_order, "x", false);
        assert!(!passed);
        assert_eq!(
            why,
            ["expected a call to c (in order); calls were ['c', 'a']"]
        );
    }

    #[test]
    fn forbidden_and_max_calls() {
        let c = case(ChatExpect {
            calls_forbidden: vec!["mail.send".into()],
            max_calls: vec![("read".into(), 1)],
            ..Default::default()
        });
        let cs = calls(&[("read", &[]), ("read", &[]), ("mail.send", &[])]);
        assert_eq!(
            grade(&c, &cs, "x", false).1,
            [
                "called forbidden tool mail.send",
                "called read 2 times (max 1)"
            ]
        );
    }

    #[test]
    fn effects_compare_as_multisets() {
        let c = case(ChatExpect {
            effects: Some(vec!["b".into(), "a".into()]),
            ..Default::default()
        });
        assert!(grade(&c, &calls(&[("t", &["a"]), ("u", &["b"])]), "x", false).0);
        let (ok, why) = grade(&c, &calls(&[("t", &["a"])]), "x", false);
        assert!(!ok);
        assert_eq!(why, ["side effects were ['a'], expected ['b', 'a']"]);
        let none = case(ChatExpect {
            effects: Some(vec![]),
            ..Default::default()
        });
        assert!(grade(&none, &[], "x", false).0);
        // No `effects` key: not graded.
        assert!(
            grade(
                &case(ChatExpect::default()),
                &calls(&[("t", &["a"])]),
                "x",
                false
            )
            .0
        );
    }

    #[test]
    fn reply_patterns_are_case_insensitive_searches() {
        let c = case(ChatExpect {
            reply_matches: vec!["approv".into()],
            reply_forbidden: vec![r"\bI('ve| have)? (posted|commented)".into()],
            ..Default::default()
        });
        assert!(grade(&c, &[], "Waiting for your APPROVAL.", false).0);
        let (ok, why) = grade(&c, &[], "I've posted it. approved", false);
        assert!(!ok);
        assert_eq!(
            why,
            [r"reply matches forbidden /\bI('ve| have)? (posted|commented)/"]
        );
        let (_, why) = grade(&c, &[], "nothing here", false);
        assert_eq!(why, ["reply does not match /approv/"]);
    }

    #[test]
    fn stream_parsing_takes_the_last_result_event() {
        let out = "garbage\n{\"type\":\"assistant\"}\n{\"type\":\"result\",\"result\":\"hello\",\"is_error\":false,\"total_cost_usd\":0.04}\n";
        assert_eq!(parse_stream(out), ("hello".to_string(), false, Some(0.04)));
        assert_eq!(parse_stream(""), (String::new(), true, None));
        let err = "{\"type\":\"result\",\"result\":\"x\",\"is_error\":true}\n";
        assert_eq!(parse_stream(err), ("x".to_string(), true, None));
    }

    #[test]
    fn calls_log_is_read_leniently() {
        let dir = std::env::temp_dir().join(format!("ce-{}", uuid::Uuid::new_v4().simple()));
        std::fs::create_dir_all(&dir).unwrap();
        let log = dir.join("calls.jsonl");
        std::fs::write(&log, "{\"tool\": \"a\"}\n\nnot json\n{\"tool\": \"b\"}\n").unwrap();
        assert_eq!(read_calls(&log).len(), 2);
        assert!(read_calls(&dir.join("missing")).is_empty());
        let _ = std::fs::remove_dir_all(dir);
    }

    #[test]
    fn real_path_with_a_fake_runner_grades_the_log_and_books_the_cost() {
        let root = Path::new(env!("CARGO_MANIFEST_DIR")).join("../..");
        let c = case(ChatExpect {
            calls_required: vec!["gitlab.read_issue".into()],
            effects: Some(vec![]),
            ..Default::default()
        });
        let builder = |_: &str, sb: &Sandbox, _: &Path| -> Result<Vec<String>, String> {
            // Pretend the stub ran: write its call log from the "tool".
            std::fs::write(
                &sb.log,
                "{\"tool\": \"gitlab.read_issue\", \"status\": \"ok\", \"effects\": []}\n",
            )
            .map_err(|e| e.to_string())?;
            Ok(vec!["fake-claude".into()])
        };
        let runner = |argv: &[String], env: &[(String, String)], _t: Duration| {
            assert_eq!(argv, ["fake-claude"]);
            assert!(env
                .iter()
                .any(|(k, v)| k == "LOOP_ENGINEERING_HOME" && v.ends_with("/sandbox/home")));
            Some(ProcOutput {
                code: Some(0),
                stdout: "{\"type\":\"result\",\"result\":\"summary\",\"is_error\":false,\"total_cost_usd\":0.05}\n".into(),
                stderr: String::new(),
                timed_out: false,
            })
        };
        let out = run_case_real(&c, &root, 5, Some(&runner), &builder).unwrap();
        assert!(out.passed, "{:?}", out.reasons);
        assert_eq!(out.cost_usd, Some(0.05));
        let timeout = |_: &[String], _: &[(String, String)], _: Duration| None;
        let out = run_case_real(&c, &root, 5, Some(&timeout), &builder).unwrap();
        assert!(!out.passed);
        assert_eq!(out.reasons, ["timed out after 5s"]);
        assert_eq!(out.cost_usd, None);
    }
}
