//! Behavior test for `cardinal tool cardinal-report` on fixture TSV files: the groups of revisions, the tables per axis, the
//! confounders next to the numbers, the refusal of what it cannot read.

use std::collections::HashMap;
use std::path::{Path, PathBuf};

const SESSIONS: &str = "session\tproject\tissues\trevision\tmodels\tversions\tstart\tduration_s\tturns\ttool_calls\tinput_tokens\toutput_tokens\tthinking_tokens\tcache_read_tokens\tcache_creation_tokens\tmain_context_peak\tadvisor_models\tadvisor_calls\tadvisor_input_tokens\tadvisor_output_tokens\thook_refusals\tskills\tvalidations\tother_messages\tunreadable_lines\tunknown_lines\tmissing_fields";
const BREACHES: &str = "rule\trevision\tapplied\tbreached\tbreaches\tblocked";
const QUALITY: &str = "revision\tissues\tdeliverables\tcommits\tfixes_in_issue\tfixes_after\treverts_after\treviews\treview_findings\ttraced\ttraced_without_red\tspec_lines\tdoc_lines\tsessions\tfailed_checks\tvalidations\tother_messages\tinput_tokens\tcache_read_tokens\toutput_tokens";
const CONTEXT: &str =
    "project\trevision\tcommit\tclaude_md_bytes\tagents_md_bytes\tskill_description_bytes\tskills";
const CHANGES: &str = "change\tmetric\tdirection\trevisions";
const SELF: &str = "self:1111111111111111111111111111111111111111";

/// A session row: the columns that vary, the others fixed (output 10); `input` holds the uncached input, cache read and
/// cache creation tokens; the main context peak is 100 per turn unless `peak` is `None` (an archived row written before
/// the column); with an `advisor` set, `calls` calls of 1,000 input and 10 output tokens each, else empty advisor cells.
#[derive(Clone)]
struct S<'a> {
    project: &'a str,
    issues: &'a str,
    revision: &'a str,
    models: &'a str,
    day: u32,
    turns: u64,
    input: [u64; 3],
    peak: Option<u64>,
    advisor: &'a str,
    calls: u64,
    others: u64,
    hooks: &'a str,
    skills: &'a str,
}

impl S<'_> {
    fn row(&self, id: usize) -> String {
        let start = format!("2026-01-{:02}T00:00:{:02}.000Z", self.day, id % 60);
        let advised = |n: u64| {
            if self.advisor.is_empty() {
                String::new()
            } else {
                n.to_string()
            }
        };
        let cells = [
            format!("s{id}"),
            self.project.into(),
            self.issues.into(),
            self.revision.into(),
            self.models.into(),
            "v1".into(),
            start,
            "60".into(),
            self.turns.to_string(),
            "2".into(),
            self.input[0].to_string(),
            "10".into(),
            "0".into(),
            self.input[1].to_string(),
            self.input[2].to_string(),
            self.peak.map(|p| p.to_string()).unwrap_or_default(),
            self.advisor.into(),
            advised(self.calls),
            advised(self.calls * 1000),
            advised(self.calls * 10),
            self.hooks.into(),
            self.skills.into(),
            "1".into(),
            self.others.to_string(),
            "0".into(),
            "0".into(),
            "0".into(),
        ];
        cells.join("\t")
    }
}

fn base<'a>(project: &'a str, revision: &'a str, day: u32, turns: u64) -> S<'a> {
    S {
        project,
        issues: "",
        revision,
        models: "m1",
        day,
        turns,
        input: [1, 2, 3],
        peak: Some(turns * 100),
        advisor: "",
        calls: 0,
        others: 0,
        hooks: "",
        skills: "",
    }
}

