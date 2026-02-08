//! Regexp pattern scanning utilities for Neovim.
//!
//! Provides `rs_skip_regexp` and `rs_skip_regexp_ex` — stateless helpers that
//! skip past a regexp pattern to its closing delimiter, handling magic modes,
//! `[...]` character class ranges, and multibyte characters.

#![allow(clippy::missing_safety_doc)]
#![allow(unsafe_code)]
#![allow(clippy::cast_possible_wrap)]
#![allow(clippy::cast_sign_loss)]
#![allow(clippy::cast_lossless)]
#![allow(clippy::borrow_as_ptr)]

use std::ffi::{c_char, c_int, c_uint, c_void};

use std::ffi::c_long;

#[allow(dead_code)]
extern "C" {
    fn utfc_ptr2len(p: *const c_char) -> c_int;
    fn nvim_regexp_get_char_class(pp: *mut *mut c_char) -> c_int;
    fn nvim_regexp_get_equi_class(pp: *mut *mut c_char) -> c_int;
    fn nvim_regexp_get_coll_element(pp: *mut *mut c_char) -> c_int;
    fn nvim_get_p_cpo() -> *const c_char;
    fn vim_strchr(string: *const c_char, c: c_int) -> *mut c_char;
    fn xstrnsave(s: *const c_char, len: usize) -> *mut c_char;
    fn nvim_regexp_get_regflags(prog: *const c_void) -> c_uint;

    // Parse state accessors
    fn nvim_regexp_get_regparse() -> *mut c_char;
    fn nvim_regexp_set_regparse(p: *mut c_char);
    fn nvim_regexp_get_prevchr_len() -> c_int;
    fn nvim_regexp_set_prevchr_len(v: c_int);
    fn nvim_regexp_get_curchr() -> c_int;
    fn nvim_regexp_set_curchr(v: c_int);
    fn nvim_regexp_get_prevchr() -> c_int;
    fn nvim_regexp_set_prevchr(v: c_int);
    fn nvim_regexp_get_prevprevchr() -> c_int;
    fn nvim_regexp_set_prevprevchr(v: c_int);
    fn nvim_regexp_get_nextchr() -> c_int;
    fn nvim_regexp_set_nextchr(v: c_int);
    fn nvim_regexp_get_at_start() -> c_int;
    fn nvim_regexp_set_at_start(v: c_int);
    fn nvim_regexp_get_prev_at_start() -> c_int;
    fn nvim_regexp_set_prev_at_start(v: c_int);
    fn nvim_regexp_get_regnpar() -> c_int;
    fn nvim_regexp_set_regnpar(v: c_int);
    fn nvim_regexp_get_reg_magic() -> c_int;
    fn nvim_regexp_set_reg_magic(v: c_int);
    fn nvim_regexp_get_after_slash() -> c_int;
    fn nvim_regexp_set_after_slash(v: c_int);
    fn nvim_regexp_get_rex_reg_ic() -> c_int;
    fn nvim_regexp_get_rex_reg_icombine() -> c_int;
    fn nvim_regexp_emsg2_fail(msg: *const c_char, is_magic_all: c_int) -> c_int;

    // Multibyte helpers
    fn utf_ptr2len(p: *const c_char) -> c_int;
    fn utf_ptr2char(p: *const c_char) -> c_int;
    fn getdigits_int(pp: *mut *mut c_char, strict: bool, def: c_int) -> c_int;

    // Case-insensitive helpers
    fn utf_fold(a: c_int) -> c_int;
    fn utf_strnicmp(s1: *const c_char, s2: *const c_char, n1: usize, n2: usize) -> c_int;
    fn mb_ptr2char_adv(pp: *mut *const c_char) -> c_int;

    // libc
    fn strncmp(s1: *const c_char, s2: *const c_char, n: usize) -> c_int;
}

// Characters always special inside [] ranges
const REGEXP_INRANGE: &[u8] = b"]^-n\\";
// Abbreviation characters after '\'
const REGEXP_ABBR: &[u8] = b"nrtebdoxuU";
// CPO_LITERAL flag character
const CPO_LITERAL: c_int = b'l' as c_int;
// CLASS_NONE return value from get_char_class
const CLASS_NONE: c_int = 99;

// Magic modes (matching regexp_defs.h)
#[allow(dead_code)]
const MAGIC_NONE: c_int = 1;
const MAGIC_OFF: c_int = 2;
const MAGIC_ON: c_int = 3;
const MAGIC_ALL: c_int = 4;

/// Skip over a "[]" range. `p` must point to the character after the '['.
/// The returned pointer is on the matching ']', or the terminating NUL.
///
/// Mirrors `skip_anyof` in `regexp.c`.
unsafe fn skip_anyof(mut p: *mut c_char, reg_cpo_lit: bool) -> *mut c_char {
    if *p == b'^' as c_char {
        p = p.add(1);
    }
    if *p == b']' as c_char || *p == b'-' as c_char {
        p = p.add(1);
    }
    while *p != 0 && *p != b']' as c_char {
        let l = utfc_ptr2len(p);
        if l > 1 {
            p = p.add(l as usize);
        } else if *p == b'-' as c_char {
            p = p.add(1);
            if *p != b']' as c_char && *p != 0 {
                // MB_PTR_ADV
                p = p.add(utfc_ptr2len(p) as usize);
            }
        } else if *p == b'\\' as c_char
            && (REGEXP_INRANGE.contains(&(*p.add(1) as u8))
                || (!reg_cpo_lit && REGEXP_ABBR.contains(&(*p.add(1) as u8))))
        {
            p = p.add(2);
        } else if *p == b'[' as c_char {
            if nvim_regexp_get_char_class(&mut p) == CLASS_NONE
                && nvim_regexp_get_equi_class(&mut p) == 0
                && nvim_regexp_get_coll_element(&mut p) == 0
                && *p != 0
            {
                p = p.add(1);
            }
        } else {
            p = p.add(1);
        }
    }
    p
}

