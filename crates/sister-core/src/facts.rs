//! L1 事實層：從文字抽出 typed facts。
//!
//! 憲法（SPEC §0.2）：**這一層零 LLM**。全部是正規表示式與程式規則，
//! 因此可重跑、可稽核、不會幻覺。抽不出來就是抽不出來——寧可漏，不可編。
//!
//! 「抄寫歸程式，意圖歸模型」：金額、電話、日期是抄寫，歸這裡；
//! 「他在為錢焦慮」是意圖，歸 L2，不歸這裡。
//!
//! 主場是繁體中文的螢幕文字，因此規則以台灣格式為第一優先
//! （NT$、09xx 手機、市話區碼、民國式日期口語、中文數字）。

use std::sync::LazyLock;

use regex::Regex;

#[derive(Debug, Clone, Copy, PartialEq, Eq, Hash)]
pub enum FactKind {
    Money,
    Phone,
    Url,
    Email,
    FilePath,
    ErrorCode,
    IdLike,
    DateTimeMention,
}

impl FactKind {
    /// 全部的類別，一份。
    ///
    /// 以前這個清單被手抄過三份：`as_str`、`from_str_kind`，還有 CLI 上
    /// `--kind` 那行說明文字。前兩份至少還編得出錯，第三份不會——加一類事實
    /// 而忘了改它，使用者看到的就是一份少一項的選單。現在後兩者都從這裡長。
    pub const ALL: [FactKind; 8] = [
        FactKind::Money,
        FactKind::Phone,
        FactKind::Url,
        FactKind::Email,
        FactKind::FilePath,
        FactKind::ErrorCode,
        FactKind::IdLike,
        FactKind::DateTimeMention,
    ];

    /// 給人看的清單，用在說明文字和錯誤訊息裡。
    pub fn names(sep: &str) -> String {
        FactKind::ALL
            .into_iter()
            .map(FactKind::as_str)
            .collect::<Vec<_>>()
            .join(sep)
    }

    pub fn as_str(self) -> &'static str {
        match self {
            FactKind::Money => "money",
            FactKind::Phone => "phone",
            FactKind::Url => "url",
            FactKind::Email => "email",
            FactKind::FilePath => "file_path",
            FactKind::ErrorCode => "error_code",
            FactKind::IdLike => "id_like",
            FactKind::DateTimeMention => "datetime",
        }
    }

    pub fn from_str_kind(s: &str) -> Option<Self> {
        FactKind::ALL.into_iter().find(|k| k.as_str() == s)
    }

    /// 重疊時誰贏。數字小的優先——格式越明確、誤判越低的排越前面。
    fn priority(self) -> u8 {
        match self {
            FactKind::Url => 0,
            FactKind::Email => 1,
            FactKind::FilePath => 2,
            FactKind::ErrorCode => 3,
            FactKind::DateTimeMention => 4,
            FactKind::Money => 5,
            FactKind::Phone => 6,
            FactKind::IdLike => 7,
        }
    }
}

/// 打錯的類別要當場被拒絕，不能靜靜地回零筆。
///
/// `sister facts -k monney` 以前印的是「沒有符合的事實。」——和「你的記憶裡
/// 真的沒有金額」一字不差。使用者會拿後者去下結論，而他手上其實有一整年的
/// 帳單。這和空答案那條是同一個病：**查不到**和**問錯了**在畫面上長一樣。
///
/// 跟同意書那邊 (`consent::Sheet`) 同一個寫法、同一種語氣，因為那是這個專案
/// 已經決定過的形狀：講出打錯的是哪個字，附上可用的清單。
impl std::str::FromStr for FactKind {
    type Err = String;

    fn from_str(s: &str) -> std::result::Result<Self, Self::Err> {
        // 連字號和底線都收：`file-path` 和 `file_path` 之間的差別不值得
        // 讓人以為這個功能壞了。
        let want = s.trim().to_ascii_lowercase().replace('-', "_");
        FactKind::from_str_kind(&want)
            .ok_or_else(|| format!("沒有這一類事實：{s}（可用的是 {}）", FactKind::names("、")))
    }
}

/// 一個被抽出的事實。
///
/// `normalized` 是可比對的正規形式（`TWD:13450`、`+886800123456`、`TIME:17:00`），
/// `raw` 保留螢幕上的原樣——回答時要能引用使用者當時真正看到的字串。
#[derive(Debug, Clone, PartialEq)]
pub struct ExtractedFact {
    pub kind: FactKind,
    pub raw: String,
    pub normalized: String,
    pub byte_start: usize,
    pub byte_end: usize,
}

// 這裡以前有一個 `confidence: f32`，每條規則手寫一個 0.85～0.97 的數字。
//
// 它的註解說它是用來決定「兩條規則搶同一段文字時誰贏」的——那句話是假的。
// 去重排序讀的是 `kind.priority()`，從來沒有讀過這個欄位。把每一個值都
// 改成 0.5，99 個測試全過。
//
// 也就是說：它被算出來、寫進資料庫的每一列、印在使用者眼前（「信心 0.93」）、
// 出現在 JSON 裡，然後沒有任何一行程式讀它。設定項要嘛實作要嘛刪掉，
// 存起來的欄位也一樣。等 Phase 1 有了重播評測集、真的量得出「這條規則抽對
// 的比例是多少」，它再帶著一個有來源的數字回來。

struct Cand {
    kind: FactKind,
    start: usize,
    end: usize,
    normalized: String,
}

/// 從一段文字抽出所有事實，依 `byte_start` 排序、互不重疊。
pub fn extract(text: &str) -> Vec<ExtractedFact> {
    if text.is_empty() {
        return Vec::new();
    }

    // 規則跑在半形摺疊後的副本上：Windows OCR 常把帳單數字讀成全形。
    // `raw` 與 byte span 必須指回原文，不能把摺疊結果當成螢幕上的字。
    let (folded, orig_at) = fold_fullwidth_for_extract(text);
    let source = folded.as_str();

    let mut cands: Vec<Cand> = Vec::new();
    urls(source, &mut cands);
    emails(source, &mut cands);
    file_paths(source, &mut cands);
    error_codes(source, &mut cands);
    datetimes(source, &mut cands);
    money(source, &mut cands);
    phones(source, &mut cands);
    ids(source, &mut cands);

    // 先把跨度上的空白修掉。可選群組不存在時，它前面的 `\s*` 會把空白吃進
    // 比對範圍，害得邊界檢查誤以為隔壁的字緊貼著（`$20 per` 就是這樣被丟掉的）。
    for c in &mut cands {
        let s = &source[c.start..c.end];
        c.start += s.len() - s.trim_start().len();
        c.end -= s.len() - s.trim_end().len();
    }
    cands.retain(|c| c.end > c.start);

    // 邊界檢查：不能長在一串英數字的中間（避免從流水號裡切出假電話）
    cands.retain(|c| ascii_word_boundary(source, c.start, c.end));

    // 優先級 → 長者勝 → 位置在前者勝
    cands.sort_by(|a, b| {
        a.kind
            .priority()
            .cmp(&b.kind.priority())
            .then((b.end - b.start).cmp(&(a.end - a.start)))
            .then(a.start.cmp(&b.start))
    });

    let mut taken: Vec<(usize, usize)> = Vec::new();
    let mut out: Vec<ExtractedFact> = Vec::new();
    for c in cands {
        if taken.iter().any(|(s, e)| c.start < *e && *s < c.end) {
            continue;
        }
        taken.push((c.start, c.end));
        let byte_start = orig_at[c.start];
        let byte_end = orig_at[c.end];
        out.push(ExtractedFact {
            kind: c.kind,
            raw: text[byte_start..byte_end].to_string(),
            normalized: c.normalized,
            byte_start,
            byte_end,
        });
    }

    out.sort_by_key(|f| f.byte_start);
    out
}