/// The sessions: `SELF` 6 (p1, issue i1, turns 1 to 6), `r-b` 5 (3 of p2 on i1 with two models, 2 of p1; turns 7 to
/// 11, the 2 of p1 with no peak, none with input; the 4 first of `SELF` with an advisor called 0, 1, 3 and 6 times), `r-c` 4
/// (turns 1 to 4, other messages 0, 0, 1, 1, no peak, input sums 0, 10, 100 and 100 whose cache reads are 0, 9, 10
/// and 50), and one with no revision, the earliest, left out. `r-c` is written first: the order is the order of use.
/// The other sessions read 2 of their 6 input tokens from the cache.
fn sessions() -> Vec<S<'static>> {
    let inputs = [[0, 0, 0], [1, 9, 0], [90, 10, 0], [40, 50, 10]];
    let mut list: Vec<S> = (1..=4)
        .zip(inputs)
        .map(|(t, input)| S {
            others: u64::from(t > 2),
            input,
            peak: None,
            ..base("p1", "r-c", 20, t)
        })
        .collect();
    list.push(base("p0", "", 1, 99));
    list.extend((1..=6).map(|t| S {
        issues: "i1",
        skills: "code-review=2",
        hooks: if t == 1 { "require_code_review=1" } else { "" },
        calls: match t {
            2 => 1,
            3 => 3,
            4 => 6,
            _ => 0,
        },
        advisor: if t <= 4 { "claude-opus-5-5" } else { "" },
        ..base("p1", SELF, 2, t)
    }));
    list.extend((7..=9).map(|t| S {
        issues: "i1",
        models: "m1,m2",
        skills: "files:commit-message=1",
        input: [0, 0, 0],
        ..base("p2", "r-b", 10, t)
    }));
    list.extend((10..=11).map(|t| S {
        peak: None,
        input: [0, 0, 0],
        ..base("p1", "r-b", 11, t)
    }));
    list
}

fn write(path: &Path, header: &str, rows: &[String]) -> PathBuf {
    std::fs::write(
        path,
        std::iter::once(header.to_string())
            .chain(rows.iter().cloned())
            .map(|l| l + "\n")
            .collect::<String>(),
    )
    .unwrap();
    path.to_path_buf()
}

fn run(dir: &Path, args: &[&std::ffi::OsStr]) -> (bool, String, String) {
    let out = tool_command(dir.join("cardinal_report.rs"))
        .args(args)
        .output()
        .unwrap();
    (
        out.status.success(),
        String::from_utf8_lossy(&out.stdout).into_owned(),
        String::from_utf8_lossy(&out.stderr).into_owned(),
    )
}

/// The tables of a markdown report by heading: each a list of rows of trimmed cells, the header row first.
fn tables(out: &str) -> HashMap<String, Vec<Vec<String>>> {
    let mut tables: HashMap<String, Vec<Vec<String>>> = HashMap::new();
    let mut heading = String::new();
    for line in out.lines() {
        if let Some(h) = line.strip_prefix("## ") {
            heading = h.trim().to_string();
        } else if line.starts_with('|') && !line.starts_with("|-") && !line.starts_with("| -") {
            let cells = line
                .trim()
                .trim_matches('|')
                .split('|')
                .map(|c| c.trim().to_string())
                .collect();
            tables.entry(heading.clone()).or_default().push(cells);
        }
    }
    tables
}

/// The cell of `column` in the row of `group` of a table, empty when absent.
fn cell(table: Option<&Vec<Vec<String>>>, group: &str, column: &str) -> String {
    let Some(rows) = table else {
        return String::new();
    };
    let Some(index) = rows
        .first()
        .and_then(|h| h.iter().position(|c| c == column))
    else {
        return String::new();
    };
    rows.iter()
        .skip(1)
        .find(|r| r.first().is_some_and(|g| g == group))
        .and_then(|r| r.get(index))
        .cloned()
        .unwrap_or_default()
}