/// Skip past regular expression, extended version.
///
/// Stop at end of `startp` or where `dirc` delimiter is found.
/// Handles backslash escapes, `[...]` ranges, `\?` replacement, and
/// `\v`/`\V` magic mode switches.
///
/// When `newp` is not NULL and `dirc` is '?', makes an allocated copy of the
/// expression and changes `\?` to `?`. If `*newp` is not NULL the expression
/// is changed in-place.
/// If a `\?` is changed to `?` then `dropped` is incremented, unless NULL.
/// If `magic_val` is not NULL, returns the effective magicness of the pattern.
#[no_mangle]
pub unsafe extern "C" fn rs_skip_regexp_ex(
    startp: *mut c_char,
    dirc: c_int,
    magic: c_int,
    newp: *mut *mut c_char,
    dropped: *mut c_int,
    magic_val: *mut c_int,
) -> *mut c_char {
    let mut mymagic: c_int = if magic != 0 { MAGIC_ON } else { MAGIC_OFF };
    let reg_cpo_lit = !vim_strchr(nvim_get_p_cpo(), CPO_LITERAL).is_null();

    let mut p = startp;
    let mut startp = startp;
    let mut startplen: usize = 0;

    while *p != 0 {
        if c_int::from(*p) == dirc {
            break;
        }
        if (*p == b'[' as c_char && mymagic >= MAGIC_ON)
            || (*p == b'\\' as c_char && *p.add(1) == b'[' as c_char && mymagic <= MAGIC_OFF)
        {
            p = skip_anyof(p.add(1), reg_cpo_lit);
            if *p == 0 {
                break;
            }
        } else if *p == b'\\' as c_char && *p.add(1) != 0 {
            if dirc == b'?' as c_int && !newp.is_null() && *p.add(1) == b'?' as c_char {
                // change "\?" to "?", make a copy first.
                if startplen == 0 {
                    startplen = libc_strlen(startp);
                }
                if (*newp).is_null() {
                    *newp = xstrnsave(startp, startplen);
                    p = (*newp).add(p.offset_from(startp) as usize);
                    startp = *newp;
                }
                if !dropped.is_null() {
                    *dropped += 1;
                }
                std::ptr::copy(
                    p.add(1),
                    p,
                    startplen - (p.add(1).offset_from(startp) as usize) + 1,
                );
            } else {
                p = p.add(1); // skip next character
            }
            if *p == b'v' as c_char {
                mymagic = MAGIC_ALL;
            } else if *p == b'V' as c_char {
                mymagic = MAGIC_NONE;
            }
        }
        // MB_PTR_ADV
        p = p.add(utfc_ptr2len(p) as usize);
    }
    if !magic_val.is_null() {
        *magic_val = mymagic;
    }
    p
}

/// Skip past regular expression.
///
/// Stop at end of `startp` or where `dirc` is found ('/', '?', etc).
/// Take care of characters with a backslash in front of it.
/// Skip strings inside [ and ].
#[no_mangle]
pub unsafe extern "C" fn rs_skip_regexp(
    startp: *mut c_char,
    dirc: c_int,
    magic: c_int,
) -> *mut c_char {
    rs_skip_regexp_ex(
        startp,
        dirc,
        magic,
        std::ptr::null_mut(),
        std::ptr::null_mut(),
        std::ptr::null_mut(),
    )
}

/// Simple strlen implementation to avoid depending on libc crate.
#[allow(clippy::missing_const_for_fn)]
unsafe fn libc_strlen(s: *const c_char) -> usize {
    let mut len = 0;
    while *s.add(len) != 0 {
        len += 1;
    }
    len
}

// --- Magic helpers (matching regexp.c macros) ---
// Magic(x) = (int)(x) - 256; is_Magic(x) = (x) < 0; un_Magic(x) = (x) + 256

/// Multi-type return values
const NOT_MULTI: c_int = 0;
const MULTI_ONE: c_int = 1;
const MULTI_MULT: c_int = 2;

/// Control character constants (matching `ascii_defs.h`)
const BS_CH: c_int = 0o010;
const TAB_CH: c_int = 0o011;
const CAR_CH: c_int = 0o015;
const ESC_CH: c_int = 0o033;

/// Magic('x') = (x as i32) - 256
const fn magic(x: u8) -> c_int {
    (x as c_int) - 256
}

/// If x is Magic (negative), strip the magic to get the plain character.
/// Otherwise return x unchanged.
#[no_mangle]
pub const extern "C" fn rs_no_magic(x: c_int) -> c_int {
    if x < 0 {
        x + 256
    } else {
        x
    }
}

/// If x is Magic (negative), un-magic it. Otherwise make it Magic.
#[no_mangle]
pub const extern "C" fn rs_toggle_magic(x: c_int) -> c_int {
    if x < 0 {
        x + 256
    } else {
        x - 256
    }
}

/// Return `NOT_MULTI` if c is not a "multi" operator.
/// Return `MULTI_ONE` if c is a single "multi" operator.
/// Return `MULTI_MULT` if c is a multi "multi" operator.
#[no_mangle]
pub const extern "C" fn rs_re_multi_type(c: c_int) -> c_int {
    if c == magic(b'@') || c == magic(b'=') || c == magic(b'?') {
        MULTI_ONE
    } else if c == magic(b'*') || c == magic(b'+') || c == magic(b'{') {
        MULTI_MULT
    } else {
        NOT_MULTI
    }
}

/// Translate '\x' to its control character, except "\n", which is Magic.
#[no_mangle]
pub const extern "C" fn rs_backslash_trans(c: c_int) -> c_int {
    match c {
        0x72 => CAR_CH, // 'r'
        0x74 => TAB_CH, // 't'
        0x65 => ESC_CH, // 'e'
        0x62 => BS_CH,  // 'b'
        _ => c,
    }
}

// --- Class table (matching `regexp.c` `init_class_tab`) ---

const RI_DIGIT: i16 = 0x01;
const RI_HEX: i16 = 0x02;
const RI_OCTAL: i16 = 0x04;
const RI_WORD: i16 = 0x08;
const RI_HEAD: i16 = 0x10;
const RI_ALPHA: i16 = 0x20;
const RI_LOWER: i16 = 0x40;
const RI_UPPER: i16 = 0x80;
const RI_WHITE: i16 = 0x100;

/// Compile-time class table matching C `init_class_tab()`.
const CLASS_TAB: [i16; 256] = {
    let mut tab = [0i16; 256];
    let mut i = 0usize;
    while i < 256 {
        if i >= b'0' as usize && i <= b'7' as usize {
            tab[i] = RI_DIGIT + RI_HEX + RI_OCTAL + RI_WORD;
        } else if i >= b'8' as usize && i <= b'9' as usize {
            tab[i] = RI_DIGIT + RI_HEX + RI_WORD;
        } else if i >= b'a' as usize && i <= b'f' as usize {
            tab[i] = RI_HEX + RI_WORD + RI_HEAD + RI_ALPHA + RI_LOWER;
        } else if i >= b'g' as usize && i <= b'z' as usize {
            tab[i] = RI_WORD + RI_HEAD + RI_ALPHA + RI_LOWER;
        } else if i >= b'A' as usize && i <= b'F' as usize {
            tab[i] = RI_HEX + RI_WORD + RI_HEAD + RI_ALPHA + RI_UPPER;
        } else if i >= b'G' as usize && i <= b'Z' as usize {
            tab[i] = RI_WORD + RI_HEAD + RI_ALPHA + RI_UPPER;
        } else if i == b'_' as usize {
            tab[i] = RI_WORD + RI_HEAD;
        }
        i += 1;
    }
    tab[b' ' as usize] |= RI_WHITE;
    tab[b'\t' as usize] |= RI_WHITE;
    tab
};