/// 從自然語言查詢裡辨認出使用者要的是哪一類事實。
///
/// 為什麼需要這個：螢幕上寫的是「客服**專線**」，使用者問的是「電話」。
/// 全文檢索永遠接不起這兩個詞——但 L1 早就把那串數字標成了 `phone`。
/// 這張表就是把「使用者的說法」接到「事實的型別」的那條線。
///
/// 純查表、零模型。詞彙不足時寧可回空集合，不猜。
const QUERY_KIND_TABLE: &[(&str, FactKind)] = &[
    ("電話", FactKind::Phone),
    ("手機", FactKind::Phone),
    ("專線", FactKind::Phone),
    ("號碼", FactKind::Phone),
    // 底下這幾條是拿真的問題去問她問出來的，不是坐在這裡想出來的：
    // 「門號」和「我要繳多少」原本各是零筆答案，而那兩個東西就在螢幕上
    // （「門號 0912-345-678」「本期應繳金額 NT$13,450」）。
    ("門號", FactKind::Phone), // 台灣講手機就是講這兩個字，帳單上也印這個
    ("分機", FactKind::Phone),
    ("phone", FactKind::Phone),
    ("telephone", FactKind::Phone),
    ("tel", FactKind::Phone),
    ("金額", FactKind::Money),
    ("價格", FactKind::Money),
    ("價錢", FactKind::Money),
    ("多少錢", FactKind::Money),
    // 「多少」自己太泛（多少人、多少次），配上動詞才問得出錢。
    ("繳多少", FactKind::Money),
    ("付多少", FactKind::Money),
    ("欠多少", FactKind::Money),
    ("應繳", FactKind::Money),
    ("費用", FactKind::Money),
    ("帳單", FactKind::Money),
    ("繳費", FactKind::Money),
    ("money", FactKind::Money),
    ("price", FactKind::Money),
    ("cost", FactKind::Money),
    ("網址", FactKind::Url),
    ("連結", FactKind::Url),
    ("網站", FactKind::Url),
    ("官網", FactKind::Url),
    ("url", FactKind::Url),
    ("link", FactKind::Url),
    ("信箱", FactKind::Email),
    ("郵件", FactKind::Email),
    ("email", FactKind::Email),
    ("mail", FactKind::Email),
    ("檔案", FactKind::FilePath),
    ("路徑", FactKind::FilePath),
    ("file", FactKind::FilePath),
    ("path", FactKind::FilePath),
    ("錯誤", FactKind::ErrorCode),
    ("例外", FactKind::ErrorCode),
    ("error", FactKind::ErrorCode),
    ("exception", FactKind::ErrorCode),
    ("編號", FactKind::IdLike),
    ("單號", FactKind::IdLike),
    ("序號", FactKind::IdLike),
    ("日期", FactKind::DateTimeMention),
    ("時間", FactKind::DateTimeMention),
    ("期限", FactKind::DateTimeMention),
    // 「幾號」刻意不收：「今天幾號」問日期，「電話幾號」問號碼，分不出來就不猜
    ("什麼時候", FactKind::DateTimeMention),
    ("date", FactKind::DateTimeMention),
    ("when", FactKind::DateTimeMention),
    ("deadline", FactKind::DateTimeMention),
];

fn query_kind_word_hits(q: &str, word: &str) -> bool {
    // 英文必須是獨立詞（可接複數 s），不能把 hotel 的 tel、profile 的
    // file 或識別字 error_code 當成類型要求。中文沒有空白，仍允許連寫；
    // 共用的 ASCII 邊界也保留「phone是多少」這種中英相接的問法。
    q.match_indices(word).any(|(start, _)| {
        let end = start + word.len();
        !word.is_ascii()
            || ascii_word_boundary(q, start, end)
            || (q[end..].starts_with('s') && ascii_word_boundary(q, start, end + 1))
    })
}

pub fn kinds_for_query(query: &str) -> Vec<FactKind> {
    let q = query.to_lowercase();
    let mut out: Vec<FactKind> = Vec::new();
    for (word, kind) in QUERY_KIND_TABLE {
        if query_kind_word_hits(&q, word) && !out.contains(kind) {
            out.push(*kind);
        }
    }
    out
}

/// 類型詞以外還剩下的主題。有的話，L1 答案必須出現在這段主題的出處附近，
/// 不能把「火星會議連結」答成記憶裡任意一個網址。
///
/// 問句虛字不是主題：「電話是多少」「請幫我找昨天電話」與
/// `what was the phone number yesterday` 都只問類型，不另限來源。
pub fn topic_constraint(query: &str) -> Option<String> {
    let lower = query.to_lowercase();
    let mut rest = strip_fact_question_edges(&lower).to_owned();
    rest = crate::question::terms(&rest).to_owned();
    rest = strip_kind_words(&rest);
    let leftover = strip_fact_question_edges(&rest)
        .split_whitespace()
        .filter(|tok| tok.chars().count() >= 2)
        .collect::<Vec<_>>()
        .join(" ");
    (!leftover.is_empty()).then_some(leftover)
}

fn strip_kind_words(rest: &str) -> String {
    let mut keys: Vec<&str> = QUERY_KIND_TABLE.iter().map(|(word, _)| *word).collect();
    keys.sort_by_key(|word| std::cmp::Reverse(word.len()));
    let mut rest = rest.to_owned();
    for key in keys {
        let mut next = String::new();
        let mut i = 0;
        while i < rest.len() {
            if rest[i..].starts_with(key) {
                let end = i + key.len();
                let taken = if key.is_ascii() && rest[end..].starts_with('s') {
                    end + 1
                } else {
                    end
                };
                if !key.is_ascii() || ascii_word_boundary(&rest, i, taken) {
                    next.push(' ');
                    i = taken;
                    continue;
                }
            }
            let ch = rest[i..].chars().next().expect("rest not empty");
            next.push(ch);
            i += ch.len_utf8();
        }
        rest = next;
    }
    rest
}

// 只剝頭尾完整問句用語，不把中間的「我家」「是否」等名稱切碎。
// 單字虛字交給 [`crate::question::terms`]，避免「是否」被「是」從開頭切掉。
fn strip_fact_question_edges(mut text: &str) -> &str {
    const CJK: &[&str] = &[
        "請幫我找",
        "請幫我查",
        "幫我找",
        "幫我查",
        "我想知道",
        "告訴我",
        "請問",
        "我要",
        "是多少",
        "是什麼",
        "有多少",
        "多少",
        "幾號",
        "在哪裡",
        "在哪",
        "昨天",
        "今天",
        "前天",
        "剛剛",
        "剛才",
        "那個",
        "這個",
    ];
    const ASCII: &[&str] = &[
        "yesterday",
        "numbers",
        "number",
        "please",
        "codes",
        "today",
        "what",
        "were",
        "code",
        "find",
        "show",
        "tell",
        "was",
        "are",
        "the",
        "and",
        "an",
        "is",
        "my",
        "me",
        "a",
    ];
    loop {
        text = text.trim_matches(|c: char| {
            c.is_whitespace() || matches!(c, '?' | '？' | '。' | '!' | '！' | ',')
        });
        let old = text;
        if let Some(tail) = CJK.iter().find_map(|word| text.strip_prefix(word)) {
            text = tail;
        } else if let Some(head) = CJK.iter().find_map(|word| text.strip_suffix(word)) {
            text = head;
        } else if let Some(tail) = ASCII.iter().find_map(|word| {
            text.strip_prefix(word)
                .filter(|_| ascii_word_boundary(text, 0, word.len()))
        }) {
            text = tail;
        } else if let Some(head) = ASCII.iter().find_map(|word| {
            text.strip_suffix(word)
                .filter(|_| ascii_word_boundary(text, text.len() - word.len(), text.len()))
        }) {
            text = head;
        }
        if text == old {
            return text;
        }
    }
}

// ---------- 共用工具 ----------

/// 全形 ASCII 與常見 OCR 連字號摺成半形。
///
/// Windows OCR 常把帳單上的 `0912-345-678`、`NT$13,450` 讀成
/// `０９１２－３４５－６７８`、`ＮＴ＄１３，４５０`。規則仍只認半形；
/// 摺疊只為了比對，原文 span 另外對回去。
fn fold_fullwidth_char(c: char) -> char {
    match c {
        '\u{3000}' => ' ',
        '\u{FF01}'..='\u{FF5E}' => char::from_u32(c as u32 - 0xFEE0).unwrap_or(c),
        '\u{2010}' | '\u{2011}' | '\u{2012}' | '\u{2013}' | '\u{2014}' | '\u{2015}'
        | '\u{2212}' | '\u{FE58}' | '\u{FE63}' => '-',
        _ => c,
    }
}

/// 摺疊後的 UTF-8，以及每個摺疊 byte 對應的原文起點。
///
/// `orig_at.len() == folded.len() + 1`；最後一格是原文結尾，給 exclusive end 用。
fn fold_fullwidth_for_extract(text: &str) -> (String, Vec<usize>) {
    let mut folded = String::with_capacity(text.len());
    let mut orig_at = Vec::with_capacity(text.len() + 1);
    for (byte_idx, ch) in text.char_indices() {
        let mapped = fold_fullwidth_char(ch);
        for _ in 0..mapped.len_utf8() {
            orig_at.push(byte_idx);
        }
        folded.push(mapped);
    }
    orig_at.push(text.len());
    (folded, orig_at)
}

/// 兩端不得緊鄰 ASCII 英數字或底線。
///
/// 刻意不用 regex 的 `\b`：在 unicode 模式下 CJK 是 word char，
/// 「帳單13450元」的數字兩側根本不存在 `\b`，整組規則會失效。
fn ascii_word_boundary(text: &str, start: usize, end: usize) -> bool {
    let before_ok = text[..start]
        .chars()
        .next_back()
        .is_none_or(|c| !(c.is_ascii_alphanumeric() || c == '_'));
    let after_ok = text[end..]
        .chars()
        .next()
        .is_none_or(|c| !(c.is_ascii_alphanumeric() || c == '_'));
    before_ok && after_ok
}