// spec: REP-3, REP-4, REP-5, REP-8, REP-9, REP-10, REP-11, REP-12
fn efficiency_checks(dir: &Path, tmp: &Path) -> Vec<(&'static str, bool)> {
    let rows: Vec<String> = sessions()
        .iter()
        .enumerate()
        .map(|(i, s)| s.row(i))
        .collect();
    let file = write(&tmp.join("sessions.tsv"), SESSIONS, &rows);
    let (ok, out, err) = run(dir, &["--sessions".as_ref(), file.as_os_str()]);
    if !ok {
        println!("{err}");
    }
    let t = tables(&out);
    let eff = t.get("Efficiency");
    let first = "self:1111111..r-b";
    let header: Vec<&str> = [
        "group",
        "sessions",
        "issues",
        "projects",
        "models",
        "versions",
        "turns",
        "tool_calls",
        "output_tokens",
        "input_tokens",
        "cache_read_share",
        "main_context_peak",
        "peak_sessions",
        "advisor_models",
        "advisor_sessions",
        "advisor_calls",
        "advisor_input_tokens",
        "advisor_output_tokens",
        "validations",
        "other_messages",
    ]
    .to_vec();
    let groups: Vec<String> = eff
        .map(|r| r.iter().skip(1).map(|c| c[0].clone()).collect())
        .unwrap_or_default();
    let too_few = eff
        .and_then(|r| r.iter().find(|c| c[0] == "r-c"))
        .is_some_and(|c| c[1] == "4" && c[2..].iter().all(|v| v == "too few"));
    vec![
        (
            "the report prints an efficiency table with its columns",
            ok && eff.and_then(|r| r.first()).is_some_and(|h| *h == header),
        ),
        (
            "revisions in the order of use, grouped up to the threshold, the empty one left out",
            groups == [first, "r-c"],
        ),
        (
            "a 40-digit revision is abbreviated to 7",
            out.contains("self:1111111") && !out.contains("self:11111111"),
        ),
        (
            "the last group under the threshold shows its size and `too few`",
            too_few,
        ),
        (
            "sessions, issues as project and issue pairs",
            cell(eff, first, "sessions") == "11" && cell(eff, first, "issues") == "2",
        ),
        (
            "projects, models and versions by sessions, most frequent first",
            cell(eff, first, "projects") == "p1=8, p2=3"
                && cell(eff, first, "models") == "m1=11, m2=3"
                && cell(eff, first, "versions") == "v1=11",
        ),
        (
            "medians per session of turns, tool calls and tokens",
            cell(eff, first, "turns") == "6"
                && cell(eff, first, "tool_calls") == "2"
                && cell(eff, first, "output_tokens") == "10"
                && cell(eff, first, "input_tokens") == "6",
        ),
        (
            "the median share of the input read from the cache",
            cell(eff, first, "cache_read_share") == "33%",
        ),
        (
            "the median main context peak leaves out the sessions with no peak",
            cell(eff, first, "main_context_peak") == "500",
        ),
        (
            "the sessions with a peak are counted next to its median",
            cell(eff, first, "peak_sessions") == "9",
        ),
        (
            "the advisors set by sessions, and the sessions that set one",
            cell(eff, first, "advisor_models") == "claude-opus-5-5=4"
                && cell(eff, first, "advisor_sessions") == "4",
        ),
        (
            "the medians of the advisor calls and tokens over the sessions that set one",
            cell(eff, first, "advisor_calls") == "2"
                && cell(eff, first, "advisor_input_tokens") == "2000"
                && cell(eff, first, "advisor_output_tokens") == "20",
        ),
    ]
}

// spec: REP-3, REP-4, REP-5, REP-8, REP-9, REP-10, REP-11, REP-12
fn option_checks(dir: &Path, tmp: &Path) -> Vec<(&'static str, bool)> {
    let rows: Vec<String> = sessions()
        .iter()
        .enumerate()
        .map(|(i, s)| s.row(i))
        .collect();
    let file = write(&tmp.join("options-sessions.tsv"), SESSIONS, &rows);
    let first = "self:1111111..r-b";
    let (_, small, _) = run(
        dir,
        &[
            "--sessions".as_ref(),
            file.as_os_str(),
            "--min-sessions".as_ref(),
            "2".as_ref(),
        ],
    );
    let small = tables(&small);
    let (_, anonymous, _) = run(
        dir,
        &[
            "--sessions".as_ref(),
            file.as_os_str(),
            "--anonymous".as_ref(),
        ],
    );
    let anon = tables(&anonymous);
    vec![
        (
            "a group with no peak has an empty main context peak and 0 peak sessions",
            cell(small.get("Efficiency"), "r-c", "main_context_peak").is_empty()
                && cell(small.get("Efficiency"), "r-c", "peak_sessions") == "0"
                && cell(small.get("Efficiency"), "r-c", "turns") == "3",
        ),
        (
            "a group with no advisor set has empty advisor cells and 0 advisor sessions",
            cell(small.get("Efficiency"), "r-c", "advisor_models").is_empty()
                && cell(small.get("Efficiency"), "r-c", "advisor_sessions") == "0"
                && cell(small.get("Efficiency"), "r-c", "advisor_calls").is_empty()
                && cell(small.get("Efficiency"), "r-c", "advisor_output_tokens").is_empty(),
        ),
        (
            "the cache read share is the median of the shares of the sessions, empty with no input",
            cell(small.get("Efficiency"), "r-c", "cache_read_share") == "50%"
                && cell(small.get("Efficiency"), "r-b", "cache_read_share").is_empty(),
        ),
        (
            "an even count takes the mean of the middle values, rounded half up",
            cell(small.get("Efficiency"), "r-c", "turns") == "3"
                && cell(small.get("Efficiency"), "r-c", "other_messages") == "1",
        ),
        (
            "--min-sessions sets the threshold",
            cell(small.get("Efficiency"), "self:1111111", "sessions") == "6"
                && cell(small.get("Efficiency"), "r-b", "sessions") == "5",
        ),
        (
            "--anonymous gives the count of projects and no project name",
            cell(anon.get("Efficiency"), first, "projects") == "2"
                && !anonymous.contains("p1")
                && !anonymous.contains("p2"),
        ),
    ]
}