/// Copy the class table into a C-provided buffer.
///
/// # Safety
///
/// `out` must point to a buffer of at least 256 `i16` elements.
#[no_mangle]
pub const unsafe extern "C" fn rs_init_class_tab(out: *mut i16) {
    std::ptr::copy_nonoverlapping(CLASS_TAB.as_ptr(), out, 256);
}

// --- re_multiline (opaque handle pattern) ---

/// `RF_HASNL` flag — regexp can match a newline.
const RF_HASNL: c_uint = 4;

/// Return non-zero if compiled regular expression `prog` can match a line break.
///
/// # Safety
///
/// `prog` must be a valid pointer to a `regprog_T`.
#[no_mangle]
pub unsafe extern "C" fn rs_re_multiline(prog: *const c_void) -> c_int {
    (nvim_regexp_get_regflags(prog) & RF_HASNL) as c_int
}

// --- Number parsers (pure-logic cores + FFI wrappers) ---

/// Check if a byte is an ASCII hex digit.
const fn is_xdigit(c: u8) -> bool {
    c.is_ascii_hexdigit()
}

/// Convert a hex digit character to its numeric value (0-15).
const fn hex2nr(c: u8) -> i64 {
    match c {
        b'0'..=b'9' => (c - b'0') as i64,
        b'a'..=b'f' => (c - b'a' + 10) as i64,
        b'A'..=b'F' => (c - b'A' + 10) as i64,
        _ => 0,
    }
}

/// Pure-logic hex parser: parse up to `maxinputlen` hex digits from `input`.
/// Returns `(value, bytes_consumed)` or `(-1, 0)` if no hex digits found.
fn gethexchrs_core(input: &[u8], maxinputlen: usize) -> (i64, usize) {
    let mut nr: i64 = 0;
    let mut i = 0;
    while i < maxinputlen && i < input.len() {
        let c = input[i];
        if !is_xdigit(c) {
            break;
        }
        nr <<= 4;
        nr |= hex2nr(c);
        i += 1;
    }
    if i == 0 {
        (-1, 0)
    } else {
        (nr, i)
    }
}

/// Pure-logic decimal parser: parse all consecutive decimal digits from `input`.
/// Returns `(value, bytes_consumed)` or `(-1, 0)` if no digits found.
fn getdecchrs_core(input: &[u8]) -> (i64, usize) {
    let mut nr: i64 = 0;
    let mut i = 0;
    while i < input.len() {
        let c = input[i];
        if !c.is_ascii_digit() {
            break;
        }
        nr *= 10;
        nr += (c - b'0') as i64;
        i += 1;
    }
    if i == 0 {
        (-1, 0)
    } else {
        (nr, i)
    }
}

/// Pure-logic octal parser: parse up to 3 octal digits, max value 255.
/// Returns `(value, bytes_consumed)` or `(-1, 0)` if no digits found.
fn getoctchrs_core(input: &[u8]) -> (i64, usize) {
    let mut nr: i64 = 0;
    let mut i = 0;
    // Match C: `for (i = 0; i < 3 && nr < 040; i++)`
    // 040 octal = 32 decimal
    while i < 3 && nr < 0o40 && i < input.len() {
        let c = input[i];
        if !(b'0'..=b'7').contains(&c) {
            break;
        }
        nr <<= 3;
        nr |= hex2nr(c);
        i += 1;
    }
    if i == 0 {
        (-1, 0)
    } else {
        (nr, i)
    }
}

/// FFI wrapper: get hex chars from regparse, advancing regparse.
#[no_mangle]
pub unsafe extern "C" fn rs_gethexchrs(maxinputlen: c_int) -> c_long {
    let regparse = nvim_regexp_get_regparse();
    let input = std::slice::from_raw_parts(regparse as *const u8, maxinputlen as usize + 1);
    // Find actual available length (up to NUL)
    let len = input.iter().position(|&b| b == 0).unwrap_or(input.len());
    let (nr, consumed) = gethexchrs_core(&input[..len], maxinputlen as usize);
    nvim_regexp_set_regparse(regparse.add(consumed));
    nr as c_long
}

/// FFI wrapper: get decimal chars from regparse, advancing regparse.
#[no_mangle]
pub unsafe extern "C" fn rs_getdecchrs() -> c_long {
    let regparse = nvim_regexp_get_regparse();
    // We need to scan forward; be generous with the slice length
    // Find NUL to bound the slice
    let mut len = 0;
    while *regparse.add(len) != 0 {
        len += 1;
        if len > 64 {
            break; // decimal numbers won't be this long
        }
    }
    let input = std::slice::from_raw_parts(regparse as *const u8, len);
    let (nr, consumed) = getdecchrs_core(input);
    nvim_regexp_set_regparse(regparse.add(consumed));
    // getdecchrs also sets curchr = -1 for each digit consumed
    if consumed > 0 {
        nvim_regexp_set_curchr(-1);
    }
    nr as c_long
}

/// FFI wrapper: get octal chars from regparse, advancing regparse.
#[no_mangle]
pub unsafe extern "C" fn rs_getoctchrs() -> c_long {
    let regparse = nvim_regexp_get_regparse();
    // Octal is at most 3 chars
    let mut len = 0;
    while len < 4 && *regparse.add(len) != 0 {
        len += 1;
    }
    let input = std::slice::from_raw_parts(regparse as *const u8, len);
    let (nr, consumed) = getoctchrs_core(input);
    nvim_regexp_set_regparse(regparse.add(consumed));
    nr as c_long
}

// --- State management: initchr, save/restore_parse_state ---

/// Matches C `parse_state_T` layout in `regexp.c`.
#[repr(C)]
pub struct ParseStateT {
    pub regparse: *mut c_char,
    pub prevchr_len: c_int,
    pub curchr: c_int,
    pub prevchr: c_int,
    pub prevprevchr: c_int,
    pub nextchr: c_int,
    pub at_start: c_int,
    pub prev_at_start: c_int,
    pub regnpar: c_int,
}

/// Start parsing at `str`. Sets regparse and resets all character state.
#[no_mangle]
pub unsafe extern "C" fn rs_initchr(str: *mut c_char) {
    nvim_regexp_set_regparse(str);
    nvim_regexp_set_prevchr_len(0);
    nvim_regexp_set_curchr(-1);
    nvim_regexp_set_prevprevchr(-1);
    nvim_regexp_set_prevchr(-1);
    nvim_regexp_set_nextchr(-1);
    nvim_regexp_set_at_start(1); // true
    nvim_regexp_set_prev_at_start(0); // false
}