/// 中文數字轉阿拉伯數字。支援 零一二三四五六七八九十百千萬億 與 兩、大寫壹貳參。
fn cjk_number(s: &str) -> Option<f64> {
    let (mut total, mut section, mut digit, mut any) = (0.0f64, 0.0f64, 0.0f64, false);
    for c in s.chars() {
        let d = match c {
            '零' | '〇' => Some(0.0),
            '一' | '壹' => Some(1.0),
            '二' | '貳' | '兩' => Some(2.0),
            '三' | '參' => Some(3.0),
            '四' | '肆' => Some(4.0),
            '五' | '伍' => Some(5.0),
            '六' | '陸' => Some(6.0),
            '七' | '柒' => Some(7.0),
            '八' | '捌' => Some(8.0),
            '九' | '玖' => Some(9.0),
            _ => None,
        };
        if let Some(d) = d {
            digit = d;
            any = true;
            continue;
        }
        // 「十」單獨出現代表 10，「二十」代表 20
        let unit = match c {
            '十' | '拾' => 10.0,
            '百' | '佰' => 100.0,
            '千' | '仟' => 1000.0,
            '萬' => {
                total += (section + digit) * 10_000.0;
                section = 0.0;
                digit = 0.0;
                any = true;
                continue;
            }
            '億' => {
                total = (total + section + digit) * 100_000_000.0;
                section = 0.0;
                digit = 0.0;
                any = true;
                continue;
            }
            _ => return None,
        };
        section += if digit == 0.0 { unit } else { digit * unit };
        digit = 0.0;
        any = true;
    }
    if !any {
        return None;
    }
    Some(total + section + digit)
}

/// 金額字串正規化：去千分位、去尾零。`13450`、`49.99`、`13450.5`
fn fmt_amount(v: f64) -> String {
    if (v - v.round()).abs() < 1e-9 {
        format!("{}", v.round() as i64)
    } else {
        let s = format!("{v:.2}");
        s.trim_end_matches('0').trim_end_matches('.').to_string()
    }
}

/// 附近是否有 CJK 字元——用來判斷孤零零的 `$` 在台灣脈絡下該算台幣還是美元。
fn cjk_nearby(text: &str, start: usize, end: usize) -> bool {
    let lo = text[..start]
        .char_indices()
        .rev()
        .take(12)
        .last()
        .map_or(0, |(i, _)| i);
    let hi = text[end..]
        .char_indices()
        .take(12)
        .last()
        .map_or(end, |(i, c)| end + i + c.len_utf8());
    text[lo..hi]
        .chars()
        .any(|c| matches!(c, '\u{3000}'..='\u{9FFF}' | '\u{FF00}'..='\u{FFEF}'))
}

// ---------- Money ----------

static RE_MONEY_PREFIX: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(
        r"(?i)(NT\$|NTD|TWD|US\$|USD|RMB|CNY|JPY|EUR|GBP|HKD|新臺幣|新台幣|台幣|人民幣|日幣|美金|美元|[¥＄€£$])\s*(\d[\d,]*(?:\.\d{1,2})?)\s*([萬千億])?",
    )
    .expect("money prefix regex")
});

static RE_MONEY_SUFFIX: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(
        r"(\d[\d,]*(?:\.\d{1,2})?)\s*([萬千億])?\s*(元整|元|塊錢|塊|圓|日圓|日元|美元|美金|歐元|英鎊|港幣|人民幣|新臺幣|新台幣|台幣)",
    )
    .expect("money suffix regex")
});

static RE_MONEY_CJK: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"[零〇一二三四五六七八九十百千萬億兩壹貳參肆伍陸柒捌玖拾佰仟]{1,12}\s*(元整|元|塊錢|塊|圓)")
        .expect("money cjk regex")
});

fn currency_of(token: &str) -> Option<&'static str> {
    let t = token.to_ascii_uppercase();
    Some(match t.as_str() {
        "NT$" | "NTD" | "TWD" => "TWD",
        "US$" | "USD" => "USD",
        "RMB" | "CNY" => "CNY",
        "JPY" => "JPY",
        "EUR" => "EUR",
        "GBP" => "GBP",
        "HKD" => "HKD",
        _ => match token {
            "新臺幣" | "新台幣" | "台幣" | "元整" | "元" | "塊錢" | "塊" | "圓" => {
                "TWD"
            }
            "人民幣" => "CNY",
            "日幣" | "日圓" | "日元" | "¥" => "JPY",
            "美金" | "美元" => "USD",
            "歐元" | "€" => "EUR",
            "英鎊" | "£" => "GBP",
            "港幣" => "HKD",
            _ => return None,
        },
    })
}

fn multiplier(m: &str) -> f64 {
    match m {
        "千" => 1_000.0,
        "萬" => 10_000.0,
        "億" => 100_000_000.0,
        _ => 1.0,
    }
}

fn money(text: &str, out: &mut Vec<Cand>) {
    for c in RE_MONEY_PREFIX.captures_iter(text) {
        let whole = c.get(0).expect("group 0");
        let sym = c.get(1).expect("symbol").as_str();
        let num: f64 = match c[2].replace(',', "").parse() {
            Ok(v) => v,
            Err(_) => continue,
        };
        let mult = c.get(3).map_or(1.0, |m| multiplier(m.as_str()));

        // 孤零零的 `$`：旁邊有中文就是台幣，否則按國際慣例算美元
        let cur = if sym == "$" || sym == "＄" {
            if cjk_nearby(text, whole.start(), whole.end()) {
                "TWD"
            } else {
                "USD"
            }
        } else {
            currency_of(sym).unwrap_or("TWD")
        };

        out.push(Cand {
            kind: FactKind::Money,
            start: whole.start(),
            end: whole.end(),
            normalized: format!("{cur}:{}", fmt_amount(num * mult)),
        });
    }

    for c in RE_MONEY_SUFFIX.captures_iter(text) {
        let whole = c.get(0).expect("group 0");
        let num: f64 = match c[1].replace(',', "").parse() {
            Ok(v) => v,
            Err(_) => continue,
        };
        let mult = c.get(2).map_or(1.0, |m| multiplier(m.as_str()));
        let cur = currency_of(&c[3]).unwrap_or("TWD");
        out.push(Cand {
            kind: FactKind::Money,
            start: whole.start(),
            end: whole.end(),
            normalized: format!("{cur}:{}", fmt_amount(num * mult)),
        });
    }

    for c in RE_MONEY_CJK.captures_iter(text) {
        let whole = c.get(0).expect("group 0");
        let unit = c.get(1).expect("unit");
        let digits = text[whole.start()..unit.start()].trim();
        let Some(v) = cjk_number(digits) else {
            continue;
        };
        let cur = currency_of(unit.as_str()).unwrap_or("TWD");
        out.push(Cand {
            kind: FactKind::Money,
            start: whole.start(),
            end: whole.end(),
            normalized: format!("{cur}:{}", fmt_amount(v)),
        });
    }
}

// ---------- Phone（台灣） ----------

static RE_PHONE: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(concat!(
        // 國際格式手機
        r"(?:\+?886[-\s]?0?9\d{2}[-\s]?\d{3}[-\s]?\d{3})",
        // 國內手機 09xx
        r"|(?:09\d{2}[-\s]?\d{3}[-\s]?\d{3})",
        // 免付費 / 付費客服 0800 0809 0203 412
        r"|(?:080[09][-\s]?\d{3}[-\s]?\d{3})",
        // 市話：(02) 2345-6789 / 02-2345-6789 / 03-123-4567 / 037-123456
        r"|(?:\(0[2-9]\d?\)[-\s]?\d{3,4}[-\s]?\d{4})",
        r"|(?:0[2-9]\d?[-\s]\d{3,4}[-\s]?\d{4})",
    ))
    .expect("phone regex")
});

fn phones(text: &str, out: &mut Vec<Cand>) {
    for m in RE_PHONE.find_iter(text) {
        let raw = m.as_str();
        let digits: String = raw.chars().filter(|c| c.is_ascii_digit()).collect();

        // 去掉國碼與國內冠碼，統一成 E.164 的國內號碼部分
        let national = digits
            .strip_prefix("886")
            .map(|d| d.trim_start_matches('0'))
            .unwrap_or_else(|| digits.trim_start_matches('0'));

        // 台灣號碼去掉 0 之後是 8~9 碼；不合就丟掉，不猜
        if national.len() < 8 || national.len() > 9 {
            continue;
        }

        out.push(Cand {
            kind: FactKind::Phone,
            start: m.start(),
            end: m.end(),
            normalized: format!("+886{national}"),
        });
    }
}

// ---------- Url / Email ----------

static RE_URL: LazyLock<Regex> = LazyLock::new(|| {
    // 字元集刻意全 ASCII：中文標點自然成為結束邊界，不必額外處理
    Regex::new(r"(?i)(?:https?://|ftp://|www\.)[A-Za-z0-9\-._~:/?#\[\]@!$&'()*+,;=%]+")
        .expect("url regex")
});

static RE_EMAIL: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"[A-Za-z0-9._%+\-]+@[A-Za-z0-9\-]+(?:\.[A-Za-z0-9\-]+)*\.[A-Za-z]{2,24}")
        .expect("email regex")
});