/// The sessions, breaches, two quality and context files of the axes checks.
fn axes_inputs(tmp: &Path) -> (PathBuf, PathBuf, PathBuf, PathBuf, PathBuf) {
    let rows: Vec<String> = sessions()
        .iter()
        .enumerate()
        .map(|(i, s)| s.row(i))
        .collect();
    let sessions = write(&tmp.join("axes-sessions.tsv"), SESSIONS, &rows);
    let breaches = write(
        &tmp.join("breaches.tsv"),
        BREACHES,
        &[
            format!("x-rule\t{SELF}\t8\t1\t3\t0"),
            "x-rule\tr-b\t4\t1\t1\t2".into(),
            "a-rule\tr-b\t2\t0\t0\t0".into(),
            "x-rule\tr-c\t1\t1\t1\t0".into(),
        ],
    );
    let quality_a = write(
        &tmp.join("quality-a.tsv"),
        QUALITY,
        &[
            format!("{SELF}\t2\t4\t6\t1\t1\t0\t2\t3\t5\t2\t150\t30\t2\t1\t3\t4\t3000000\t2000000\t10000"),
            "zzz\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9\t9".into(),
        ],
    );
    let quality_b = write(
        &tmp.join("quality-b.tsv"),
        QUALITY,
        &["r-b\t1\t1\t2\t0\t0\t0\t1\t\t1\t1\t50\t20\t1\t0\t1\t0\t1\t0\t2".into()],
    );
    let context = write(
        &tmp.join("context.tsv"),
        CONTEXT,
        &[
            format!("p1\t{SELF}\tc1\t100\t200\t300\tcode-review,commit-message,write-spec"),
            "p1\tr-b\tc2\t201\t400\t500\taudit,code-review,commit-message".into(),
            "p2\tr-b\t\t\t\t\t".into(),
        ],
    );
    (sessions, breaches, quality_a, quality_b, context)
}

// spec: REP-6, REP-7
fn axes_checks(dir: &Path, tmp: &Path) -> Vec<(&'static str, bool)> {
    let (sessions, breaches, quality_a, quality_b, context) = axes_inputs(tmp);
    let arg = |s: &'static str| std::ffi::OsStr::new(s);
    let (ok, out, err) = run(
        dir,
        &[
            arg("--sessions"),
            sessions.as_os_str(),
            arg("--breaches"),
            breaches.as_os_str(),
            arg("--quality"),
            quality_a.as_os_str(),
            arg("--quality"),
            quality_b.as_os_str(),
            arg("--context"),
            context.as_os_str(),
        ],
    );
    if !ok {
        println!("{err}");
    }
    let t = tables(&out);
    let first = "self:1111111..r-b";
    let (quality, rules, skills, fixed) = (
        t.get("Quality"),
        t.get("Rules"),
        t.get("Skills"),
        t.get("Fixed context"),
    );
    let rule_rows: Vec<String> = rules
        .map(|r| {
            r.iter()
                .skip(1)
                .filter(|c| c[0] == first)
                .map(|c| c[2..].join(" "))
                .collect()
        })
        .unwrap_or_default();
    let few = |table: Option<&Vec<Vec<String>>>| {
        table.is_some_and(|r| {
            r.iter().filter(|c| c[0] == "r-c").count() == 1
                && r.iter()
                    .any(|c| c[0] == "r-c" && c[1] == "4" && c[2..].iter().all(|v| v == "too few"))
        })
    };
    let too_few = [quality, rules, skills, fixed].into_iter().all(few);
    vec![
        (
            "quality sums over the revisions and files of a group, other revisions left out",
            ok && cell(quality, first, "issues") == "3"
                && cell(quality, first, "commits") == "8"
                && cell(quality, first, "issue_sessions") == "3"
                && cell(quality, first, "other_messages") == "4"
                && cell(quality, first, "traced") == "6"
                && cell(quality, first, "traced_without_red") == "3",
        ),
        (
            "an empty value empties its sum and its ratio",
            cell(quality, first, "review_findings").is_empty()
                && cell(quality, first, "findings_per_review").is_empty(),
        ),
        (
            "fixes after per issue with two decimals",
            cell(quality, first, "fixes_after_per_issue") == "0.33",
        ),
        (
            "doc lines per spec line with two decimals",
            cell(quality, first, "doc_lines") == "50"
                && cell(quality, first, "doc_lines_per_spec_line") == "0.25",
        ),
        (
            "one rules row per rule of the group, sorted, sums and share",
            rule_rows == ["a-rule 2 0 0 0 0%", "x-rule 12 2 4 2 17%"],
        ),
        (
            "skill calls and hook refusals summed, most frequent first",
            cell(skills, first, "calls") == "code-review=12, files:commit-message=3"
                && cell(skills, first, "hook_refusals") == "require_code_review=1",
        ),
        (
            "unused skills of the revisions, a prefixed call counting",
            cell(skills, first, "unused") == "audit, write-spec",
        ),
        (
            "fixed context means over the rows with bytes, rounded half up",
            cell(fixed, first, "claude_md_bytes") == "151"
                && cell(fixed, first, "agents_md_bytes") == "300"
                && cell(fixed, first, "skill_description_bytes") == "400"
                && cell(fixed, first, "total_bytes") == "851",
        ),
        (
            "a group with too few sessions is one row of `too few` in every table",
            too_few,
        ),
    ]
}

