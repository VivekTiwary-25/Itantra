package com.chmod777.itantra

import java.text.Normalizer

/**
 * Text normalisation for the Meta MMS Bengali voice, whose character vocabulary silently drops
 * anything it does not contain. Only two transformations are applied, both meaning-preserving:
 *
 * 1. Digit runs (Bengali ০-৯ or ASCII 0-9) become Bengali cardinal words, attached in place so a
 *    classifier stays joined (১২টি -> বারোটি). MMS drops Bengali digits and mis-speaks ASCII digits
 *    (an ASCII "12" was heard as "two"), so neither may reach the model. Runs of up to nine digits
 *    without a leading zero are read as one number (Indian grouping: হাজার, লাখ, কোটি); longer runs
 *    and runs with a leading zero (phone numbers, codes) are read digit by digit.
 * 2. Unicode NFC, which rewrites the precomposed ড় ঢ় য় (U+09DC/09DD/09DF, absent from the
 *    vocabulary) as base letter + nukta (both present). It is a canonical equivalence.
 *
 * Words and the grouping rules come from AI4Bharat indic-numtowords 1.1.0 (MIT, ben/data/nums.py),
 * first listed variant only. The danda is deliberately left alone: the model drops it, and splitting
 * sentences there measured slightly worse. Commas and decimal points inside numbers are not handled.
 */
object BengaliTextNormalizer {

    fun normalize(text: String): String {
        val expanded = DIGIT_RUN.replace(text) { verbalize(toAsciiDigits(it.value)) }
        return Normalizer.normalize(expanded, Normalizer.Form.NFC)
    }

    internal fun verbalize(digits: String): String {
        if (digits.length > MAX_CARDINAL_DIGITS || (digits.length > 1 && digits[0] == '0')) {
            return digits.map { UNITS[it - '0'] }.joinToString(" ")
        }
        var rest = digits.trimStart('0')
        if (rest.isEmpty()) return UNITS[0]
        val words = ArrayList<String>()
        for ((minLen, scale) in SCALES) {
            if (rest.length >= minLen) {
                val head = rest.substring(0, rest.length - (minLen - 1))
                words += UNITS[head.toInt()]
                words += scale
                rest = rest.substring(head.length).trimStart('0')
            }
        }
        if (rest.length == 3) {
            words += HUNDREDS[rest[0] - '0']
            rest = rest.substring(1).trimStart('0')
        }
        if (rest.isNotEmpty()) words += UNITS[rest.toInt()]
        return words.joinToString(" ")
    }

    private fun toAsciiDigits(run: String): String =
        run.map { if (it in '০'..'৯') '0' + (it - '০') else it }.joinToString("")

    private val DIGIT_RUN = Regex("[0-9০-৯]+")
    private const val MAX_CARDINAL_DIGITS = 9

    // (minimum run length that reaches this scale, scale word): crore 10^7, lakh 10^5, thousand 10^3.
    private val SCALES = listOf(8 to "কোটি", 6 to "লাখ", 4 to "হাজার")

    private val UNITS = arrayOf(
        "শূন্য", "এক", "দুই", "তিন", "চার", "পাঁচ", "ছয়", "সাত", "আট", "নয়",
        "দশ", "এগারো", "বারো", "তেরো", "চৌদ্দ", "পনেরো", "ষোল", "সতেরো", "আঠারো", "ঊনিশ",
        "বিশ", "একুশ", "বাইশ", "তেইশ", "চব্বিশ", "পঁচিশ", "ছাব্বিশ", "সাতাশ", "আঠাশ", "ঊনত্রিশ",
        "ত্রিশ", "একত্রিশ", "বত্রিশ", "তেত্রিশ", "চৌত্রিশ", "পঁয়ত্রিশ", "ছত্রিশ", "সাঁইত্রিশ", "আটত্রিশ", "ঊনচল্লিশ",
        "চল্লিশ", "একচল্লিশ", "বিয়াল্লিশ", "তেতাল্লিশ", "চুয়াল্লিশ", "পঁয়তাল্লিশ", "ছেচল্লিশ", "সাতচল্লিশ", "আটচল্লিশ", "ঊনপঞ্চাশ",
        "পঞ্চাশ", "একান্ন", "বাহান্ন", "তিপ্পান্ন", "চুয়ান্ন", "পঞ্চান্ন", "ছাপ্পান্ন", "সাতান্ন", "আটান্ন", "ঊনষাট",
        "ষাট", "একষট্টি", "বাষট্টি", "তেষট্টি", "চৌষট্টি", "পঁয়ষট্টি", "ছেষট্টি", "সাতষট্টি", "আটষট্টি", "ঊনসত্তর",
        "সত্তর", "একাত্তর", "বাহাত্তর", "তিয়াত্তর", "চুয়াত্তর", "পঁচাত্তর", "ছিয়াত্তর", "সাতাত্তর", "আটাত্তর", "ঊনআশি",
        "আশি", "একাশি", "বিরাশি", "তিরাশি", "চুরাশি", "পঁচাশি", "ছিয়াশি", "সাতাশি", "অষ্টআশি", "ঊননব্বই",
        "নব্বই", "একানব্বই", "বিরানব্বই", "তিরানব্বই", "চুরানব্বই", "পঁচানব্বই", "ছিয়ানব্বই", "সাতানব্বই", "আটানব্বই", "নিরানব্বই"
    )
    private val HUNDREDS = arrayOf("", "একশো", "দুশো", "তিনশো", "চারশো", "পাঁচশো", "ছশো", "সাতশো", "আটশো", "নশো")
}