fn urls(text: &str, out: &mut Vec<Cand>) {
    for m in RE_URL.find_iter(text) {
        // 句尾標點不屬於網址
        let trimmed = m
            .as_str()
            .trim_end_matches(['.', ',', ';', ':', '!', '?', ')', ']', '}', '\'', '"', '>']);
        if trimmed.len() < 8 {
            continue;
        }
        let lower = trimmed.to_ascii_lowercase();
        let normalized = if lower.starts_with("www.") {
            format!("https://{lower}")
        } else {
            lower
        };
        out.push(Cand {
            kind: FactKind::Url,
            start: m.start(),
            end: m.start() + trimmed.len(),
            normalized,
        });
    }
}

fn emails(text: &str, out: &mut Vec<Cand>) {
    for m in RE_EMAIL.find_iter(text) {
        out.push(Cand {
            kind: FactKind::Email,
            start: m.start(),
            end: m.end(),
            normalized: m.as_str().to_ascii_lowercase(),
        });
    }
}

// ---------- FilePath ----------

/// Windows 路徑的合法字元。刻意用「白名單」而非 `[^\s...]`：
/// 負向字元集會把後面的中文一路吞掉（`C:\x\y.rs，找不到` → 整句變成路徑）。
/// 空白允許（`C:\Program Files\`），但由 [`trim_path_tail`] 事後收尾。
const WIN_PATH_CHARS: &str = r"[A-Za-z0-9_\-.\\/()~$@#%&+='\[\] ]";

static RE_PATH: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(
        &concat!(
            // Windows 絕對路徑 C:\Users\ted\x.rs
            r"(?:[A-Za-z]:\\{c}{2,240})",
            // UNC \\server\share\x
            r"|(?:\\\\{c}{3,240})",
            // Unix / ~ 開頭，且含副檔名
            r"|(?:(?:~|\.{1,2})?/(?:[\w.+\-@]+/)*[\w.+\-@]+\.[A-Za-z0-9]{1,8})",
            // Unix 目錄（至少兩層）
            r"|(?:(?:~|\.{1,2})?/(?:[\w.+\-@]+/){2,}[\w.+\-@]*)",
            // 相對路徑：至少兩段且有副檔名（`crates/sister-core/src/db.rs`）
            r"|(?:[\w.+\-@]+(?:/[\w.+\-@]+)+\.[A-Za-z0-9]{1,8})",
        )
        .replace("{c}", WIN_PATH_CHARS),
    )
    .expect("path regex")
});

/// 收掉尾巴上不屬於路徑的東西。
///
/// 路徑裡可以有空白，但只有在空白之後還有分隔符時才算數。
/// `C:\Program Files\App\x.exe is missing` 的最後一段是 `x.exe is missing`，
/// 其中的空白之後沒有 `\`，所以從那裡切斷。
fn trim_path_tail(s: &str) -> &str {
    let s = s.trim_end_matches([' ', '.', ',', ';', ':', ')', ']', '"', '\'']);
    let last_sep = s.rfind(['\\', '/']).map_or(0, |i| i + 1);
    match s[last_sep..].find(' ') {
        Some(i) => s[..last_sep + i].trim_end_matches([' ', '\\', '/']),
        None => s,
    }
}

fn file_paths(text: &str, out: &mut Vec<Cand>) {
    for m in RE_PATH.find_iter(text) {
        let raw = trim_path_tail(m.as_str());
        if raw.len() < 5 {
            continue;
        }
        // 反斜線統一成正斜線只是為了比對；raw 仍保留使用者看到的樣子
        out.push(Cand {
            kind: FactKind::FilePath,
            start: m.start(),
            end: m.start() + raw.len(),
            normalized: raw.replace('\\', "/"),
        });
    }
}

// ---------- ErrorCode ----------

/// 常見 errno / POSIX 錯誤名。用白名單而非 `E[A-Z]+`，避免把縮寫詞當錯誤碼。
const ERRNO: &[&str] = &[
    "ENOENT",
    "EACCES",
    "EPERM",
    "EEXIST",
    "ENOTDIR",
    "EISDIR",
    "EINVAL",
    "ENOSPC",
    "EPIPE",
    "EAGAIN",
    "EBUSY",
    "EMFILE",
    "ENFILE",
    "ECONNREFUSED",
    "ECONNRESET",
    "ECONNABORTED",
    "ETIMEDOUT",
    "EHOSTUNREACH",
    "ENETUNREACH",
    "EADDRINUSE",
    "EADDRNOTAVAIL",
    "EPROTO",
    "ENOMEM",
    "EIO",
    "EROFS",
    "EXDEV",
    "ELOOP",
    "ENAMETOOLONG",
];

static RE_ERR_SNAKE: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"[A-Z][A-Z0-9]*(?:_[A-Z0-9]+)+").expect("err snake regex"));
static RE_ERR_HEX: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"0x[0-9A-Fa-f]{8}").expect("err hex regex"));
static RE_ERR_COMPILER: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(?:E|TS|CS|MSB|CA|SA|CVE-\d{4}-)\d{3,7}").expect("err code regex")
});
static RE_ERR_SIGNAL: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"SIG(?:SEGV|KILL|TERM|ABRT|BUS|FPE|ILL|INT|HUP|PIPE)").expect("signal regex")
});
static RE_ERR_EXC: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"[A-Z][A-Za-z0-9]{2,40}(?:Exception|Error)").expect("exception regex")
});
static RE_ERR_HTTP: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(?i)(?:http|https|status|狀態碼|錯誤碼|回應碼)\s*[:：]?\s*([1-5]\d{2})")
        .expect("http status regex")
});
static RE_ERRNO: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"E[A-Z]{2,12}").expect("errno regex"));

/// SCREAMING_SNAKE 常數多得是，只有語意上真的在講錯誤的才收。
fn snake_looks_like_error(s: &str) -> bool {
    const SIGNALS: &[&str] = &[
        "ERR",
        "ERROR",
        "FAIL",
        "FAILED",
        "FAILURE",
        "INVALID",
        "DENIED",
        "REFUSED",
        "TIMEOUT",
        "TIMED_OUT",
        "NOT_FOUND",
        "UNAUTHORIZED",
        "FORBIDDEN",
        "ABORTED",
        "CRASH",
        "PANIC",
        "UNAVAILABLE",
        "EXCEPTION",
        "FATAL",
        "CORRUPT",
        "MISMATCH",
        "REJECTED",
        "EXPIRED",
    ];
    s.len() >= 6 && SIGNALS.iter().any(|k| s.contains(k))
}

fn error_codes(text: &str, out: &mut Vec<Cand>) {
    let mut push = |start: usize, end: usize, norm: String| {
        out.push(Cand {
            kind: FactKind::ErrorCode,
            start,
            end,
            normalized: norm,
        });
    };

    for m in RE_ERR_SNAKE.find_iter(text) {
        if snake_looks_like_error(m.as_str()) {
            push(m.start(), m.end(), m.as_str().to_string());
        }
    }
    for m in RE_ERRNO.find_iter(text) {
        if ERRNO.contains(&m.as_str()) {
            push(m.start(), m.end(), m.as_str().to_string());
        }
    }
    for m in RE_ERR_HEX.find_iter(text) {
        push(
            m.start(),
            m.end(),
            m.as_str().to_ascii_uppercase().replace("0X", "0x"),
        );
    }
    for m in RE_ERR_COMPILER.find_iter(text) {
        push(m.start(), m.end(), m.as_str().to_ascii_uppercase());
    }
    for m in RE_ERR_SIGNAL.find_iter(text) {
        push(m.start(), m.end(), m.as_str().to_string());
    }
    for m in RE_ERR_EXC.find_iter(text) {
        push(m.start(), m.end(), m.as_str().to_string());
    }
    for c in RE_ERR_HTTP.captures_iter(text) {
        let code = c.get(1).expect("status group");
        push(code.start(), code.end(), format!("HTTP:{}", code.as_str()));
    }
}

// ---------- IdLike ----------

static RE_UUID: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"[0-9a-fA-F]{8}-[0-9a-fA-F]{4}-[0-9a-fA-F]{4}-[0-9a-fA-F]{4}-[0-9a-fA-F]{12}")
        .expect("uuid regex")
});
static RE_TWID: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"[A-Z][12]\d{8}").expect("tw id regex"));
static RE_VAT: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(?:統一編號|統編|營利事業統一編號|VAT|Tax\s*ID)\s*[:：]?\s*(\d{8})")
        .expect("vat regex")
});
static RE_SHA: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"(?i)commit\s+([0-9a-f]{7,40})").expect("sha regex"));
static RE_ORDER: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(
        r"(?i)(?:訂單編號|訂單號碼|訂單|單號|案件編號|會員編號|序號|發票號碼|order\s*(?:id|no\.?|number)|ticket|ref\.?)\s*[:：#]?\s*([A-Za-z0-9][A-Za-z0-9\-]{4,23})",
    )
    .expect("order regex")
});