/// Save the current parse state into `ps`.
#[no_mangle]
pub unsafe extern "C" fn rs_save_parse_state(ps: *mut ParseStateT) {
    (*ps).regparse = nvim_regexp_get_regparse();
    (*ps).prevchr_len = nvim_regexp_get_prevchr_len();
    (*ps).curchr = nvim_regexp_get_curchr();
    (*ps).prevchr = nvim_regexp_get_prevchr();
    (*ps).prevprevchr = nvim_regexp_get_prevprevchr();
    (*ps).nextchr = nvim_regexp_get_nextchr();
    (*ps).at_start = nvim_regexp_get_at_start();
    (*ps).prev_at_start = nvim_regexp_get_prev_at_start();
    (*ps).regnpar = nvim_regexp_get_regnpar();
}

/// Restore a previously saved parse state from `ps`.
#[no_mangle]
pub unsafe extern "C" fn rs_restore_parse_state(ps: *const ParseStateT) {
    nvim_regexp_set_regparse((*ps).regparse);
    nvim_regexp_set_prevchr_len((*ps).prevchr_len);
    nvim_regexp_set_curchr((*ps).curchr);
    nvim_regexp_set_prevchr((*ps).prevchr);
    nvim_regexp_set_prevprevchr((*ps).prevprevchr);
    nvim_regexp_set_nextchr((*ps).nextchr);
    nvim_regexp_set_at_start((*ps).at_start);
    nvim_regexp_set_prev_at_start((*ps).prev_at_start);
    nvim_regexp_set_regnpar((*ps).regnpar);
}

// --- Core scanner: peekchr, skipchr, skipchr_keepstart, getchr, ungetchr ---

/// `META_FLAGS` table — copied from regexp.c.
/// Index by ASCII value; nonzero means the character may be magic after `\`.
#[rustfmt::skip]
const META_FLAGS: [u8; 127] = [
    0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0,
    0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0,
//                 %  &     (  )  *  +        .
    0, 0, 0, 0, 0, 1, 1, 0, 1, 1, 1, 1, 0, 0, 1, 0,
//     1  2  3  4  5  6  7  8  9        <  =  >  ?
    0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 1, 1,
//  @  A     C  D     F     H  I     K  L  M     O
    1, 1, 0, 1, 1, 0, 1, 0, 1, 1, 0, 1, 1, 1, 0, 1,
//  P        S     U  V  W  X     Z  [           _
    1, 0, 0, 1, 0, 1, 1, 1, 1, 0, 1, 1, 0, 0, 0, 1,
//     a     c  d     f     h  i     k  l  m  n  o
    0, 1, 0, 1, 1, 0, 1, 0, 1, 1, 0, 1, 1, 1, 1, 1,
//  p        s     u  v  w  x     z  {  |     ~
    1, 0, 0, 1, 0, 1, 1, 1, 1, 0, 1, 1, 1, 0, 1,
];

/// Get the next character without advancing. Handles magic modes.
#[no_mangle]
#[allow(clippy::too_many_lines)]
pub unsafe extern "C" fn rs_peekchr() -> c_int {
    let mut curchr = nvim_regexp_get_curchr();
    if curchr != -1 {
        return curchr;
    }

    let regparse = nvim_regexp_get_regparse();
    let reg_magic = nvim_regexp_get_reg_magic();
    let at_start = nvim_regexp_get_at_start();
    let prev_at_start = nvim_regexp_get_prev_at_start();
    let prevchr = nvim_regexp_get_prevchr();
    let prevprevchr = nvim_regexp_get_prevprevchr();
    let after_slash = nvim_regexp_get_after_slash();

    curchr = *regparse as u8 as c_int;
    #[allow(clippy::cast_possible_truncation)]
    let c_byte = curchr as u8; // safe: came from u8 read above

    match c_byte {
        b'.' | b'[' | b'~' => {
            if reg_magic >= MAGIC_ON {
                curchr = magic(c_byte);
            }
        }
        b'(' | b')' | b'{' | b'%' | b'+' | b'=' | b'?' | b'@' | b'!' | b'&' | b'|' | b'<'
        | b'>' | b'#' | b'"' | b'\'' | b',' | b'-' | b':' | b';' | b'`' | b'/' => {
            if reg_magic == MAGIC_ALL {
                curchr = magic(c_byte);
            }
        }
        b'*' => {
            if reg_magic >= MAGIC_ON
                && at_start == 0
                && !(prev_at_start != 0 && prevchr == magic(b'^'))
                && (after_slash != 0
                    || (prevchr != magic(b'(') && prevchr != magic(b'&') && prevchr != magic(b'|')))
            {
                curchr = magic(b'*');
            }
        }
        b'^' => {
            if reg_magic >= MAGIC_OFF
                && (at_start != 0
                    || reg_magic == MAGIC_ALL
                    || prevchr == magic(b'(')
                    || prevchr == magic(b'|')
                    || prevchr == magic(b'&')
                    || prevchr == magic(b'n')
                    || (rs_no_magic(prevchr) == b'(' as c_int && prevprevchr == magic(b'%')))
            {
                curchr = magic(b'^');
                nvim_regexp_set_at_start(1);
                nvim_regexp_set_prev_at_start(0);
            }
        }
        b'$' => {
            if reg_magic >= MAGIC_OFF {
                let mut p = regparse.add(1) as *const u8;
                let mut is_magic_all = reg_magic == MAGIC_ALL;

                // ignore \c \C \m \M \v \V and \Z after '$'
                while *p == b'\\'
                    && matches!(*p.add(1), b'c' | b'C' | b'm' | b'M' | b'v' | b'V' | b'Z')
                {
                    if *p.add(1) == b'v' {
                        is_magic_all = true;
                    } else if matches!(*p.add(1), b'm' | b'M' | b'V') {
                        is_magic_all = false;
                    }
                    p = p.add(2);
                }
                if *p == 0
                    || (*p == b'\\' && matches!(*p.add(1), b'|' | b'&' | b')' | b'n'))
                    || (is_magic_all && matches!(*p, b'|' | b'&' | b')'))
                    || reg_magic == MAGIC_ALL
                {
                    curchr = magic(b'$');
                }
            }
        }
        b'\\' => {
            let c = *regparse.add(1) as u8;

            if c == 0 {
                curchr = b'\\' as c_int; // trailing '\'
            } else if c <= b'~' && META_FLAGS[c as usize] != 0 {
                // META character after '\' — toggle magicness via recursive call
                nvim_regexp_set_curchr(-1);
                nvim_regexp_set_prev_at_start(nvim_regexp_get_at_start());
                nvim_regexp_set_at_start(0); // be able to say "/\*ptr"
                nvim_regexp_set_regparse(regparse.add(1));
                nvim_regexp_set_after_slash(after_slash + 1);
                rs_peekchr();
                nvim_regexp_set_regparse(regparse);
                nvim_regexp_set_after_slash(after_slash);
                curchr = rs_toggle_magic(nvim_regexp_get_curchr());
            } else if REGEXP_ABBR.contains(&c) {
                // Handle abbreviations, like "\t" for TAB
                curchr = rs_backslash_trans(c as c_int);
            } else if reg_magic == MAGIC_NONE && (c == b'$' || c == b'^') {
                curchr = rs_toggle_magic(c as c_int);
            } else {
                // Next character can never be (made) magic?
                curchr = utf_ptr2char(regparse.add(1));
            }
        }
        _ => {
            curchr = utf_ptr2char(regparse);
        }
    }

    nvim_regexp_set_curchr(curchr);
    curchr
}