// spec: REP-6, REP-7
fn axes_threshold_checks(dir: &Path, tmp: &Path) -> Vec<(&'static str, bool)> {
    let (sessions, _, quality_a, _, _) = axes_inputs(tmp);
    let arg = |s: &'static str| std::ffi::OsStr::new(s);
    let only_b = write(
        &tmp.join("breaches-b.tsv"),
        BREACHES,
        &["x-rule\tr-b\t4\t1\t1\t2".into()],
    );
    let (_, small, _) = run(
        dir,
        &[
            arg("--sessions"),
            sessions.as_os_str(),
            arg("--min-sessions"),
            arg("2"),
            arg("--breaches"),
            only_b.as_os_str(),
            arg("--quality"),
            quality_a.as_os_str(),
        ],
    );
    let small = tables(&small);
    let no_rule = small
        .get("Rules")
        .and_then(|r| r.iter().find(|c| c[0] == "self:1111111"))
        .is_some_and(|c| c.len() == 8 && c[2..].iter().all(String::is_empty));
    let no_spec = write(
        &tmp.join("quality-no-spec.tsv"),
        QUALITY,
        &[format!(
            "{SELF}\t1\t1\t1\t0\t0\t0\t1\t0\t0\t0\t0\t9\t1\t0\t0\t0\t\t\t"
        )],
    );
    let (_, docs_only, _) = run(
        dir,
        &[
            arg("--sessions"),
            sessions.as_os_str(),
            arg("--min-sessions"),
            arg("2"),
            arg("--quality"),
            no_spec.as_os_str(),
        ],
    );
    let docs_only = tables(&docs_only);
    let (_, bare, _) = run(dir, &[arg("--sessions"), sessions.as_os_str()]);
    let bare = tables(&bare);
    vec![
        (
            "a group with no quality row has empty sums, not zeros",
            cell(small.get("Quality"), "r-c", "issues").is_empty()
                && cell(small.get("Quality"), "self:1111111", "issues") == "2",
        ),
        (
            "no doc lines per spec line when the group changed no spec line",
            cell(docs_only.get("Quality"), "self:1111111", "doc_lines") == "9"
                && cell(
                    docs_only.get("Quality"),
                    "self:1111111",
                    "doc_lines_per_spec_line",
                )
                .is_empty(),
        ),
        (
            "a group with no rule row keeps one row of empty cells",
            no_rule,
        ),
        (
            "a table whose input is not given is not printed",
            bare.contains_key("Skills")
                && !bare.contains_key("Quality")
                && !bare.contains_key("Rules")
                && !bare.contains_key("Fixed context"),
        ),
    ]
}