/// 中華民國身分證字號檢查碼。有了它，`[A-Z][12]\d{8}` 的誤判率趨近於零。
fn tw_id_valid(s: &str) -> bool {
    let b = s.as_bytes();
    if b.len() != 10 {
        return false;
    }
    let letter = b[0];
    if !letter.is_ascii_uppercase() {
        return false;
    }
    const MAP: &[u32] = &[
        10, 11, 12, 13, 14, 15, 16, 17, 34, 18, 19, 20, 21, 22, 35, 23, 24, 25, 26, 27, 28, 29, 32,
        30, 31, 33,
    ];
    let code = MAP[(letter - b'A') as usize];
    let mut sum = code / 10 + (code % 10) * 9;
    for (i, d) in b[1..10].iter().enumerate() {
        if !d.is_ascii_digit() {
            return false;
        }
        let weight = if i == 8 { 1 } else { 8 - i as u32 };
        sum += (d - b'0') as u32 * weight;
    }
    sum.rem_euclid(10) == 0
}

fn ids(text: &str, out: &mut Vec<Cand>) {
    let mut push = |start: usize, end: usize, norm: String| {
        out.push(Cand {
            kind: FactKind::IdLike,
            start,
            end,
            normalized: norm,
        });
    };

    for m in RE_UUID.find_iter(text) {
        push(m.start(), m.end(), m.as_str().to_ascii_lowercase());
    }
    for m in RE_TWID.find_iter(text) {
        if tw_id_valid(m.as_str()) {
            push(m.start(), m.end(), m.as_str().to_string());
        }
    }
    for c in [&*RE_VAT, &*RE_SHA, &*RE_ORDER]
        .into_iter()
        .flat_map(|re| re.captures_iter(text))
    {
        let g = c.get(1).expect("id group");
        push(g.start(), g.end(), g.as_str().to_string());
    }
}

// ---------- DateTimeMention ----------
//
// L1 只記「線索」，不解析成絕對時間。`明天` 正規化成 `REL:+1d`，
// 要換算成哪一天由呼叫端配合該筆 chunk 的時間戳決定——抽取器拿不到
// 時間戳，硬猜就是編造。

static RE_DATE_FULL: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"(\d{4})[-/年](\d{1,2})[-/月](\d{1,2})日?").expect("date regex"));
static RE_DATE_PART: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"(\d{1,2})([/月])(\d{1,2})日?").expect("partial date regex"));
static RE_CLOCK: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"(\d{1,2}):(\d{2})(?::(\d{2}))?").expect("clock regex"));
static RE_AMPM: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"(?i)(\d{1,2})(?::(\d{2}))?\s*(am|pm)").expect("ampm regex"));
static RE_CJK_CLOCK: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(凌晨|清晨|早上|上午|中午|下午|傍晚|晚上|晚間|深夜|半夜)?\s*(\d{1,2})\s*[點時](半|\d{1,2}\s*分?)?")
        .expect("cjk clock regex")
});
static RE_REL_WORD: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"大後天|大前天|後天|前天|明天|明日|隔天|明早|明晚|昨天|昨日|今天|今日|今晚|今夜")
        .expect("relative word regex")
});
static RE_REL_QTY: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(
        r"(\d{1,4}|[零一二三四五六七八九十百兩]{1,6})\s*(個月|分鐘|小時|星期|週|周|天|日|年)\s*(以後|之後|以內|之內|以前|之前|後|內|前)",
    )
    .expect("relative qty regex")
});
static RE_WEEK: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(上上|下下|上|下|這|本|今)?(?:週|周|星期|禮拜)([一二三四五六日天])?")
        .expect("week regex")
});
static RE_MONTH_OFF: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(上上|下下|上|下|這|本|今)\s*個?月").expect("month offset regex")
});

fn week_offset_days(prefix: &str) -> i32 {
    match prefix {
        "上上" => -14,
        "下下" => 14,
        "上" => -7,
        "下" => 7,
        _ => 0,
    }
}

fn datetimes(text: &str, out: &mut Vec<Cand>) {
    let mut push = |start: usize, end: usize, norm: String| {
        out.push(Cand {
            kind: FactKind::DateTimeMention,
            start,
            end,
            normalized: norm,
        });
    };

    for c in RE_DATE_FULL.captures_iter(text) {
        let (y, m, d) = (
            c[1].parse::<u32>().unwrap_or(0),
            c[2].parse::<u32>().unwrap_or(0),
            c[3].parse::<u32>().unwrap_or(0),
        );
        if !(1900..=2200).contains(&y) || !(1..=12).contains(&m) || !(1..=31).contains(&d) {
            continue;
        }
        let w = c.get(0).expect("group 0");
        push(w.start(), w.end(), format!("DATE:{y:04}-{m:02}-{d:02}"));
    }

    for c in RE_DATE_PART.captures_iter(text) {
        let (m, d) = (
            c[1].parse::<u32>().unwrap_or(0),
            c[3].parse::<u32>().unwrap_or(0),
        );
        if !(1..=12).contains(&m) || !(1..=31).contains(&d) {
            continue;
        }
        let w = c.get(0).expect("group 0");
        // `8月17日` 不會有別的意思；`8/17` 可能是分數、比例或版本號。
        // 這裡以前把後者的 confidence 壓成 0.65 就算處理過了——但沒有人讀
        // 那個數字，所以 `8/17` 一直是以「日期」的身分照樣抽出來的。留著這
        // 段話是為了記住：這個歧義還沒有解，壓一個沒人看的分數不算解。
        push(w.start(), w.end(), format!("DATE:--{m:02}-{d:02}"));
    }

    for c in RE_CLOCK.captures_iter(text) {
        let (h, m) = (
            c[1].parse::<u32>().unwrap_or(99),
            c[2].parse::<u32>().unwrap_or(99),
        );
        if h > 23 || m > 59 {
            continue;
        }
        let w = c.get(0).expect("group 0");
        push(w.start(), w.end(), format!("TIME:{h:02}:{m:02}"));
    }

    for c in RE_AMPM.captures_iter(text) {
        let mut h = c[1].parse::<u32>().unwrap_or(99);
        let m = c
            .get(2)
            .and_then(|g| g.as_str().parse::<u32>().ok())
            .unwrap_or(0);
        if h > 12 || m > 59 {
            continue;
        }
        let pm = c[3].eq_ignore_ascii_case("pm");
        if pm && h < 12 {
            h += 12;
        } else if !pm && h == 12 {
            h = 0;
        }
        let w = c.get(0).expect("group 0");
        push(w.start(), w.end(), format!("TIME:{h:02}:{m:02}"));
    }

    for c in RE_CJK_CLOCK.captures_iter(text) {
        let mut h = c[2].parse::<u32>().unwrap_or(99);
        if h > 23 {
            continue;
        }
        let m = match c.get(3).map(|g| g.as_str().trim()) {
            Some("半") => 30,
            Some(s) => s
                .trim_end_matches(['分', ' '])
                .trim()
                .parse::<u32>()
                .unwrap_or(0),
            None => 0,
        };
        if m > 59 {
            continue;
        }
        match c.get(1).map(|g| g.as_str()) {
            Some("下午" | "傍晚" | "晚上" | "晚間") if h < 12 => h += 12,
            Some("深夜" | "半夜") if h < 6 => {}
            Some("深夜" | "半夜") if h < 12 => h += 12,
            Some("凌晨" | "清晨" | "早上" | "上午") if h == 12 => h = 0,
            _ => {}
        }
        let w = c.get(0).expect("group 0");
        push(w.start(), w.end(), format!("TIME:{h:02}:{m:02}"));
    }

    for m in RE_REL_WORD.find_iter(text) {
        let days = match m.as_str() {
            "大後天" => 3,
            "後天" => 2,
            "明天" | "明日" | "隔天" | "明早" | "明晚" => 1,
            "今天" | "今日" | "今晚" | "今夜" => 0,
            "昨天" | "昨日" => -1,
            "前天" => -2,
            "大前天" => -3,
            _ => continue,
        };
        push(m.start(), m.end(), format!("REL:{days:+}d"));
    }

    for c in RE_REL_QTY.captures_iter(text) {
        let n = c[1]
            .parse::<f64>()
            .ok()
            .or_else(|| cjk_number(&c[1]))
            .unwrap_or(0.0);
        if n <= 0.0 || n > 10_000.0 {
            continue;
        }
        let (mult, unit) = match &c[2] {
            "分鐘" => (1.0, 'm'),
            "小時" => (1.0, 'h'),
            "天" | "日" => (1.0, 'd'),
            "星期" | "週" | "周" => (7.0, 'd'),
            "個月" => (30.0, 'd'),
            "年" => (365.0, 'd'),
            _ => continue,
        };
        let sign = if c[3].contains('前') { -1.0 } else { 1.0 };
        let v = (n * mult * sign) as i64;
        let w = c.get(0).expect("group 0");
        push(w.start(), w.end(), format!("REL:{v:+}{unit}"));
    }

    for c in RE_WEEK.captures_iter(text) {
        let w = c.get(0).expect("group 0");
        match c.get(2).map(|g| g.as_str()) {
            Some(d) => {
                let n = match d {
                    "一" => 1,
                    "二" => 2,
                    "三" => 3,
                    "四" => 4,
                    "五" => 5,
                    "六" => 6,
                    _ => 7, // 日 / 天
                };
                push(w.start(), w.end(), format!("WEEKDAY:{n}"));
            }
            // 光一個「週」太模糊，只有帶上/下/這才是時間指涉
            None => {
                if let Some(p) = c.get(1) {
                    let days = week_offset_days(p.as_str());
                    push(w.start(), w.end(), format!("REL:{days:+}d"));
                }
            }
        }
    }

    for c in RE_MONTH_OFF.captures_iter(text) {
        let days = week_offset_days(&c[1]) / 7 * 30;
        let w = c.get(0).expect("group 0");
        push(w.start(), w.end(), format!("REL:{days:+}d"));
    }
}