/// Eat one lexed character. Advances regparse and updates character state.
#[no_mangle]
pub unsafe extern "C" fn rs_skipchr() {
    let regparse = nvim_regexp_get_regparse();
    // peekchr() eats a backslash, do the same here
    let mut prevchr_len = c_int::from(*regparse == b'\\' as c_char);
    if *regparse.add(prevchr_len as usize) != 0 {
        // Exclude composing chars that utfc_ptr2len does include.
        prevchr_len += utf_ptr2len(regparse.add(prevchr_len as usize));
    }
    nvim_regexp_set_regparse(regparse.add(prevchr_len as usize));
    nvim_regexp_set_prevchr_len(prevchr_len);
    nvim_regexp_set_prev_at_start(nvim_regexp_get_at_start());
    nvim_regexp_set_at_start(0);
    nvim_regexp_set_prevprevchr(nvim_regexp_get_prevchr());
    nvim_regexp_set_prevchr(nvim_regexp_get_curchr());
    nvim_regexp_set_curchr(nvim_regexp_get_nextchr()); // use previously unget char, or -1
    nvim_regexp_set_nextchr(-1);
}

/// Skip a character while keeping `prev_at_start`, `prevchr`, `prevprevchr`.
#[no_mangle]
pub unsafe extern "C" fn rs_skipchr_keepstart() {
    let saved_as = nvim_regexp_get_prev_at_start();
    let saved_pr = nvim_regexp_get_prevchr();
    let saved_prpr = nvim_regexp_get_prevprevchr();

    rs_skipchr();

    nvim_regexp_set_at_start(saved_as);
    nvim_regexp_set_prevchr(saved_pr);
    nvim_regexp_set_prevprevchr(saved_prpr);
}

/// Get the next character and advance past it.
#[no_mangle]
pub unsafe extern "C" fn rs_getchr() -> c_int {
    let chr = rs_peekchr();
    rs_skipchr();
    chr
}

/// Put character back. Works only once!
#[no_mangle]
pub unsafe extern "C" fn rs_ungetchr() {
    nvim_regexp_set_nextchr(nvim_regexp_get_curchr());
    nvim_regexp_set_curchr(nvim_regexp_get_prevchr());
    nvim_regexp_set_prevchr(nvim_regexp_get_prevprevchr());
    nvim_regexp_set_at_start(nvim_regexp_get_prev_at_start());
    nvim_regexp_set_prev_at_start(0);

    // Backup regparse by prevchr_len
    let regparse = nvim_regexp_get_regparse();
    let prevchr_len = nvim_regexp_get_prevchr_len();
    nvim_regexp_set_regparse(regparse.sub(prevchr_len as usize));
}

// --- Limit parser: read_limits ---

/// Maximum limit value for `\{n,m}` ranges.
const MAX_LIMIT: c_int = 32767 << 16;

/// OK return code matching C definition.
const OK: c_int = 1;

/// Parse `\{n,m}` range limits. On success writes to `*minval` and `*maxval`
/// and returns `OK`; on syntax error emits a message and returns `FAIL`.
#[no_mangle]
pub unsafe extern "C" fn rs_read_limits(minval: *mut c_int, maxval: *mut c_int) -> c_int {
    let mut regparse = nvim_regexp_get_regparse();

    let reverse = if *regparse == b'-' as c_char {
        regparse = regparse.add(1);
        true
    } else {
        false
    };
    let first_char = regparse;
    *minval = getdigits_int(&mut regparse, false, 0);
    if *regparse == b',' as c_char {
        regparse = regparse.add(1);
        if (*regparse as u8).is_ascii_digit() {
            *maxval = getdigits_int(&mut regparse, false, MAX_LIMIT);
        } else {
            *maxval = MAX_LIMIT;
        }
    } else if (*first_char as u8).is_ascii_digit() {
        *maxval = *minval; // It was \{n} or \{-n}
    } else {
        *maxval = MAX_LIMIT; // It was \{} or \{-}
    }
    if *regparse == b'\\' as c_char {
        regparse = regparse.add(1); // Allow either \{...} or \{...\}
    }
    if *regparse as u8 != b'}' {
        nvim_regexp_set_regparse(regparse);
        return nvim_regexp_emsg2_fail(
            c"E554: Syntax error in %s{...}".as_ptr(),
            c_int::from(nvim_regexp_get_reg_magic() == MAGIC_ALL),
        );
    }

    // Reverse the range if there was a '-', or make sure it is in the right
    // order otherwise.
    if (!reverse && *minval > *maxval) || (reverse && *minval < *maxval) {
        core::ptr::swap(minval, maxval);
    }
    nvim_regexp_set_regparse(regparse);
    rs_skipchr(); // let's be friends with the lexer again
    OK
}

// --- Hebrew decomposition table (0xfb20..=0xfb4f) ---

/// Decomposition entry: base character + up to 2 combining marks.
struct DecompEntry {
    a: c_int,
    b: c_int,
    c: c_int,
}