// spec: REP-3
fn refusal_checks(dir: &Path, tmp: &Path) -> Vec<(&'static str, bool)> {
    let good = write(
        &tmp.join("good.tsv"),
        SESSIONS,
        &[base("p1", "r", 1, 1).row(0)],
    );
    let bad = write(&tmp.join("bad.tsv"), "session\tsomething_else", &[]);
    let refused = |args: &[&std::ffi::OsStr]| !run(dir, args).0;
    vec![
        ("a missing --sessions is refused", refused(&[])),
        (
            "a sessions file with another header is refused",
            refused(&["--sessions".as_ref(), bad.as_os_str()]),
        ),
        (
            "a quality file with another header is refused",
            refused(&[
                "--sessions".as_ref(),
                good.as_os_str(),
                "--quality".as_ref(),
                bad.as_os_str(),
            ]),
        ),
        (
            "a --min-sessions out of range is refused",
            refused(&[
                "--sessions".as_ref(),
                good.as_os_str(),
                "--min-sessions".as_ref(),
                "0".as_ref(),
            ]),
        ),
        (
            "an unknown option is refused",
            refused(&["--sessions".as_ref(), good.as_os_str(), "--bogus".as_ref()]),
        ),
        (
            "a changes file with another header is refused",
            refused(&[
                "--sessions".as_ref(),
                good.as_os_str(),
                "--changes".as_ref(),
                bad.as_os_str(),
            ]),
        ),
        (
            "a readable input is accepted",
            run(dir, &["--sessions".as_ref(), good.as_os_str()]).0,
        ),
    ]
}

/// A 40-digit commit hash made of `c`.
fn hash(c: char) -> String {
    c.to_string().repeat(40)
}

/// The rows of the `Verdicts` table, header apart, for these sessions and changes (and the extra arguments).
fn verdicts(
    dir: &Path,
    tmp: &Path,
    sessions: &[S],
    changes: &[String],
    extra: &[&str],
) -> Vec<Vec<String>> {
    static RUNS: std::sync::atomic::AtomicUsize = std::sync::atomic::AtomicUsize::new(0);
    let n = RUNS.fetch_add(1, std::sync::atomic::Ordering::Relaxed) + 1;
    let rows: Vec<String> = sessions.iter().enumerate().map(|(i, s)| s.row(i)).collect();
    let sessions = write(&tmp.join(format!("v-sessions-{n}.tsv")), SESSIONS, &rows);
    let changes = write(&tmp.join(format!("v-changes-{n}.tsv")), CHANGES, changes);
    let breaches = write(
        &tmp.join(format!("v-breaches-{n}.tsv")),
        BREACHES,
        &[
            "x-rule\tra\t4\t2\t2\t0".into(),
            "x-rule\trb\t4\t1\t1\t0".into(),
        ],
    );
    let mut args: Vec<&std::ffi::OsStr> = vec![
        "--sessions".as_ref(),
        sessions.as_os_str(),
        "--changes".as_ref(),
        changes.as_os_str(),
        "--breaches".as_ref(),
        breaches.as_os_str(),
        "--min-sessions".as_ref(),
        "2".as_ref(),
    ];
    args.extend(extra.iter().map(std::ffi::OsStr::new));
    let (ok, out, err) = run(dir, &args);
    if !ok {
        println!("{err}");
    }
    let last = out.rfind("## ").map_or("", |i| &out[i..]);
    tables(&out)
        .remove("Verdicts")
        .filter(|_| last.starts_with("## Verdicts"))
        .unwrap_or_default()
        .into_iter()
        .skip(1)
        .collect()
}

/// Two identical sessions.
fn two(project: &'static str, revision: &'static str, day: u32, turns: u64) -> Vec<S<'static>> {
    vec![
        base(project, revision, day, turns),
        base(project, revision, day, turns),
    ]
}

fn pair(a: Vec<S<'static>>, b: Vec<S<'static>>) -> Vec<S<'static>> {
    a.into_iter().chain(b).collect()
}

/// A change `c` of `metric` expected down, held by `revisions`.
fn change(c: char, metric: &str, revisions: &str) -> String {
    format!("{}\t{metric}\tdown\t{revisions}", hash(c))
}

/// The verdict column of verdict rows.
fn verdict(rows: &[Vec<String>]) -> Vec<String> {
    rows.iter().map(|r| r[7].clone()).collect()
}