#[cfg(test)]
mod tests {
    use super::*;

    /// 取出某一類事實的正規化值。
    fn norms(text: &str, kind: FactKind) -> Vec<String> {
        extract(text)
            .into_iter()
            .filter(|f| f.kind == kind)
            .map(|f| f.normalized)
            .collect()
    }

    fn raws(text: &str, kind: FactKind) -> Vec<String> {
        extract(text)
            .into_iter()
            .filter(|f| f.kind == kind)
            .map(|f| f.raw)
            .collect()
    }

    fn has(text: &str, kind: FactKind, normalized: &str) -> bool {
        norms(text, kind).iter().any(|n| n == normalized)
    }

    // ---------- 結構不變式 ----------

    #[test]
    fn output_is_sorted_and_non_overlapping() {
        let text = "2026-08-17 17:00 帳單 NT$13,450 客服 0800-123-456 \
                    見 https://bill.example.com/x 或 ted@ted-h.com";
        let facts = extract(text);
        assert!(facts.len() >= 5, "expected several facts, got {facts:?}");

        let mut prev_end = 0;
        for f in &facts {
            assert!(f.byte_start >= prev_end, "overlap or bad order at {f:?}");
            assert!(f.byte_end > f.byte_start);
            assert_eq!(
                &text[f.byte_start..f.byte_end],
                f.raw,
                "raw must match its span"
            );
            prev_end = f.byte_end;
        }
    }

    #[test]
    fn empty_and_boring_text_yields_nothing() {
        assert!(extract("").is_empty());
        assert!(extract("   \n  ").is_empty());
        assert!(extract("天氣不錯，我在想事情。").is_empty());
        assert!(extract("hello there how are you").is_empty());
    }

    #[test]
    fn optional_trailing_groups_do_not_eat_the_next_word() {
        // 迴歸測試：`$20 per month` 曾因為比對範圍多含一個空白而整個被丟掉
        let f = extract("Pro plan $20 per month");
        assert_eq!(f.len(), 1, "{f:?}");
        assert_eq!(f[0].raw, "$20", "span must not include trailing space");
        assert_eq!(f[0].normalized, "USD:20");
        assert_eq!(raws("訂閱費 $390 每月", FactKind::Money), vec!["$390"]);
    }

    #[test]
    fn query_keywords_map_to_fact_kinds() {
        // 這條線就是 Phase 0 退出條件成立的原因：螢幕上是「客服專線」，
        // 使用者問「電話」，接起來的不是全文檢索而是 L1 的型別。
        assert_eq!(kinds_for_query("電話"), vec![FactKind::Phone]);
        assert_eq!(kinds_for_query("客服電話幾號"), vec![FactKind::Phone]);
        assert_eq!(kinds_for_query("phone number"), vec![FactKind::Phone]);
        assert_eq!(kinds_for_query("帳單多少錢"), vec![FactKind::Money]);
        assert_eq!(
            kinds_for_query("繳費期限"),
            vec![FactKind::Money, FactKind::DateTimeMention]
        );
        assert_eq!(
            kinds_for_query("那個 error code"),
            vec![FactKind::ErrorCode]
        );
        // 拿真的問題去問她之後補的兩條。之前各是零筆答案，而東西就在螢幕上。
        assert_eq!(kinds_for_query("門號"), vec![FactKind::Phone]);
        assert_eq!(kinds_for_query("我要繳多少"), vec![FactKind::Money]);
        assert_eq!(kinds_for_query("昨天應繳"), vec![FactKind::Money]);
        assert_eq!(kinds_for_query("昨天那個網站"), vec![FactKind::Url]);
        assert_eq!(kinds_for_query("官網網址"), vec![FactKind::Url]);
        // 「多少」自己不算——問「多少人」不是在問錢
        assert!(kinds_for_query("那場會議來了多少人").is_empty());
        // 認不出來就回空的，不猜
        assert!(kinds_for_query("我昨天在幹嘛").is_empty());
        assert!(kinds_for_query("").is_empty());
    }

    #[test]
    fn topic_constraint_keeps_named_sources_and_drops_question_filler() {
        assert_eq!(topic_constraint("昨天電話"), None);
        assert_eq!(topic_constraint("昨天那個網站"), None);
        assert_eq!(topic_constraint("電話是多少"), None);
        assert_eq!(topic_constraint("請幫我找昨天電話"), None);
        assert_eq!(topic_constraint("我要繳多少"), None);
        assert_eq!(
            topic_constraint("what was the phone number yesterday"),
            None
        );
        assert_eq!(
            topic_constraint("火星會議連結").as_deref(),
            Some("火星會議")
        );
        assert_eq!(topic_constraint("客服電話").as_deref(), Some("客服"));
        assert_eq!(topic_constraint("是否電話"), None);
    }

    #[test]
    fn words_and_identifiers_do_not_accidentally_request_fact_types() {
        for query in [
            "hotel booking",
            "profile settings",
            "update release",
            "updated",
            "costume",
            "blink",
            "whenever",
            "telephone_directory",
            "error_code",
            "user_email",
            "file2",
            "myphone",
            "DATE_FORMAT",
        ] {
            assert!(kinds_for_query(query).is_empty(), "{query}");
        }
    }

    #[test]
    fn explicit_english_fact_words_keep_case_punctuation_plurals_and_chinese_neighbors() {
        for query in [
            "PHONE number",
            "(tel)",
            "電話phone",
            "phone是多少",
            "phones",
            "telephone",
        ] {
            assert_eq!(kinds_for_query(query), vec![FactKind::Phone], "{query}");
        }
        for (query, kind) in [
            ("files", FactKind::FilePath),
            ("emails", FactKind::Email),
            ("e-mail", FactKind::Email),
            ("URLs", FactKind::Url),
            ("prices", FactKind::Money),
            ("dates", FactKind::DateTimeMention),
            ("errors", FactKind::ErrorCode),
        ] {
            assert_eq!(kinds_for_query(query), vec![kind], "{query}");
        }
        assert_eq!(kinds_for_query("hotel phone"), vec![FactKind::Phone]);
        assert_eq!(
            kinds_for_query("profile file path"),
            vec![FactKind::FilePath]
        );
    }

    #[test]
    fn kind_strings_round_trip() {
        for k in [
            FactKind::Money,
            FactKind::Phone,
            FactKind::Url,
            FactKind::Email,
            FactKind::FilePath,
            FactKind::ErrorCode,
            FactKind::IdLike,
            FactKind::DateTimeMention,
        ] {
            assert_eq!(FactKind::from_str_kind(k.as_str()), Some(k));
        }
        assert_eq!(FactKind::from_str_kind("nope"), None);
    }

    // ---------- Money ----------

    #[test]
    fn money_taiwan_formats() {
        assert!(has("本期應繳 NT$13,450", FactKind::Money, "TWD:13450"));
        assert!(has("本期應繳 NT$ 13,450 元", FactKind::Money, "TWD:13450"));
        assert!(has("金額 13,450元", FactKind::Money, "TWD:13450"));
        assert!(has("新台幣13,450元整", FactKind::Money, "TWD:13450"));
        assert!(has("TWD 1350", FactKind::Money, "TWD:1350"));
        assert!(has("要價 1.5萬元", FactKind::Money, "TWD:15000"));
        assert!(has("差 250 塊", FactKind::Money, "TWD:250"));
    }

    #[test]
    fn money_decimals_and_foreign_currencies() {
        assert!(has("USD 49.99", FactKind::Money, "USD:49.99"));
        assert!(has("US$1,299.00", FactKind::Money, "USD:1299"));
        assert!(has("€89.50", FactKind::Money, "EUR:89.5"));
        assert!(has("JPY 12000", FactKind::Money, "JPY:12000"));
        assert!(has("人民幣 300", FactKind::Money, "CNY:300"));
        assert!(has("賣 100 美元", FactKind::Money, "USD:100"));
    }