#[rustfmt::skip]
const DECOMP_TABLE: [DecompEntry; 0xfb4f - 0xfb20 + 1] = [
    DecompEntry { a: 0x5e2, b: 0,     c: 0 },      // 0xfb20  alt ayin
    DecompEntry { a: 0x5d0, b: 0,     c: 0 },      // 0xfb21  alt alef
    DecompEntry { a: 0x5d3, b: 0,     c: 0 },      // 0xfb22  alt dalet
    DecompEntry { a: 0x5d4, b: 0,     c: 0 },      // 0xfb23  alt he
    DecompEntry { a: 0x5db, b: 0,     c: 0 },      // 0xfb24  alt kaf
    DecompEntry { a: 0x5dc, b: 0,     c: 0 },      // 0xfb25  alt lamed
    DecompEntry { a: 0x5dd, b: 0,     c: 0 },      // 0xfb26  alt mem-sofit
    DecompEntry { a: 0x5e8, b: 0,     c: 0 },      // 0xfb27  alt resh
    DecompEntry { a: 0x5ea, b: 0,     c: 0 },      // 0xfb28  alt tav
    DecompEntry { a: b'+' as c_int, b: 0, c: 0 },   // 0xfb29  alt plus
    DecompEntry { a: 0x5e9, b: 0x5c1, c: 0 },      // 0xfb2a  shin+shin-dot
    DecompEntry { a: 0x5e9, b: 0x5c2, c: 0 },      // 0xfb2b  shin+sin-dot
    DecompEntry { a: 0x5e9, b: 0x5c1, c: 0x5bc },  // 0xfb2c  shin+shin-dot+dagesh
    DecompEntry { a: 0x5e9, b: 0x5c2, c: 0x5bc },  // 0xfb2d  shin+sin-dot+dagesh
    DecompEntry { a: 0x5d0, b: 0x5b7, c: 0 },      // 0xfb2e  alef+patah
    DecompEntry { a: 0x5d0, b: 0x5b8, c: 0 },      // 0xfb2f  alef+qamats
    DecompEntry { a: 0x5d0, b: 0x5b4, c: 0 },      // 0xfb30  alef+hiriq
    DecompEntry { a: 0x5d1, b: 0x5bc, c: 0 },      // 0xfb31  bet+dagesh
    DecompEntry { a: 0x5d2, b: 0x5bc, c: 0 },      // 0xfb32  gimel+dagesh
    DecompEntry { a: 0x5d3, b: 0x5bc, c: 0 },      // 0xfb33  dalet+dagesh
    DecompEntry { a: 0x5d4, b: 0x5bc, c: 0 },      // 0xfb34  he+dagesh
    DecompEntry { a: 0x5d5, b: 0x5bc, c: 0 },      // 0xfb35  vav+dagesh
    DecompEntry { a: 0x5d6, b: 0x5bc, c: 0 },      // 0xfb36  zayin+dagesh
    DecompEntry { a: 0xfb37, b: 0,    c: 0 },      // 0xfb37  -- UNUSED
    DecompEntry { a: 0x5d8, b: 0x5bc, c: 0 },      // 0xfb38  tet+dagesh
    DecompEntry { a: 0x5d9, b: 0x5bc, c: 0 },      // 0xfb39  yud+dagesh
    DecompEntry { a: 0x5da, b: 0x5bc, c: 0 },      // 0xfb3a  kaf sofit+dagesh
    DecompEntry { a: 0x5db, b: 0x5bc, c: 0 },      // 0xfb3b  kaf+dagesh
    DecompEntry { a: 0x5dc, b: 0x5bc, c: 0 },      // 0xfb3c  lamed+dagesh
    DecompEntry { a: 0xfb3d, b: 0,    c: 0 },      // 0xfb3d  -- UNUSED
    DecompEntry { a: 0x5de, b: 0x5bc, c: 0 },      // 0xfb3e  mem+dagesh
    DecompEntry { a: 0xfb3f, b: 0,    c: 0 },      // 0xfb3f  -- UNUSED
    DecompEntry { a: 0x5e0, b: 0x5bc, c: 0 },      // 0xfb40  nun+dagesh
    DecompEntry { a: 0x5e1, b: 0x5bc, c: 0 },      // 0xfb41  samech+dagesh
    DecompEntry { a: 0xfb42, b: 0,    c: 0 },      // 0xfb42  -- UNUSED
    DecompEntry { a: 0x5e3, b: 0x5bc, c: 0 },      // 0xfb43  pe sofit+dagesh
    DecompEntry { a: 0x5e4, b: 0x5bc, c: 0 },      // 0xfb44  pe+dagesh
    DecompEntry { a: 0xfb45, b: 0,    c: 0 },      // 0xfb45  -- UNUSED
    DecompEntry { a: 0x5e6, b: 0x5bc, c: 0 },      // 0xfb46  tsadi+dagesh
    DecompEntry { a: 0x5e7, b: 0x5bc, c: 0 },      // 0xfb47  qof+dagesh
    DecompEntry { a: 0x5e8, b: 0x5bc, c: 0 },      // 0xfb48  resh+dagesh
    DecompEntry { a: 0x5e9, b: 0x5bc, c: 0 },      // 0xfb49  shin+dagesh
    DecompEntry { a: 0x5ea, b: 0x5bc, c: 0 },      // 0xfb4a  tav+dagesh
    DecompEntry { a: 0x5d5, b: 0x5b9, c: 0 },      // 0xfb4b  vav+holam
    DecompEntry { a: 0x5d1, b: 0x5bf, c: 0 },      // 0xfb4c  bet+rafe
    DecompEntry { a: 0x5db, b: 0x5bf, c: 0 },      // 0xfb4d  kaf+rafe
    DecompEntry { a: 0x5e4, b: 0x5bf, c: 0 },      // 0xfb4e  pe+rafe
    DecompEntry { a: 0x5d0, b: 0x5dc, c: 0 },      // 0xfb4f  alef-lamed
];

/// Decompose a Hebrew presentation form character into base + combining marks.
#[allow(clippy::manual_range_contains)]
const fn mb_decompose(ch: c_int, c1: &mut c_int, c2: &mut c_int, c3: &mut c_int) {
    if ch >= 0xfb20 && ch <= 0xfb4f {
        let d = &DECOMP_TABLE[(ch - 0xfb20) as usize];
        *c1 = d.a;
        *c2 = d.b;
        *c3 = d.c;
    } else {
        *c1 = ch;
        *c2 = 0;
        *c3 = 0;
    }
}

// --- Case-insensitive operations: cstrncmp, cstrchr ---