// spec: VRD-5, VRD-6, VRD-7, VRD-9
fn verdict_checks(dir: &Path, tmp: &Path) -> Vec<(&'static str, bool)> {
    // Groups `ra` (turns 10), `rb` (5), `rc` (8), `rd` (one session: too few).
    let plain: Vec<S> = [
        two("p1", "ra", 1, 10),
        two("p1", "rb", 2, 5),
        two("p1", "rc", 3, 8),
        vec![base("p1", "rd", 4, 3)],
    ]
    .into_iter()
    .flatten()
    .collect();
    let main = verdicts(
        dir,
        tmp,
        &plain,
        &[
            format!("{}\tturns\tdown\trb,rc,rd", hash('a')),
            format!("{}\tbreached_share:x-rule\tdown\trb,rc,rd", hash('a')),
            format!("{}\tturns\tdown\trc,rd", hash('b')),
            format!("{}\tturns\tdown\trd", hash('c')),
            format!("{}\tturns\tdown\t", hash('d')),
            format!("{}\tturns\tup\tra,rb,rc,rd", hash('e')),
        ],
        &[],
    );
    let row = |change: char, metric: &str, rest: &[&str]| -> Vec<String> {
        [&hash(change)[..7], metric]
            .iter()
            .copied()
            .chain(rest.iter().copied())
            .map(str::to_string)
            .collect()
    };
    let expected = vec![
        row('a', "turns", &["down", "ra", "rb", "10", "5", "helped"]),
        row(
            'a',
            "breached_share:x-rule",
            &["down", "ra", "rb", "50", "25", "helped"],
        ),
        row('b', "turns", &["down", "rb", "rc", "5", "8", "hurt"]),
        row('c', "turns", &["down", "rc", "rd", "8", "3", "confounded"]),
        row('d', "turns", &["down", "", "", "", "", "no data"]),
        row('e', "turns", &["up", "", "ra", "", "10", "no data"]),
    ];
    let one = |extra: &[&str], sessions: Vec<S<'static>>, changes: &[String]| {
        verdict(&verdicts(dir, tmp, &sessions, changes, extra))
    };
    let models: Vec<S> = pair(
        two("p1", "ra", 1, 10),
        vec![
            S {
                models: "m2",
                ..base("p1", "rb", 2, 5)
            },
            S {
                models: "m2",
                ..base("p1", "rb", 2, 5)
            },
        ],
    );
    let anonymous = verdicts(
        dir,
        tmp,
        &pair(two("p1", "ra", 1, 10), two("secret-project", "rb", 2, 5)),
        &[change('a', "turns", "rb")],
        &["--anonymous"],
    );
    let mut mixed = two("p1", "ra", 1, 10);
    mixed.extend(two("p1", "ra", 1, 10));
    mixed.extend(two("p1", "rb", 2, 5));
    mixed.extend(two("p1", "rc", 3, 5));
    vec![
        (
            "the verdicts table comes last with a row per change and metric",
            main == expected,
        ),
        (
            "a change of the most frequent model confounds",
            one(&[], models, &[change('a', "turns", "rb")]) == ["confounded"],
        ),
        (
            "a change of the most frequent project confounds, and --anonymous names none",
            verdict(&anonymous) == ["confounded"]
                && !anonymous.concat().iter().any(|c| c.contains("secret")),
        ),
        (
            "an after group holding a revision without the change confounds",
            one(
                &["--min-sessions", "4"],
                mixed,
                &[change('a', "turns", "rc")],
            ) == ["confounded"],
        ),
    ]
}

// spec: VRD-5, VRD-6, VRD-7, VRD-9
fn verdict_edge_checks(dir: &Path, tmp: &Path) -> Vec<(&'static str, bool)> {
    let one = |sessions: Vec<S<'static>>, changes: &[String]| {
        verdict(&verdicts(dir, tmp, &sessions, changes, &[]))
    };
    let unpeaked = |s: S<'static>| S { peak: None, ..s };
    let peak_after: Vec<S> = pair(
        two("p1", "ra", 1, 10),
        vec![base("p1", "rb", 2, 5), unpeaked(base("p1", "rb", 2, 5))],
    );
    let peak_before: Vec<S> = pair(
        vec![unpeaked(base("p1", "ra", 1, 10)), base("p1", "ra", 1, 10)],
        two("p1", "rb", 2, 5),
    );
    let no_peak_before: Vec<S> = pair(
        vec![
            unpeaked(base("p1", "ra", 1, 10)),
            unpeaked(base("p1", "ra", 1, 10)),
        ],
        two("p1", "rb", 2, 5),
    );
    vec![
        (
            "two changes with the same after group confound each other",
            one(
                pair(two("p1", "ra", 1, 10), two("p1", "rb", 2, 5)),
                &[change('a', "turns", "rb"), change('b', "validations", "rb")],
            ) == ["confounded", "confounded"],
        ),
        (
            "a main context peak held by fewer sessions than the threshold confounds, before or after",
            one(peak_after, &[change('a', "main_context_peak", "rb")]) == ["confounded"]
                && one(peak_before, &[change('a', "main_context_peak", "rb")]) == ["confounded"],
        ),
        (
            "a main context peak every session holds gets a verdict",
            one(
                pair(two("p1", "ra", 1, 10), two("p1", "rb", 2, 5)),
                &[change('a', "main_context_peak", "rb")],
            ) == ["helped"],
        ),
        (
            "a group with no main context peak at all gives no data",
            one(no_peak_before, &[change('a', "main_context_peak", "rb")]) == ["no data"],
        ),
        (
            "the cache read share gets a verdict, its `%` dropped",
            one(
                pair(
                    two("p1", "ra", 1, 5),
                    vec![
                        S {
                            input: [90, 10, 0],
                            ..base("p1", "rb", 2, 5)
                        };
                        2
                    ],
                ),
                &[change('a', "cache_read_share", "rb")],
            ) == ["helped"],
        ),
        (
            "an unchanged value is no observed effect",
            one(
                pair(two("p1", "ra", 1, 5), two("p1", "rb", 2, 5)),
                &[change('a', "turns", "rb")],
            ) == ["no observed effect"],
        ),
    ]
}