    #[test]
    fn money_cjk_numerals() {
        assert!(has("繳了一百二十元", FactKind::Money, "TWD:120"));
        assert!(has("兩萬元", FactKind::Money, "TWD:20000"));
        assert!(has("三萬五千元", FactKind::Money, "TWD:35000"));
        assert!(has("一千兩百五十元", FactKind::Money, "TWD:1250"));
    }

    #[test]
    fn bare_dollar_sign_reads_context() {
        // 旁邊有中文 → 台灣脈絡下的 $ 是台幣
        assert!(has("訂閱費 $390 每月", FactKind::Money, "TWD:390"));
        // 純英文脈絡 → 依國際慣例算美元
        assert!(has("Pro plan $20 per month", FactKind::Money, "USD:20"));
    }

    #[test]
    fn money_does_not_invent_currency_from_bare_numbers() {
        // 「3萬人」是人數不是錢——沒有貨幣詞就不該猜
        assert!(norms("現場有3萬人", FactKind::Money).is_empty());
        assert!(norms("共 13450 筆資料", FactKind::Money).is_empty());
        assert!(norms("版本 2.5", FactKind::Money).is_empty());
    }

    // ---------- Phone ----------

    #[test]
    fn phone_taiwan_formats_normalize_to_e164() {
        assert!(has(
            "客服專線 0800-123-456",
            FactKind::Phone,
            "+886800123456"
        ));
        assert!(has("手機 0912-345-678", FactKind::Phone, "+886912345678"));
        assert!(has("手機 0912345678", FactKind::Phone, "+886912345678"));
        assert!(has("手機 0912 345 678", FactKind::Phone, "+886912345678"));
        assert!(has("打 +886-912-345-678", FactKind::Phone, "+886912345678"));
        assert!(has("市話 02-2345-6789", FactKind::Phone, "+886223456789"));
        assert!(has("市話 (02) 2345-6789", FactKind::Phone, "+886223456789"));
        assert!(has("台中 04-1234-5678", FactKind::Phone, "+886412345678"));
    }

    #[test]
    fn fullwidth_ocr_digits_still_extract_taiwan_phone_and_money() {
        let bill = "門號 ０９１２－３４５－６７８\n本期應繳 ＮＴ＄１３，４５０";
        let facts = extract(bill);
        let phone = facts
            .iter()
            .find(|f| f.kind == FactKind::Phone)
            .expect("fullwidth mobile");
        assert_eq!(phone.normalized, "+886912345678");
        assert_eq!(phone.raw, "０９１２－３４５－６７８");
        assert_eq!(&bill[phone.byte_start..phone.byte_end], phone.raw);
        let money = facts
            .iter()
            .find(|f| f.kind == FactKind::Money)
            .expect("fullwidth amount");
        assert_eq!(money.normalized, "TWD:13450");
        assert_eq!(money.raw, "ＮＴ＄１３，４５０");
        assert_eq!(&bill[money.byte_start..money.byte_end], money.raw);
        assert!(has(
            "客服專線 ０８００－０８０－１２３",
            FactKind::Phone,
            "+886800080123"
        ));
    }

    #[test]
    fn phone_rejects_lookalikes() {
        // 日期不是電話
        assert!(norms("2026-08-17", FactKind::Phone).is_empty());
        // 訂單流水號不是電話（邊界檢查要擋住從中間切一段出來）
        assert!(norms("ORDER0912345678901234", FactKind::Phone).is_empty());
        assert!(norms("金額 13,450", FactKind::Phone).is_empty());
        // 長度不對就不猜
        assert!(norms("0912-345", FactKind::Phone).is_empty());
    }

    // ---------- Url / Email ----------

    #[test]
    fn urls_and_emails() {
        assert!(has(
            "看 https://dash.cloudflare.com/dns 設定",
            FactKind::Url,
            "https://dash.cloudflare.com/dns"
        ));
        assert!(has(
            "到 www.example.com 看看",
            FactKind::Url,
            "https://www.example.com"
        ));
        assert!(has(
            "寄給 Ted@Ted-H.com 就好",
            FactKind::Email,
            "ted@ted-h.com"
        ));
    }

    #[test]
    fn url_stops_at_sentence_punctuation() {
        // 中文標點與句號都不屬於網址
        assert_eq!(
            raws("請看 https://example.com/a/b。", FactKind::Url),
            vec!["https://example.com/a/b"]
        );
        assert_eq!(
            raws("see https://example.com/a/b.", FactKind::Url),
            vec!["https://example.com/a/b"]
        );
    }

    #[test]
    fn email_inside_url_does_not_double_count() {
        let facts = extract("https://api.example.com/u/bob@example.com/profile");
        assert_eq!(facts.len(), 1, "url must win the overlap: {facts:?}");
        assert_eq!(facts[0].kind, FactKind::Url);
    }

    // ---------- FilePath ----------

    #[test]
    fn file_paths_unix_and_windows() {
        assert!(has(
            "編輯 /home/ted-h/projects/AI-Sister/docs/SPEC.md",
            FactKind::FilePath,
            "/home/ted-h/projects/AI-Sister/docs/SPEC.md"
        ));
        assert!(has(
            "開 C:\\Users\\ted\\notes.txt",
            FactKind::FilePath,
            "C:/Users/ted/notes.txt"
        ));
        assert!(has(
            "放在 ~/Downloads/bill.pdf",
            FactKind::FilePath,
            "~/Downloads/bill.pdf"
        ));
    }

    #[test]
    fn windows_path_stops_before_trailing_prose() {
        // 白名單字元集擋住中文，trim_path_tail 擋住英文句子
        assert_eq!(
            raws("C:\\x\\y.rs，找不到檔案", FactKind::FilePath),
            vec!["C:\\x\\y.rs"]
        );
        assert_eq!(
            raws(
                "C:\\Program Files\\App\\x.exe is missing",
                FactKind::FilePath
            ),
            vec!["C:\\Program Files\\App\\x.exe"]
        );
    }

    // ---------- ErrorCode ----------

    #[test]
    fn error_codes_across_ecosystems() {
        assert!(has(
            "ERR_CONNECTION_REFUSED",
            FactKind::ErrorCode,
            "ERR_CONNECTION_REFUSED"
        ));
        assert!(has(
            "connect ECONNREFUSED 127.0.0.1",
            FactKind::ErrorCode,
            "ECONNREFUSED"
        ));
        assert!(has("open failed: ENOENT", FactKind::ErrorCode, "ENOENT"));
        assert!(has("錯誤 0x80070005", FactKind::ErrorCode, "0x80070005"));
        assert!(has(
            "error[E0308]: mismatched types",
            FactKind::ErrorCode,
            "E0308"
        ));
        assert!(has(
            "TS2345: argument of type",
            FactKind::ErrorCode,
            "TS2345"
        ));
        assert!(has("killed by SIGSEGV", FactKind::ErrorCode, "SIGSEGV"));
        assert!(has(
            "threw a NullPointerException",
            FactKind::ErrorCode,
            "NullPointerException"
        ));
    }

    #[test]
    fn http_status_needs_context_and_bare_numbers_do_not_count() {
        assert!(has("HTTP 404 Not Found", FactKind::ErrorCode, "HTTP:404"));
        assert!(has("狀態碼：500", FactKind::ErrorCode, "HTTP:500"));
        // 光一個 404 太模糊，不收
        assert!(norms("共 404 筆", FactKind::ErrorCode).is_empty());
    }

    #[test]
    fn ordinary_constants_are_not_error_codes() {
        // SCREAMING_SNAKE 滿街都是，只有語意上在講錯誤的才算
        assert!(norms("MAX_RETRY_COUNT = 3", FactKind::ErrorCode).is_empty());
        assert!(norms("API_BASE_URL", FactKind::ErrorCode).is_empty());
        // 反過來，名字裡就有錯誤語意的仍然要收
        assert!(has(
            "DEFAULT_TIMEOUT_MS",
            FactKind::ErrorCode,
            "DEFAULT_TIMEOUT_MS"
        ));
    }

    // ---------- IdLike ----------

    #[test]
    fn ids_with_explicit_format() {
        assert!(has(
            "trace 550e8400-e29b-41d4-a716-446655440000",
            FactKind::IdLike,
            "550e8400-e29b-41d4-a716-446655440000"
        ));
        assert!(has("身分證 A123456789", FactKind::IdLike, "A123456789"));
        assert!(has("統一編號: 12345675", FactKind::IdLike, "12345675"));
        assert!(has(
            "訂單編號 TW-20260817-001",
            FactKind::IdLike,
            "TW-20260817-001"
        ));
        assert!(has("commit a1b2c3d4e5f6", FactKind::IdLike, "a1b2c3d4e5f6"));
    }

    #[test]
    fn tw_id_checksum_rejects_invalid() {
        assert!(tw_id_valid("A123456789"));
        assert!(!tw_id_valid("A123456788"));
        assert!(!tw_id_valid("A123456780"));
        assert!(!tw_id_valid("1234567890"));
        assert!(!tw_id_valid("A12345678"));
        // 檢查碼擋掉的東西不該進 facts
        assert!(norms("代號 A123456788", FactKind::IdLike).is_empty());
    }