/// Compare two strings, strncmp-like, with optional case-folding.
///
/// If `rex.reg_ic` is set, compare case-insensitively. `*n` may be adjusted
/// downward if s2 is shorter (measured in characters) than the byte-length
/// specified.
///
/// If `rex.reg_icombine` is set and the comparison fails, retry by
/// decomposing characters and comparing base characters only.
///
/// Returns 0 for match, nonzero for mismatch.
#[no_mangle]
#[allow(clippy::too_many_lines, clippy::cast_possible_truncation)]
pub unsafe extern "C" fn rs_cstrncmp(s1: *mut c_char, s2: *mut c_char, n: *mut c_int) -> c_int {
    let result;

    if nvim_regexp_get_rex_reg_ic() == 0 {
        // Case-sensitive compare
        result = strncmp(s1, s2, *n as usize);
    } else {
        // Case-insensitive: count characters for byte-length of s1
        let mut p = s1;
        let mut n2 = 0_i32;
        let mut n1 = *n;
        while n1 > 0 && *p != 0 {
            n1 -= utfc_ptr2len(s1);
            p = p.add(utfc_ptr2len(p) as usize); // MB_PTR_ADV
            n2 += 1;
        }
        // Count bytes to advance the same number of chars for s2
        p = s2;
        while n2 > 0 && *p != 0 {
            p = p.add(utfc_ptr2len(p) as usize); // MB_PTR_ADV
            n2 -= 1;
        }

        n2 = p.offset_from(s2) as c_int;

        result = utf_strnicmp(s1, s2, *n as usize, n2 as usize);
        if result == 0 && n2 < *n {
            *n = n2;
        }
    }

    // If it failed and it's utf8 and we want to combineignore:
    if result != 0 && nvim_regexp_get_rex_reg_icombine() != 0 {
        let mut str1: *const c_char = s1;
        let mut str2: *const c_char = s2;
        let mut c1;
        let mut c2;

        loop {
            if (str1 as usize - s1 as usize) as c_int >= *n {
                // Reached the end — match
                *n = (str2 as usize - s2 as usize) as c_int;
                return 0;
            }
            c1 = mb_ptr2char_adv(&mut str1);
            c2 = mb_ptr2char_adv(&mut str2);

            if c1 != c2 && (nvim_regexp_get_rex_reg_ic() == 0 || utf_fold(c1) != utf_fold(c2)) {
                // Decomposition necessary?
                let mut c11: c_int = 0;
                let mut c12: c_int = 0;
                let mut junk1: c_int = 0;
                let mut junk2: c_int = 0;
                mb_decompose(c1, &mut c11, &mut junk1, &mut junk2);
                mb_decompose(c2, &mut c12, &mut junk1, &mut junk2);
                c1 = c11;
                c2 = c12;
                if c11 != c12
                    && (nvim_regexp_get_rex_reg_ic() == 0 || utf_fold(c11) != utf_fold(c12))
                {
                    break;
                }
            }
        }
        return c2 - c1;
    }

    result
}