// spec: VRD-10
fn advisor_verdict_checks(dir: &Path, tmp: &Path) -> Vec<(&'static str, bool)> {
    let one = |sessions: Vec<S<'static>>, changes: &[String]| {
        verdict(&verdicts(dir, tmp, &sessions, changes, &[]))
    };
    let advised = |revision: &'static str, calls: u64| -> Vec<S<'static>> {
        let day = if revision == "ra" { 1 } else { 2 };
        vec![
            S {
                advisor: "claude-opus-5-5",
                calls,
                ..base("p1", revision, day, 5)
            };
            2
        ]
    };
    let advisor_after = pair(
        advised("ra", 6),
        vec![advised("rb", 2).remove(0), base("p1", "rb", 2, 5)],
    );
    let advisor_before = pair(
        vec![advised("ra", 6).remove(0), base("p1", "ra", 1, 5)],
        advised("rb", 2),
    );
    vec![
        (
            "advisor metrics set by fewer sessions than the threshold confound, before or after",
            one(advisor_after, &[change('a', "advisor_calls", "rb")]) == ["confounded"]
                && one(
                    advisor_before,
                    &[change('a', "advisor_output_tokens", "rb")],
                ) == ["confounded"],
        ),
        (
            "a change of the most frequent advisor confounds an advisor metric, not another one",
            one(
                pair(
                    advised("ra", 6),
                    advised("rb", 2)
                        .into_iter()
                        .map(|s| S {
                            advisor: "claude-haiku-5-5",
                            ..s
                        })
                        .collect(),
                ),
                &[change('a', "advisor_calls", "rb")],
            ) == ["confounded"]
                && one(
                    pair(
                        advised("ra", 6),
                        vec![
                            S {
                                advisor: "claude-haiku-5-5",
                                turns: 4,
                                ..advised("rb", 2).remove(0)
                            };
                            2
                        ],
                    ),
                    &[change('a', "turns", "rb")],
                ) == ["helped"],
        ),
        (
            "advisor metrics every session sets get a verdict",
            one(
                pair(advised("ra", 6), advised("rb", 2)),
                &[change('a', "advisor_input_tokens", "rb")],
            ) == ["helped"],
        ),
    ]
}

#[test]
fn cardinal_report() {
    let dir = std::path::PathBuf::from("/tools");
    let temp = tempfile::tempdir().unwrap();
    let checks: Vec<_> = efficiency_checks(&dir, temp.path())
        .into_iter()
        .chain(option_checks(&dir, temp.path()))
        .chain(axes_checks(&dir, temp.path()))
        .chain(axes_threshold_checks(&dir, temp.path()))
        .chain(refusal_checks(&dir, temp.path()))
        .chain(verdict_checks(&dir, temp.path()))
        .chain(verdict_edge_checks(&dir, temp.path()))
        .chain(advisor_verdict_checks(&dir, temp.path()))
        .collect();
    let mut failed = false;
    for (name, ok) in checks {
        println!("{} - {name}", if ok { "ok  " } else { "FAIL" });
        failed |= !ok;
    }
    assert!(!failed, "a check failed: see the FAIL lines");
}

/// `cardinal tool <name>` for the script path the checks were written against (`next_issue.rs` is `next-issue`).
fn tool_command(script: impl AsRef<std::path::Path>) -> std::process::Command {
    let stem = script
        .as_ref()
        .file_stem()
        .unwrap()
        .to_string_lossy()
        .replace('_', "-");
    let mut cmd = std::process::Command::new(env!("CARGO_BIN_EXE_cardinal"));
    cmd.arg("tool").arg(stem);
    cmd
}