    #[test]
    fn bare_digit_runs_are_not_ids() {
        // 沒有格式也沒有關鍵字 → 不猜，否則 facts 表會被流水號淹掉
        assert!(norms("12345678901234", FactKind::IdLike).is_empty());
    }

    // ---------- DateTimeMention ----------

    #[test]
    fn absolute_dates() {
        assert!(has(
            "2026-08-17 交件",
            FactKind::DateTimeMention,
            "DATE:2026-08-17"
        ));
        assert!(has(
            "2026/8/17",
            FactKind::DateTimeMention,
            "DATE:2026-08-17"
        ));
        assert!(has(
            "2026年8月17日",
            FactKind::DateTimeMention,
            "DATE:2026-08-17"
        ));
        assert!(has(
            "8月17日截止",
            FactKind::DateTimeMention,
            "DATE:--08-17"
        ));
        // 不合法的日期不收
        assert!(norms("2026-13-45", FactKind::DateTimeMention).is_empty());
    }

    #[test]
    fn clock_times() {
        assert!(has("17:00 開會", FactKind::DateTimeMention, "TIME:17:00"));
        assert!(has("下午5點", FactKind::DateTimeMention, "TIME:17:00"));
        assert!(has("晚上8點半", FactKind::DateTimeMention, "TIME:20:30"));
        assert!(has("早上9點30分", FactKind::DateTimeMention, "TIME:09:30"));
        assert!(has("5pm", FactKind::DateTimeMention, "TIME:17:00"));
        assert!(has("9:30 AM", FactKind::DateTimeMention, "TIME:09:30"));
        assert!(norms("25:99", FactKind::DateTimeMention).is_empty());
    }

    #[test]
    fn relative_time_stays_relative() {
        // L1 不換算成絕對日期——抽取器拿不到當下時間，硬換算就是編造
        assert!(has("明天交", FactKind::DateTimeMention, "REL:+1d"));
        assert!(has("後天", FactKind::DateTimeMention, "REL:+2d"));
        assert!(has("昨天", FactKind::DateTimeMention, "REL:-1d"));
        assert!(has("三天後", FactKind::DateTimeMention, "REL:+3d"));
        assert!(has("兩週後", FactKind::DateTimeMention, "REL:+14d"));
        assert!(has("3小時後", FactKind::DateTimeMention, "REL:+3h"));
        assert!(has("30分鐘後", FactKind::DateTimeMention, "REL:+30m"));
        assert!(has("兩天前", FactKind::DateTimeMention, "REL:-2d"));
        assert!(has("下個月", FactKind::DateTimeMention, "REL:+30d"));
    }

    #[test]
    fn weekdays_beat_bare_week_offsets() {
        // 「下週三」要抽出星期三，不能被「下週」吃掉
        assert!(has("下週三開會", FactKind::DateTimeMention, "WEEKDAY:3"));
        assert!(has("星期日", FactKind::DateTimeMention, "WEEKDAY:7"));
        assert!(has("禮拜五", FactKind::DateTimeMention, "WEEKDAY:5"));
        // 沒帶星期幾時才退回週偏移
        assert!(has("下週再說", FactKind::DateTimeMention, "REL:+7d"));
        // 光一個「這週」以外的裸「週」字太模糊
        assert!(norms("週報", FactKind::DateTimeMention).is_empty());
    }

    #[test]
    fn date_and_time_coexist_in_one_line() {
        let facts = extract("2026-08-17 17:00 在會議室");
        let dt: Vec<_> = facts
            .iter()
            .filter(|f| f.kind == FactKind::DateTimeMention)
            .collect();
        assert_eq!(dt.len(), 2, "date and time are separate facts: {dt:?}");
        assert_eq!(dt[0].normalized, "DATE:2026-08-17");
        assert_eq!(dt[1].normalized, "TIME:17:00");
    }

    // ---------- 真實場景 ----------

    #[test]
    fn a_realistic_bill_screen() {
        let screen = "中華電信 帳單查詢\n\
                      本期應繳金額 NT$13,450\n\
                      繳費期限 2026/08/25\n\
                      客服專線 0800-080-123\n\
                      線上繳費 https://bill.cht.com.tw/pay";
        let facts = extract(screen);

        assert!(has(screen, FactKind::Money, "TWD:13450"));
        assert!(has(screen, FactKind::DateTimeMention, "DATE:2026-08-25"));
        assert!(has(screen, FactKind::Phone, "+886800080123"));
        assert!(has(screen, FactKind::Url, "https://bill.cht.com.tw/pay"));

        // 每個事實都必須指得回原文的確切位置
        for f in &facts {
            assert_eq!(&screen[f.byte_start..f.byte_end], f.raw);
        }
    }

    #[test]
    fn a_realistic_error_screen() {
        let screen = "Failed to compile crates/sister-core/src/db.rs\n\
                      error[E0308]: mismatched types\n\
                      caused by ECONNREFUSED at 17:42";
        assert!(has(screen, FactKind::ErrorCode, "E0308"));
        assert!(has(screen, FactKind::ErrorCode, "ECONNREFUSED"));
        assert!(has(screen, FactKind::DateTimeMention, "TIME:17:42"));
        assert!(has(
            screen,
            FactKind::FilePath,
            "crates/sister-core/src/db.rs"
        ));
    }

    // ---------- 內部工具 ----------

    #[test]
    fn cjk_number_parser() {
        assert_eq!(cjk_number("一百二十"), Some(120.0));
        assert_eq!(cjk_number("兩萬"), Some(20_000.0));
        assert_eq!(cjk_number("三萬五千"), Some(35_000.0));
        assert_eq!(cjk_number("一千兩百五十"), Some(1250.0));
        assert_eq!(cjk_number("十"), Some(10.0));
        assert_eq!(cjk_number("二十"), Some(20.0));
        assert_eq!(cjk_number("零"), Some(0.0));
        assert_eq!(cjk_number("abc"), None);
        assert_eq!(cjk_number(""), None);
    }

    #[test]
    fn amount_formatting_drops_noise_zeros() {
        assert_eq!(fmt_amount(13450.0), "13450");
        assert_eq!(fmt_amount(49.99), "49.99");
        assert_eq!(fmt_amount(89.50), "89.5");
        assert_eq!(fmt_amount(0.0), "0");
    }

    #[test]
    fn ascii_word_boundary_treats_cjk_as_a_boundary() {
        // 這正是不能用 regex \b 的原因：CJK 在 unicode 模式下是 word char
        let t = "帳單13450元";
        let start = t.find("13450").expect("digits");
        assert!(ascii_word_boundary(t, start, start + 5));

        let t2 = "ORDER13450X";
        let start2 = t2.find("13450").expect("digits");
        assert!(!ascii_word_boundary(t2, start2, start2 + 5));
    }

    #[test]
    fn every_kind_is_in_the_one_list() {
        // 底下這個 match 是故意寫成窮舉的：新增一個變體時它會編不過，而它就在
        // `ALL` 旁邊——那一刻就是去補 `ALL` 的時候。少補的後果不會編不過，
        // 只會讓 `--kind` 的說明少一項、而那一項照樣查得到，沒人會發現。
        for k in FactKind::ALL {
            match k {
                FactKind::Money
                | FactKind::Phone
                | FactKind::Url
                | FactKind::Email
                | FactKind::FilePath
                | FactKind::ErrorCode
                | FactKind::IdLike
                | FactKind::DateTimeMention => {}
            }
            // 每一個都認得自己的名字，來回一趟要回到原點。
            assert_eq!(FactKind::from_str_kind(k.as_str()), Some(k));
        }

        let mut names: Vec<_> = FactKind::ALL.into_iter().map(FactKind::as_str).collect();
        names.sort_unstable();
        let before = names.len();
        names.dedup();
        assert_eq!(before, names.len(), "兩個類別共用一個名字，其中一個查不到");
    }

    #[test]
    fn a_kind_that_does_not_exist_is_refused_not_answered_with_silence() {
        // 這是重點：打錯字**不可以**長得像「你沒有這一類事實」。
        let e = "monney"
            .parse::<FactKind>()
            .expect_err("打錯的類別要被拒絕");
        assert!(e.contains("monney"), "要講出他打錯的是哪個字：{e}");
        assert!(e.contains("money"), "要附上可用的清單：{e}");

        // 清單是長出來的，不是抄的——每一類都要出現在錯誤訊息裡。
        for k in FactKind::ALL {
            assert!(e.contains(k.as_str()), "{} 不在清單裡：{e}", k.as_str());
        }
    }

    #[test]
    fn the_two_ways_of_writing_file_path_both_work() {
        // `file-path` 和 `file_path` 之間的差別不值得讓人以為功能壞了。
        assert_eq!("file-path".parse::<FactKind>(), Ok(FactKind::FilePath));
        assert_eq!("FILE_PATH".parse::<FactKind>(), Ok(FactKind::FilePath));
        assert_eq!("  phone  ".parse::<FactKind>(), Ok(FactKind::Phone));
    }
}