/// Search for character `c` in string `s`, with optional case-insensitivity.
///
/// When `rex.reg_ic` is set, searches case-insensitively.
/// Returns `NULL` if no match, otherwise pointer to the position in `s`.
#[no_mangle]
pub unsafe extern "C" fn rs_cstrchr(s: *const c_char, c: c_int) -> *mut c_char {
    if nvim_regexp_get_rex_reg_ic() == 0 {
        return vim_strchr(s, c);
    }

    let cc: c_int;
    let lc: c_int;
    if c > 0x80 {
        let folded = utf_fold(c);
        cc = folded;
        lc = folded;
    } else if c >= b'A' as c_int && c <= b'Z' as c_int {
        // ASCII_ISUPPER
        cc = c + (b'a' - b'A') as c_int; // TOLOWER_ASC
        lc = cc;
    } else if c >= b'a' as c_int && c <= b'z' as c_int {
        // ASCII_ISLOWER
        cc = c - (b'a' - b'A') as c_int; // TOUPPER_ASC
        lc = c;
    } else {
        return vim_strchr(s, c);
    }

    let mut p = s;
    while *p != 0 {
        let uc = utf_ptr2char(p);
        if c > 0x80 || uc > 0x80 {
            // Do not match an illegal byte. E.g. 0xff matches 0xc3 0xbf, not 0xff.
            // Compare with lower case of the character.
            if (uc < 0x80 || uc != *p as u8 as c_int) && utf_fold(uc) == lc {
                return p.cast_mut();
            }
        } else if *p as u8 as c_int == c || *p as u8 as c_int == cc {
            return p.cast_mut();
        }
        p = p.add(utfc_ptr2len(p) as usize);
    }

    std::ptr::null_mut()
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn test_no_magic_positive() {
        // Positive values pass through
        assert_eq!(rs_no_magic(0), 0);
        assert_eq!(rs_no_magic(65), 65); // 'A'
        assert_eq!(rs_no_magic(255), 255);
    }

    #[test]
    fn test_no_magic_negative() {
        // Negative (magic) values get un-magicked: x + 256
        assert_eq!(rs_no_magic(-1), 255);
        assert_eq!(rs_no_magic(-192), 64); // Magic('@') -> '@'
        assert_eq!(rs_no_magic(-256), 0);
    }

    #[test]
    fn test_no_magic_boundary() {
        // At the boundary
        assert_eq!(rs_no_magic(-1), 255);
        assert_eq!(rs_no_magic(0), 0);
    }

    #[test]
    fn test_toggle_magic_positive() {
        // Positive (non-magic) -> subtract 256
        assert_eq!(rs_toggle_magic(65), 65 - 256); // 'A' -> Magic('A')
        assert_eq!(rs_toggle_magic(0), -256);
    }

    #[test]
    fn test_toggle_magic_negative() {
        // Negative (magic) -> add 256
        assert_eq!(rs_toggle_magic(-192), 64); // Magic('@') -> '@'
        assert_eq!(rs_toggle_magic(-1), 255);
    }

    #[test]
    fn test_toggle_magic_roundtrip() {
        // toggle(toggle(x)) == x for values in the valid Magic range.
        // Magic chars are in [-256, 0) and plain chars in [0, 256).
        for x in -256..256 {
            assert_eq!(rs_toggle_magic(rs_toggle_magic(x)), x);
        }
    }

    #[test]
    fn test_re_multi_type_one() {
        assert_eq!(rs_re_multi_type(magic(b'@')), MULTI_ONE);
        assert_eq!(rs_re_multi_type(magic(b'=')), MULTI_ONE);
        assert_eq!(rs_re_multi_type(magic(b'?')), MULTI_ONE);
    }

    #[test]
    fn test_re_multi_type_mult() {
        assert_eq!(rs_re_multi_type(magic(b'*')), MULTI_MULT);
        assert_eq!(rs_re_multi_type(magic(b'+')), MULTI_MULT);
        assert_eq!(rs_re_multi_type(magic(b'{')), MULTI_MULT);
    }

    #[test]
    fn test_re_multi_type_not() {
        assert_eq!(rs_re_multi_type(0), NOT_MULTI);
        assert_eq!(rs_re_multi_type(65), NOT_MULTI); // 'A'
        assert_eq!(rs_re_multi_type(magic(b'a')), NOT_MULTI);
        assert_eq!(rs_re_multi_type(-1), NOT_MULTI);
    }

    #[test]
    fn test_backslash_trans_escapes() {
        assert_eq!(rs_backslash_trans(b'r' as c_int), CAR_CH);
        assert_eq!(rs_backslash_trans(b't' as c_int), TAB_CH);
        assert_eq!(rs_backslash_trans(b'e' as c_int), ESC_CH);
        assert_eq!(rs_backslash_trans(b'b' as c_int), BS_CH);
    }

    #[test]
    fn test_backslash_trans_passthrough() {
        assert_eq!(rs_backslash_trans(b'n' as c_int), b'n' as c_int);
        assert_eq!(rs_backslash_trans(b'a' as c_int), b'a' as c_int);
        assert_eq!(rs_backslash_trans(0), 0);
        assert_eq!(rs_backslash_trans(255), 255);
    }

    // --- CLASS_TAB tests ---

    #[test]
    fn test_class_tab_digits() {
        // 0-7 have DIGIT + HEX + OCTAL + WORD
        for c in b'0'..=b'7' {
            let v = CLASS_TAB[c as usize];
            assert!(v & RI_DIGIT != 0, "digit {c}");
            assert!(v & RI_HEX != 0, "hex {c}");
            assert!(v & RI_OCTAL != 0, "octal {c}");
            assert!(v & RI_WORD != 0, "word {c}");
        }
        // 8-9 have DIGIT + HEX + WORD but NOT OCTAL
        for c in b'8'..=b'9' {
            let v = CLASS_TAB[c as usize];
            assert!(v & RI_DIGIT != 0);
            assert!(v & RI_HEX != 0);
            assert!(v & RI_OCTAL == 0, "8-9 should not be OCTAL");
            assert!(v & RI_WORD != 0);
        }
    }

    #[test]
    fn test_class_tab_hex() {
        // a-f have HEX
        for c in b'a'..=b'f' {
            assert!(CLASS_TAB[c as usize] & RI_HEX != 0);
        }
        // A-F have HEX
        for c in b'A'..=b'F' {
            assert!(CLASS_TAB[c as usize] & RI_HEX != 0);
        }
        // g-z, G-Z do NOT have HEX
        for c in b'g'..=b'z' {
            assert!(CLASS_TAB[c as usize] & RI_HEX == 0);
        }
        for c in b'G'..=b'Z' {
            assert!(CLASS_TAB[c as usize] & RI_HEX == 0);
        }
    }

    #[test]
    fn test_class_tab_alpha() {
        for c in b'a'..=b'z' {
            let v = CLASS_TAB[c as usize];
            assert!(v & RI_ALPHA != 0);
            assert!(v & RI_LOWER != 0);
            assert!(v & RI_UPPER == 0);
        }
        for c in b'A'..=b'Z' {
            let v = CLASS_TAB[c as usize];
            assert!(v & RI_ALPHA != 0);
            assert!(v & RI_UPPER != 0);
            assert!(v & RI_LOWER == 0);
        }
    }

    #[test]
    fn test_class_tab_underscore() {
        let v = CLASS_TAB[b'_' as usize];
        assert!(v & RI_WORD != 0);
        assert!(v & RI_HEAD != 0);
        assert!(v & RI_ALPHA == 0, "underscore is not ALPHA");
    }

    #[test]
    fn test_class_tab_white() {
        assert!(CLASS_TAB[b' ' as usize] & RI_WHITE != 0);
        assert!(CLASS_TAB[b'\t' as usize] & RI_WHITE != 0);
    }

    #[test]
    fn test_class_tab_zero() {
        // NUL and other non-matching chars
        assert_eq!(CLASS_TAB[0], 0);
        assert_eq!(CLASS_TAB[1], 0);
        assert_eq!(CLASS_TAB[b'!' as usize], 0);
        assert_eq!(CLASS_TAB[b'@' as usize], 0);
    }

    // --- Number parser tests ---

    #[test]
    fn test_gethexchrs_basic() {
        assert_eq!(gethexchrs_core(b"20", 2), (0x20, 2));
        assert_eq!(gethexchrs_core(b"ff", 2), (0xff, 2));
        assert_eq!(gethexchrs_core(b"FF", 2), (0xFF, 2));
        assert_eq!(gethexchrs_core(b"0a", 2), (0x0a, 2));
        assert_eq!(gethexchrs_core(b"20AC", 4), (0x20AC, 4));
    }

    #[test]
    fn test_gethexchrs_empty() {
        assert_eq!(gethexchrs_core(b"", 2), (-1, 0));
        assert_eq!(gethexchrs_core(b"gg", 2), (-1, 0));
        assert_eq!(gethexchrs_core(b"xyz", 4), (-1, 0));
    }

    #[test]
    fn test_gethexchrs_max_clipping() {
        // maxinputlen=2 should only consume 2 hex chars
        assert_eq!(gethexchrs_core(b"20AC", 2), (0x20, 2));
        // maxinputlen=4 consumes all 4
        assert_eq!(gethexchrs_core(b"20AC", 4), (0x20AC, 4));
    }

    #[test]
    fn test_gethexchrs_partial() {
        // Non-hex char stops parsing
        assert_eq!(gethexchrs_core(b"2g", 2), (0x2, 1));
        assert_eq!(gethexchrs_core(b"a_", 4), (0xa, 1));
    }

    #[test]
    fn test_gethexchrs_8digit() {
        assert_eq!(gethexchrs_core(b"12345678", 8), (0x1234_5678, 8));
    }

    #[test]
    fn test_getdecchrs_basic() {
        assert_eq!(getdecchrs_core(b"123"), (123, 3));
        assert_eq!(getdecchrs_core(b"0"), (0, 1));
        assert_eq!(getdecchrs_core(b"42rest"), (42, 2));
    }

    #[test]
    fn test_getdecchrs_empty() {
        assert_eq!(getdecchrs_core(b""), (-1, 0));
        assert_eq!(getdecchrs_core(b"abc"), (-1, 0));
    }

    #[test]
    fn test_getdecchrs_large() {
        assert_eq!(getdecchrs_core(b"999999"), (999_999, 6));
    }

    #[test]
    fn test_getoctchrs_basic() {
        assert_eq!(getoctchrs_core(b"377"), (0xFF, 3)); // 255
        assert_eq!(getoctchrs_core(b"210"), (0o210, 3)); // 136
        assert_eq!(getoctchrs_core(b"0"), (0, 1));
        assert_eq!(getoctchrs_core(b"7"), (7, 1));
    }

    #[test]
    fn test_getoctchrs_empty() {
        assert_eq!(getoctchrs_core(b""), (-1, 0));
        assert_eq!(getoctchrs_core(b"8"), (-1, 0));
        assert_eq!(getoctchrs_core(b"9"), (-1, 0));
    }

    #[test]
    fn test_getoctchrs_truncation() {
        // "400" — first two digits "40" = 0o40 = 32 >= 0o40, so loop stops after 2
        assert_eq!(getoctchrs_core(b"400"), (0o40, 2));
        // "37" = 31 < 32, so third char would be processed if available
        assert_eq!(getoctchrs_core(b"370"), (0o370, 3)); // 248
    }

    #[test]
    fn test_getoctchrs_max3() {
        // At most 3 octal digits consumed
        assert_eq!(getoctchrs_core(b"1234"), (0o123, 3));
    }
}
