/*
 * Copyright 2026-2027 Angel Conde and the vecruntime contributors
 *
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 *     http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 */
package io.vecruntime.spark.adapter;

import java.lang.foreign.Arena;
import java.lang.foreign.MemorySegment;
import java.lang.foreign.ValueLayout;
import java.lang.invoke.MethodHandles;
import java.lang.invoke.VarHandle;
import java.lang.reflect.Field;
import java.nio.ByteBuffer;
import java.nio.ByteOrder;
import java.util.Arrays;

import io.vecruntime.kernels.ArrowLayout;
import io.vecruntime.kernels.Bitmap;
import io.vecruntime.kernels.Decimal128;
import io.vecruntime.kernels.SegmentVectorBuffers;
import io.vecruntime.kernels.VecType;
import io.vecruntime.kernels.VectorBuffers;
import org.apache.spark.sql.execution.vectorized.Dictionary;
import org.apache.spark.sql.execution.vectorized.OffHeapColumnVector;
import org.apache.spark.sql.execution.vectorized.OnHeapColumnVector;
import org.apache.spark.sql.execution.vectorized.WritableColumnVector;
import org.apache.spark.sql.types.ByteType;
import org.apache.spark.sql.types.Decimal;
import org.apache.spark.sql.types.DecimalType;
import org.apache.spark.sql.types.ShortType;
import org.apache.spark.sql.vectorized.ColumnVector;
import org.apache.spark.unsafe.types.UTF8String;

/**
 * Adapts a Spark {@link ColumnVector} (typically {@code OnHeapColumnVector} or
 * {@code OffHeapColumnVector} from the vectorized Parquet reader) to
 * Arrow-layout segments.
 *
 * <p>Fixed-width data is copied once into native memory: straight out of the
 * backing {@code int[]}/{@code long[]}/{@code double[]} (on heap) or native
 * buffer (off heap) of Spark's own writable vectors, or through the bulk
 * getters ({@code getInts} etc., which copy once more) for foreign vector
 * classes. Kernels read native segments noticeably faster than heap-array
 * segments on the Vector API, which is why the arrays are not wrapped in place.
 * Numeric columns the Parquet reader left dictionary encoded are decoded
 * through a per-batch lookup table instead of one virtual call per row. The
 * validity bitmap is rebuilt only when the vector has nulls.
 *
 * <p>String columns that the Parquet reader left dictionary encoded are copied
 * as dictionary indices plus the distinct values actually referenced by the
 * batch, so downstream kernels never touch the row strings; other string
 * columns are copied byte-wise without materialising a {@code UTF8String} per
 * row.
 */
public final class SparkColumnVectorBuffers {

    private static final Field DICTIONARY_FIELD = field(WritableColumnVector.class, "dictionary");
    private static final Field ONHEAP_NULLS = field(OnHeapColumnVector.class, "nulls");
    private static final Field ONHEAP_INTS = field(OnHeapColumnVector.class, "intData");
    private static final Field ONHEAP_LONGS = field(OnHeapColumnVector.class, "longData");
    private static final Field ONHEAP_DOUBLES = field(OnHeapColumnVector.class, "doubleData");
    private static final Field OFFHEAP_NULLS = field(OffHeapColumnVector.class, "nulls");
    private static final Field OFFHEAP_DATA = field(OffHeapColumnVector.class, "data");

    private SparkColumnVectorBuffers() {}

    /**
     * Test-visible counter: off-heap fixed-width columns handed over as views
     * instead of copies.
     */
    private static final java.util.concurrent.atomic.LongAdder WRAPPED_OFFHEAP_COLUMNS = new java.util.concurrent.atomic.LongAdder();

    public static long wrappedOffHeapColumns() {
        return WRAPPED_OFFHEAP_COLUMNS.sum();
    }

    /** Test-visible counter: wide decimal columns converted into DECIMAL128 lanes. */
    private static final java.util.concurrent.atomic.LongAdder WIDE_DECIMAL_COLUMNS = new java.util.concurrent.atomic.LongAdder();

    public static long wideDecimalColumns() {
        return WIDE_DECIMAL_COLUMNS.sum();
    }

    public static VectorBuffers copy(ColumnVector cv, int numRows, Arena arena) {
        VecType type = TypeMapping.vecTypeOf(cv.dataType());
        if (type == null) {
            throw new UnsupportedOperationException("unsupported Spark type " + cv.dataType());
        }
        MemorySegment validity = copyValidity(cv, numRows, arena);
        if (cv.dataType() instanceof DecimalType dec) {
            return copyDecimal(cv, dec, numRows, arena, validity);
        }
        if (cv.dataType() instanceof ByteType || cv.dataType() instanceof ShortType) {
            // TINYINT / SMALLINT widen into the INT32 lane (#327); the per-row getters decode a Parquet
            // dictionary, which the bulk ones do not, and the int fast paths below would read the wrong array.
            MemorySegment data = ArrowLayout.allocateData(arena, VecType.INT32, numRows);
            boolean bytes = cv.dataType() instanceof ByteType;
            for (int i = 0; i < numRows; i++) {
                if (validity == null || Bitmap.isSet(validity, i)) {
                    data.setAtIndex(VectorBuffers.LE_INT, i,
                            bytes ? cv.getByte(i) : cv.getShort(i));
                }
            }
            return SegmentVectorBuffers.fixedWidth(VecType.INT32, numRows, validity, data);
        }
        if (type.isFixedWidth() && cv instanceof WritableColumnVector w) {
            Dictionary dict = w.hasDictionary() ? dictionaryOf(w) : null;
            if (dict == null && cv instanceof OffHeapColumnVector) {
                // Off-heap Parquet batches (spark.sql.columnVector.offheap.enabled): the data already sits in
                // native memory in Arrow's fixed-width layout, so the lane is a view of it, not a copy. The
                // batch outlives every read of it (operators drain a batch before pulling the next one), as
                // with the Comet and Iceberg zero-copy adapters.
                MemorySegment view = wrapData(w, type, numRows);
                if (view != null) {
                    WRAPPED_OFFHEAP_COLUMNS.increment();
                    return SegmentVectorBuffers.fixedWidth(type, numRows, validity, view);
                }
            }
            if (dict != null) {
                MemorySegment data = ArrowLayout.allocateData(arena, type, numRows);
                if (decodeDictionaryInto(w, dict, type, numRows, validity, data,
                        false)) {
                    return SegmentVectorBuffers.fixedWidth(type, numRows, validity, data);
                }
            } else {
                MemorySegment source = wrapData(w, type, numRows);
                if (source != null) {
                    MemorySegment data = ArrowLayout.allocateData(arena, type, numRows);
                    MemorySegment.copy(source, 0, data, 0, source.byteSize());
                    return SegmentVectorBuffers.fixedWidth(type, numRows, validity, data);
                }
            }
        }
        switch (type) {
            case INT32 -> {
                MemorySegment data = ArrowLayout.allocateData(arena, type, numRows);
                MemorySegment.copy(cv.getInts(0, numRows), 0, data, VectorBuffers.LE_INT, 0,
                        numRows);
                return SegmentVectorBuffers.fixedWidth(type, numRows, validity, data);
            }
            case INT64 -> {
                MemorySegment data = ArrowLayout.allocateData(arena, type, numRows);
                MemorySegment.copy(cv.getLongs(0, numRows), 0, data, VectorBuffers.LE_LONG, 0,
                        numRows);
                return SegmentVectorBuffers.fixedWidth(type, numRows, validity, data);
            }
            case FLOAT64 -> {
                MemorySegment data = ArrowLayout.allocateData(arena, type, numRows);
                MemorySegment.copy(cv.getDoubles(0, numRows), 0, data, VectorBuffers.LE_DOUBLE, 0,
                        numRows);
                return SegmentVectorBuffers.fixedWidth(type, numRows, validity, data);
            }
            case BOOL -> {
                MemorySegment data = ArrowLayout.allocateBitmap(arena, numRows);
                boolean[] values = cv.getBooleans(0, numRows);
                for (int i = 0; i < numRows; i++) {
                    if (values[i]) {
                        Bitmap.set(data, i);
                    }
                }
                return SegmentVectorBuffers.fixedWidth(type, numRows, validity, data);
            }
            case UTF8 -> {
                if (cv instanceof WritableColumnVector w) {
                    Dictionary dict = w.hasDictionary() ? dictionaryOf(w) : null;
                    if (dict != null) {
                        return copyDictionaryUtf8(w, dict, numRows, arena, validity);
                    }
                    return copyWritableUtf8(w, numRows, arena, validity);
                }
                return copyUtf8(cv, numRows, arena, validity);
            }
            default -> throw new IllegalStateException(type.toString());
        }
    }

    /**
     * Decimals of up to 18 digits: Spark's writable vectors keep them as ints
     * (precision <= 9) or longs, the Parquet reader possibly dictionary
     * encoded; both bulk getters decode the dictionary. Foreign vectors
     * (Comet's 128-bit decimals, for instance) are read through {@code
     * getDecimal}.
     */
    private static VectorBuffers copyDecimal(ColumnVector cv, DecimalType dec, int numRows,
            Arena arena, MemorySegment validity) {
        if (dec.precision() > TypeMapping.MAX_DECIMAL_PRECISION) {
            return copyWideDecimal(cv, dec, numRows, arena, validity);
        }
        MemorySegment data = ArrowLayout.allocateData(arena, VecType.INT64, numRows);
        if (cv instanceof WritableColumnVector w) {
            // A dictionary-encoded decimal column through the bulk dictionary path (#416): the reader's
            // bulk getInts/getLongs decode a dictionary value by value through the virtual getters --
            // q18's five decimal(7,2) measures were 5% of its task time at SF10 that way. The int-backed
            // dictionary (up to 9 digits) is widened into the INT64 lane as it is written.
            Dictionary dict = w.hasDictionary() ? dictionaryOf(w) : null;
            if (dict != null) {
                boolean ints = dec.precision() <= Decimal.MAX_INT_DIGITS();
                if (decodeDictionaryInto(w, dict, ints ? VecType.INT32 : VecType.INT64, numRows,
                        validity, data, ints)) {
                    return SegmentVectorBuffers.fixedWidth(VecType.INT64, numRows, validity, data);
                }
            }
            if (dec.precision() <= Decimal.MAX_INT_DIGITS()) {
                int[] ints = cv.getInts(0, numRows);
                for (int i = 0; i < numRows; i++) {
                    data.setAtIndex(VectorBuffers.LE_LONG, i, ints[i]);
                }
            } else {
                MemorySegment.copy(cv.getLongs(0, numRows), 0, data, VectorBuffers.LE_LONG, 0,
                        numRows);
            }
        } else {
            for (int i = 0; i < numRows; i++) {
                if (validity == null || Bitmap.isSet(validity, i)) {
                    Decimal d = cv.getDecimal(i, dec.precision(), dec.scale());
                    data.setAtIndex(VectorBuffers.LE_LONG, i,
                            d == null ? 0L : d.toUnscaledLong());
                }
            }
        }
        return SegmentVectorBuffers.fixedWidth(VecType.INT64, numRows, validity, data);
    }

    /**
     * Decimals of 19 to 38 digits become a DECIMAL128 lane. Spark's writable
     * vectors keep them as big-endian two's complement byte strings ({@code
     * getBinary}, which also resolves the Parquet reader's dictionary), so each
     * row is two sign-extended limbs without a {@code BigDecimal} on the way; a
     * foreign vector is read through {@code getDecimal}.
     */
    private static VectorBuffers copyWideDecimal(ColumnVector cv, DecimalType dec, int numRows,
            Arena arena, MemorySegment validity) {
        MemorySegment data = ArrowLayout.allocateData(arena, VecType.DECIMAL128, numRows);
        WIDE_DECIMAL_COLUMNS.increment();
        boolean writable = cv instanceof WritableColumnVector;
        for (int i = 0; i < numRows; i++) {
            if (validity != null && !Bitmap.isSet(validity, i)) {
                continue;
            }
            if (writable) {
                byte[] be = cv.getBinary(i);
                Decimal128.set(data, i, Decimal128.hiFromBigEndian(be, 0, be.length), Decimal128.loFromBigEndian(be, 0, be.length));
            } else {
                Decimal d = cv.getDecimal(i, dec.precision(), dec.scale());
                if (d != null) {
                    java.math.BigInteger unscaled = d.toJavaBigDecimal().unscaledValue();
                    Decimal128.set(data, i, Decimal128.hiOf(unscaled), Decimal128.loOf(unscaled));
                }
            }
        }
        return SegmentVectorBuffers.fixedWidth(VecType.DECIMAL128, numRows, validity, data);
    }

    // Spark keeps one null byte per row; the bitmap takes one bit. Converting eight bytes per read and
    // writing one bitmap word per 64 rows replaced a byte-per-row loop into a heap byte[] plus a copy
    // (#398), and on the off-heap path a checked read and a Bitmap.set per row: ~2.7% of executor
    // samples at 1 TB (#541).
    private static final VarHandle LONGS_OF_BYTES = MethodHandles.byteArrayViewVarHandle(long[].class, ByteOrder.LITTLE_ENDIAN);

    /**
     * Validity bits of eight rows from their eight null bytes (little-endian,
     * byte {@code j} = row {@code j}): bit {@code j} is set when byte {@code j}
     * is zero, i.e. the row is not null. Any non-zero byte counts as null, not
     * just 1.
     */
    static int validByte(long nullBytes) {
        long nz = nullBytes | (nullBytes >>> 4);
        nz |= nz >>> 2;
        nz |= nz >>> 1;
        long valid = ~nz & 0x0101010101010101L;
        // Gathers bit 0 of byte j into bit 56 + j.
        return (int) ((valid * 0x0102040810204080L) >>> 56);
    }

    /**
     * The validity word of rows {@code [base, base + 64)} from a heap null
     * array, all 64 present.
     */
    private static long heapWord(byte[] nulls, int base) {
        long w = 0L;
        for (int j = 0; j < 8; j++) {
            w |= (long) validByte((long) LONGS_OF_BYTES.get(nulls, base + (j << 3))) << (j << 3);
        }
        return w;
    }

    /** The same from native null bytes. */
    private static long nativeWord(MemorySegment nulls, int base) {
        long w = 0L;
        for (int j = 0; j < 8; j++) {
            w |= (long) validByte(nulls.get(ValueLayout.JAVA_LONG_UNALIGNED, base + (j << 3))) << (j << 3);
        }
        return w;
    }

    private static MemorySegment copyValidity(ColumnVector cv, int numRows, Arena arena) {
        if (!cv.hasNull()) {
            return null;
        }
        byte[] heap = heapNulls(cv, numRows);
        if (heap != null && heap.length < numRows) {
            heap = null;
        }
        MemorySegment nativeNulls = heap == null && cv instanceof OffHeapColumnVector
                ? nativeSegment(OFFHEAP_NULLS, cv, numRows)
                : null;
        MemorySegment validity = ArrowLayout.allocateBitmap(arena, numRows);
        int full = numRows >>> 6;
        long nulls = 0L;
        for (int w = 0; w < full; w++) {
            long word = heap != null
                    ? heapWord(heap, w << 6)
                    : nativeNulls != null ? nativeWord(nativeNulls, w << 6) : rowWord(cv, w << 6, 64);
            nulls += 64 - Long.bitCount(word);
            validity.setAtIndex(ValueLayout.JAVA_LONG_UNALIGNED, w, word);
        }
        int tail = numRows & 63;
        if (tail != 0) {
            int base = full << 6;
            long word = 0L;
            for (int i = 0; i < tail; i++) {
                boolean isNull = heap != null
                        ? heap[base + i] != 0
                        : nativeNulls != null ? nativeNulls.get(ValueLayout.JAVA_BYTE, base + i) != 0 : cv.isNullAt(base + i);
                if (!isNull) {
                    word |= 1L << i;
                }
            }
            nulls += tail - Long.bitCount(word);
            Bitmap.setWord(validity, full, numRows, word);
        }
        // hasNull() may be conservative (e.g. nulls outside [0, numRows)); drop an all-valid bitmap.
        return nulls == 0 ? null : validity;
    }

    /**
     * A validity word through {@code isNullAt}, for vectors whose null storage
     * we cannot read.
     */
    private static long rowWord(ColumnVector cv, int base, int count) {
        long word = 0L;
        for (int i = 0; i < count; i++) {
            if (!cv.isNullAt(base + i)) {
                word |= 1L << i;
            }
        }
        return word;
    }

    /**
     * View of a writable vector's fixed-width storage, or {@code null} when the
     * vector class is not one we know how to read directly.
     */
    private static MemorySegment wrapData(WritableColumnVector cv, VecType type, int numRows) {
        long bytes = (long) numRows * type.byteWidth();
        if (cv instanceof OnHeapColumnVector) {
            Object array = switch (type) {
                case INT32 -> get(ONHEAP_INTS, cv);
                case INT64 -> get(ONHEAP_LONGS, cv);
                case FLOAT64 -> get(ONHEAP_DOUBLES, cv);
                default -> null;
            };
            MemorySegment heap = switch (array) {
                case int[] a when a.length >= numRows -> MemorySegment.ofArray(a);
                case long[] a when a.length >= numRows -> MemorySegment.ofArray(a);
                case double[] a when a.length >= numRows -> MemorySegment.ofArray(a);
                case null, default -> null;
            };
            return heap == null ? null : heap.asSlice(0, bytes);
        }
        if (cv instanceof OffHeapColumnVector) {
            return nativeSegment(OFFHEAP_DATA, cv, bytes);
        }
        return null;
    }

    /**
     * Per-thread scratch for the decoded dictionary table: no allocation per
     * column per batch.
     */
    private static final ThreadLocal<long[]> DICTIONARY_TABLE = ThreadLocal.withInitial(() -> new long[256]);

    /**
     * A dictionary's decoded values, kept across the batches the dictionary
     * serves (#416). Spark's parquet reader wraps a column chunk's dictionary
     * in a new {@code ParquetDictionary} for every batch it reads, and the fast
     * path decoded the ids up to the batch's largest for each 4096-row batch
     * anew: for a fact table's key columns, whose chunk dictionaries run to
     * hundreds of thousands of entries, that was more work than the rows
     * themselves -- 7% of q18's task time at SF10, most of the adapter's share.
     * The cache is keyed on the parquet dictionary behind the wrapper (the
     * stable object, one per column chunk) and decodes it whole on first sight;
     * a dictionary of another kind is keyed on itself and decoded as far as
     * each batch needs.
     */
    private static final class DecodedDictionary {
        /**
         * The identity the cache is keyed on: the parquet dictionary behind a
         * {@code ParquetDictionary}, else the dictionary itself.
         */
        final Object key;

        final boolean transform;

        /**
         * The lane type the table was decoded for (a dictionary object serving
         * two types is not a parquet one, but a test's).
         */
        final VecType type;

        long[] table;

        /** Ids {@code [0, decoded)} are in {@code table}. */
        int decoded;

        DecodedDictionary(Object key, boolean transform, VecType type) {
            this.key = key;
            this.transform = transform;
            this.type = type;
            this.table = new long[256];
        }

        long[] upTo(Dictionary dictionary, int maxId, VecType type) {
            if (maxId < decoded) {
                return table;
            }
            if (key instanceof org.apache.parquet.column.Dictionary parquet) {
                maxId = Math.max(maxId, parquet.getMaxId()); // the whole chunk dictionary, once
            }
            if (table.length <= maxId) {
                table = Arrays.copyOf(table, Integer.highestOneBit(maxId) << 1);
            }
            switch (type) {
                case INT32 -> {
                    for (int id = decoded; id <= maxId; id++) {
                        table[id] = dictionary.decodeToInt(id);
                    }
                }
                case INT64 -> {
                    for (int id = decoded; id <= maxId; id++) {
                        table[id] = dictionary.decodeToLong(id);
                    }
                }
                default -> {
                    for (int id = decoded; id <= maxId; id++) {
                        table[id] = Double.doubleToRawLongBits(dictionary.decodeToDouble(id));
                    }
                }
            }
            decoded = maxId + 1;
            return table;
        }
    }

    /**
     * The thread's recently seen dictionaries (one per column of the task's
     * current chunk, a handful).
     */
    private static final ThreadLocal<DecodedDictionary[]> DECODED_DICTIONARIES = ThreadLocal.withInitial(() -> new DecodedDictionary[16]);

    private static final Class<?> PARQUET_DICTIONARY = classOrNull("org.apache.spark.sql.execution.datasources.parquet.ParquetDictionary");
    private static final Field PARQUET_DICTIONARY_INNER = PARQUET_DICTIONARY == null ? null : field(PARQUET_DICTIONARY, "dictionary");
    private static final Field PARQUET_DICTIONARY_TRANSFORM = PARQUET_DICTIONARY == null ? null : field(PARQUET_DICTIONARY, "needTransform");

    private static Class<?> classOrNull(String name) {
        try {
            return Class.forName(name);
        } catch (ClassNotFoundException e) {
            return null;
        }
    }

    @SuppressWarnings("ReferenceEquality") // the decoded-dictionary cache is keyed on the dictionary object itself
    private static DecodedDictionary decodedDictionary(Dictionary dict, VecType type) {
        Object key = dict;
        boolean transform = false;
        if (PARQUET_DICTIONARY_INNER != null && PARQUET_DICTIONARY.isInstance(dict)) {
            Object inner = get(PARQUET_DICTIONARY_INNER, dict);
            if (inner != null) {
                key = inner;
                transform = get(PARQUET_DICTIONARY_TRANSFORM, dict) instanceof Boolean b && b;
            }
        }
        DecodedDictionary[] recent = DECODED_DICTIONARIES.get();
        for (int i = 0; i < recent.length; i++) {
            DecodedDictionary d = recent[i];
            if (d == null) {
                break;
            }
            if (d.key == key && d.transform == transform && d.type == type) {
                if (i > 0) { // most recently used first, so a chunk's columns stay at the front
                    System.arraycopy(recent, 0, recent, 1, i);
                    recent[0] = d;
                }
                return d;
            }
        }
        DecodedDictionary d = new DecodedDictionary(key, transform, type);
        System.arraycopy(recent, 0, recent, 1, recent.length - 1); // the oldest falls off the end
        recent[0] = d;
        return d;
    }

    /**
     * Numeric column left dictionary encoded by the Parquet reader: decodes the
     * dictionary once (ids are dense, so every id up to the largest one
     * referenced exists) and gathers straight into the arena segment. Nothing
     * is allocated on the heap: the earlier form built three arrays per column
     * per batch (ids, table, values) and was the GC behind the shuffle's
     * short-query regressions.
     */
    private static boolean decodeDictionaryInto(
            WritableColumnVector cv,
            Dictionary dict,
            VecType type,
            int numRows,
            MemorySegment validity,
            MemorySegment data,
            boolean widenToLong) {
        if (type != VecType.INT32 && type != VecType.INT64 && type != VecType.FLOAT64) {
            return false;
        }
        if (widenToLong && type != VecType.INT32) {
            return false;
        }
        WritableColumnVector ids = cv.getDictionaryIds();
        if (ids instanceof OffHeapColumnVector
                && (validity == null || cv instanceof OffHeapColumnVector)
                && decodeOffHeapDictionaryInto(cv, ids, dict, type, numRows,
                        validity != null, data, widenToLong)) {
            return true;
        }
        int[] idArray = heapIds(ids, numRows);
        byte[] nulls = validity != null ? heapNulls(cv, numRows) : null;
        if (idArray == null
                || idArray.length < numRows
                || (validity != null && (nulls == null || nulls.length < numRows))) {
            return !widenToLong && decodeDictionaryIntoSlow(cv, dict, type, numRows, validity, data);
        }
        // The reader's own arrays, a heap staging array and one copy out (#398): the per-row virtual
        // getInt, Bitmap.isSet and setAtIndex were 7% of an executor's time in q8 at SF10.
        // The dictionary decoded once per column chunk, not once per batch (#416); a Parquet one is
        // decoded whole, so its size bounds every id and the maxId pass is skipped (#551).
        DecodedDictionary decoded = decodedDictionary(dict, type);
        long[] table;
        if (decoded.key instanceof org.apache.parquet.column.Dictionary parquet && parquet.getMaxId() >= 0) {
            table = decoded.upTo(dict, 0, type);
        } else {
            int maxId = -1;
            for (int i = 0; i < numRows; i++) {
                if (nulls == null || nulls[i] == 0) {
                    maxId = Math.max(maxId, idArray[i]);
                }
            }
            if (maxId < 0) {
                // Every row null: the lanes are zero, nothing to decode.
                data.asSlice(0, (long) numRows * (widenToLong ? 8 : type.byteWidth())).fill((byte) 0);
                return true;
            }
            table = decoded.upTo(dict, maxId, type);
        }
        // Two loops per lane width, one without nulls and one with, the latter without a branch: a null
        // row reads table entry 0 and is masked to zero (#416, see GatherKernels.gatherFixed).
        if (type == VecType.INT32 && !widenToLong) {
            int[] out = intScratch(numRows);
            if (nulls == null) {
                for (int i = 0; i < numRows; i++) {
                    out[i] = (int) table[idArray[i]];
                }
            } else {
                for (int i = 0; i < numRows; i++) {
                    int keep = ((nulls[i] & 0xFF) - 1) >> 31; // 0 -> all ones, any null marker -> zero
                    out[i] = (int) table[idArray[i] & keep] & keep;
                }
            }
            MemorySegment.copy(out, 0, data, VectorBuffers.LE_INT, 0, numRows);
        } else {
            long[] out = longScratch(numRows);
            if (nulls == null) {
                for (int i = 0; i < numRows; i++) {
                    out[i] = table[idArray[i]];
                }
            } else {
                for (int i = 0; i < numRows; i++) {
                    int keep = ((nulls[i] & 0xFF) - 1) >> 31;
                    out[i] = table[idArray[i] & keep] & keep;
                }
            }
            MemorySegment.copy(out, 0, data, VectorBuffers.LE_LONG, 0, numRows);
        }
        return true;
    }

    /**
     * {@link #decodeDictionaryInto} for the reader's off-heap vectors (#551):
     * the ids and null flags are copied out of native memory in one bulk copy
     * each, into the thread's reusable scratch arrays, instead of into a fresh
     * {@code int[]} and {@code byte[]} per column per batch -- that staging,
     * with the {@code maxId} pass, was most of the adapter's cost in q88 at 1
     * TB (17% of executor samples). A Parquet dictionary is decoded whole for
     * its column chunk, so its size bounds every id and no {@code maxId} pass
     * is needed; any other dictionary is still scanned for its largest id. The
     * values are gathered into the thread's heap scratch and copied out once,
     * as the heap path does (#398).
     *
     * @return false when the vectors' native addresses are not readable, for
     *     the caller's heap path
     */
    private static boolean decodeOffHeapDictionaryInto(
            WritableColumnVector cv,
            WritableColumnVector ids,
            Dictionary dict,
            VecType type,
            int numRows,
            boolean nullable,
            MemorySegment data,
            boolean widenToLong) {
        MemorySegment idSeg = nativeSegment(OFFHEAP_DATA, ids, 4L * numRows);
        MemorySegment nullSeg = nullable ? nativeSegment(OFFHEAP_NULLS, cv, numRows) : null;
        if (idSeg == null || (nullable && nullSeg == null)) {
            return false;
        }
        // One bulk copy each out of native memory into the thread's reusable scratch (#551): read row
        // by row, the native segments cost liveness checks and non-inlined scoped accesses on the
        // executors (8.1% + 4.3% of q88's samples at 1 TB) that took back most of what dropping the
        // per-batch arrays saved.
        int[] idArray = idScratch(numRows);
        MemorySegment.copy(idSeg, ValueLayout.JAVA_INT_UNALIGNED,
                0, idArray, 0, numRows);
        byte[] nulls = null;
        if (nullSeg != null) {
            nulls = nullScratch(numRows);
            MemorySegment.copy(nullSeg, ValueLayout.JAVA_BYTE, 0, nulls, 0, numRows);
        }
        DecodedDictionary decoded = decodedDictionary(dict, type);
        long[] table;
        if (decoded.key instanceof org.apache.parquet.column.Dictionary parquet && parquet.getMaxId() >= 0) {
            table = decoded.upTo(dict, 0, type); // the whole chunk dictionary, decoded once
        } else {
            int maxId = -1;
            for (int i = 0; i < numRows; i++) {
                if (nulls == null || nulls[i] == 0) {
                    maxId = Math.max(maxId, idArray[i]);
                }
            }
            if (maxId < 0) {
                // Every row null: the lanes are zero, nothing to decode.
                data.asSlice(0, (long) numRows * (widenToLong ? 8 : type.byteWidth())).fill((byte) 0);
                return true;
            }
            table = decoded.upTo(dict, maxId, type);
        }
        // A null row reads table entry 0 and is masked to zero, without a branch (#416).
        if (type == VecType.INT32 && !widenToLong) {
            int[] out = intScratch(numRows);
            if (nulls == null) {
                for (int i = 0; i < numRows; i++) {
                    out[i] = (int) table[idArray[i]];
                }
            } else {
                for (int i = 0; i < numRows; i++) {
                    int keep = ((nulls[i] & 0xFF) - 1) >> 31;
                    out[i] = (int) table[idArray[i] & keep] & keep;
                }
            }
            MemorySegment.copy(out, 0, data, VectorBuffers.LE_INT, 0, numRows);
        } else {
            long[] out = longScratch(numRows);
            if (nulls == null) {
                for (int i = 0; i < numRows; i++) {
                    out[i] = table[idArray[i]];
                }
            } else {
                for (int i = 0; i < numRows; i++) {
                    int keep = ((nulls[i] & 0xFF) - 1) >> 31;
                    out[i] = table[idArray[i] & keep] & keep;
                }
            }
            MemorySegment.copy(out, 0, data, VectorBuffers.LE_LONG, 0, numRows);
        }
        return true;
    }

    private static final ThreadLocal<int[]> ID_SCRATCH = ThreadLocal.withInitial(() -> new int[4096]);
    private static final ThreadLocal<byte[]> NULL_SCRATCH = ThreadLocal.withInitial(() -> new byte[4096]);

    /**
     * The thread's reusable array for a batch's dictionary ids, apart from the
     * output scratch.
     */
    private static int[] idScratch(int n) {
        int[] s = ID_SCRATCH.get();
        if (s.length < n) {
            s = new int[Integer.highestOneBit(n) << 1];
            ID_SCRATCH.set(s);
        }
        return s;
    }

    /** The thread's reusable array for a batch's null bytes. */
    private static byte[] nullScratch(int n) {
        byte[] s = NULL_SCRATCH.get();
        if (s.length < n) {
            s = new byte[Integer.highestOneBit(n) << 1];
            NULL_SCRATCH.set(s);
        }
        return s;
    }

    private static final ThreadLocal<int[]> INT_SCRATCH = ThreadLocal.withInitial(() -> new int[4096]);
    private static final ThreadLocal<long[]> LONG_SCRATCH = ThreadLocal.withInitial(() -> new long[4096]);

    private static int[] intScratch(int n) {
        int[] s = INT_SCRATCH.get();
        if (s.length < n) {
            s = new int[Integer.highestOneBit(n) << 1];
            INT_SCRATCH.set(s);
        }
        return s;
    }

    private static long[] longScratch(int n) {
        long[] s = LONG_SCRATCH.get();
        if (s.length < n) {
            s = new long[Integer.highestOneBit(n) << 1];
            LONG_SCRATCH.set(s);
        }
        return s;
    }

    /**
     * The general form: any column vector, ids through the vector's accessor,
     * validity from the bitmap.
     */
    private static boolean decodeDictionaryIntoSlow(WritableColumnVector cv, Dictionary dict, VecType type,
            int numRows, MemorySegment validity, MemorySegment data) {
        WritableColumnVector ids = cv.getDictionaryIds();
        int maxId = -1;
        for (int i = 0; i < numRows; i++) {
            if (validity == null || Bitmap.isSet(validity, i)) {
                maxId = Math.max(maxId, ids.getInt(i));
            }
        }
        long[] table = DICTIONARY_TABLE.get();
        if (table.length <= maxId) {
            table = new long[Integer.highestOneBit(maxId) << 1];
            DICTIONARY_TABLE.set(table);
        }
        switch (type) {
            case INT32 -> {
                for (int id = 0; id <= maxId; id++) {
                    table[id] = dict.decodeToInt(id);
                }
                for (int i = 0; i < numRows; i++) {
                    if (validity == null || Bitmap.isSet(validity, i)) {
                        data.setAtIndex(VectorBuffers.LE_INT, i, (int) table[ids.getInt(i)]);
                    }
                }
            }
            case INT64 -> {
                for (int id = 0; id <= maxId; id++) {
                    table[id] = dict.decodeToLong(id);
                }
                for (int i = 0; i < numRows; i++) {
                    if (validity == null || Bitmap.isSet(validity, i)) {
                        data.setAtIndex(VectorBuffers.LE_LONG, i, table[ids.getInt(i)]);
                    }
                }
            }
            default -> {
                for (int id = 0; id <= maxId; id++) {
                    table[id] = Double.doubleToRawLongBits(dict.decodeToDouble(id));
                }
                for (int i = 0; i < numRows; i++) {
                    if (validity == null || Bitmap.isSet(validity, i)) {
                        data.setAtIndex(VectorBuffers.LE_LONG, i, table[ids.getInt(i)]);
                    }
                }
            }
        }
        return true;
    }

    /**
     * Dictionary-encoded strings: Spark keeps Parquet dictionary ids per row
     * and decodes on access. The ids are remapped to a dense dictionary holding
     * only the values this batch references.
     */
    private static VectorBuffers copyDictionaryUtf8(WritableColumnVector cv, Dictionary dict, int numRows,
            Arena arena, MemorySegment validity) {
        // Per-thread scratch, grown and kept: the four fresh arrays per column per batch this used to
        // allocate were GC on every dictionary string column adapted (the shuffle adapts every batch).
        Utf8Scratch sc = UTF8_SCRATCH.get();
        WritableColumnVector idVector = cv.getDictionaryIds();
        int[] remap = sc.remap;
        Arrays.fill(remap, -1);
        int distinct = 0;
        byte[] bytes = sc.bytes;
        int used = 0;
        int[] offsets = sc.offsets;
        MemorySegment indices = ArrowLayout.allocateData(arena, VecType.INT32, numRows);
        for (int i = 0; i < numRows; i++) {
            if (validity != null && !Bitmap.isSet(validity, i)) {
                indices.setAtIndex(VectorBuffers.LE_INT, i, 0);
                continue;
            }
            int id = idVector.getInt(i);
            if (id >= remap.length) {
                int old = remap.length;
                remap = Arrays.copyOf(remap,
                        Math.max(id + 1, old * 2));
                Arrays.fill(remap, old, remap.length, -1);
            }
            int k = remap[id];
            if (k < 0) {
                byte[] value = dict.decodeToBinary(id);
                if (used + value.length > bytes.length) {
                    bytes = Arrays.copyOf(bytes,
                            Math.max(bytes.length * 2, used + value.length));
                }
                System.arraycopy(value, 0, bytes, used, value.length);
                used += value.length;
                k = distinct++;
                if (distinct >= offsets.length) {
                    offsets = Arrays.copyOf(offsets, offsets.length * 2);
                }
                offsets[distinct] = used;
                remap[id] = k;
            }
            indices.setAtIndex(VectorBuffers.LE_INT, i, k);
        }
        sc.remap = remap;
        sc.bytes = bytes;
        sc.offsets = offsets;
        MemorySegment dictOffsets = ArrowLayout.allocateOffsets(arena, distinct);
        MemorySegment.copy(offsets, 0, dictOffsets, VectorBuffers.LE_INT, 0,
                distinct + 1);
        MemorySegment dictData = ArrowLayout.allocateBytes(arena, used);
        MemorySegment.copy(bytes, 0, dictData, ValueLayout.JAVA_BYTE, 0, used);
        VectorBuffers dictionary = SegmentVectorBuffers.utf8(distinct, null, dictOffsets, dictData);
        return SegmentVectorBuffers.dictionaryUtf8(numRows, validity, indices, dictionary);
    }

    private static final class Utf8Scratch {
        int[] remap = new int[1024];
        byte[] bytes = new byte[1 << 16];
        int[] offsets = new int[1025];
    }

    private static final ThreadLocal<Utf8Scratch> UTF8_SCRATCH = ThreadLocal.withInitial(Utf8Scratch::new);

    /**
     * Plain strings in a writable vector: copied straight out of its byte
     * storage.
     */
    private static VectorBuffers copyWritableUtf8(WritableColumnVector cv, int numRows, Arena arena,
            MemorySegment validity) {
        WritableColumnVector bytes = cv.arrayData();
        long total = 0;
        for (int i = 0; i < numRows; i++) {
            if (validity == null || Bitmap.isSet(validity, i)) {
                total += cv.getArrayLength(i);
            }
        }
        MemorySegment offsets = ArrowLayout.allocateOffsets(arena, numRows);
        MemorySegment data = ArrowLayout.allocateBytes(arena, total);
        int pos = 0;
        for (int i = 0; i < numRows; i++) {
            offsets.set(VectorBuffers.LE_INT, (long) i << 2, pos);
            if (validity == null || Bitmap.isSet(validity, i)) {
                int len = cv.getArrayLength(i);
                if (len > 0) {
                    ByteBuffer bb = bytes.getByteBuffer(cv.getArrayOffset(i), len);
                    if (bb.hasArray()) {
                        MemorySegment.copy(bb.array(), bb.arrayOffset() + bb.position(), data, ValueLayout.JAVA_BYTE,
                                pos, len);
                    } else {
                        MemorySegment.copy(MemorySegment.ofBuffer(bb), 0, data, pos, len);
                    }
                    pos += len;
                }
            }
        }
        offsets.set(VectorBuffers.LE_INT, (long) numRows << 2, pos);
        return SegmentVectorBuffers.utf8(numRows, validity, offsets, data);
    }

    /** Any other column vector: one {@link UTF8String} per row. */
    private static VectorBuffers copyUtf8(ColumnVector cv, int numRows, Arena arena,
            MemorySegment validity) {
        UTF8String[] strings = new UTF8String[numRows];
        long total = 0;
        for (int i = 0; i < numRows; i++) {
            if (validity == null || Bitmap.isSet(validity, i)) {
                strings[i] = cv.getUTF8String(i);
                total += strings[i].numBytes();
            }
        }
        MemorySegment offsets = ArrowLayout.allocateOffsets(arena, numRows);
        MemorySegment data = ArrowLayout.allocateBytes(arena, total);
        int pos = 0;
        for (int i = 0; i < numRows; i++) {
            offsets.set(VectorBuffers.LE_INT, (long) i << 2, pos);
            UTF8String s = strings[i];
            if (s != null) {
                byte[] bytes = s.getBytes();
                MemorySegment.copy(bytes, 0, data, ValueLayout.JAVA_BYTE, pos, bytes.length);
                pos += bytes.length;
            }
        }
        offsets.set(VectorBuffers.LE_INT, (long) numRows << 2, pos);
        return SegmentVectorBuffers.utf8(numRows, validity, offsets, data);
    }

    private static Field field(Class<?> cls, String name) {
        try {
            Field f = cls.getDeclaredField(name);
            f.setAccessible(true);
            return f;
        } catch (ReflectiveOperationException | RuntimeException e) {
            return null;
        }
    }

    private static Object get(Field f, Object target) {
        if (f == null) {
            return null;
        }
        try {
            return f.get(target);
        } catch (IllegalAccessException e) {
            return null;
        }
    }

    /**
     * Native memory a Spark off-heap vector points to, as a segment of {@code
     * bytes}.
     */
    private static MemorySegment nativeSegment(Field addressField, Object target, long bytes) {
        Object address = get(addressField, target);
        if (!(address instanceof Long addr) || addr == 0L) {
            return null;
        }
        return MemorySegment.ofAddress(addr).reinterpret(bytes);
    }

    /**
     * The reader's null flags as a heap array, one byte per row: the on-heap
     * vector's own array, or the off-heap vector's native array copied out
     * once. With {@code spark.sql.columnVector.offheap.enabled} the bulk
     * validity and dictionary paths of #398 otherwise fell to their per-row
     * forms -- the scan-heavy queries of the 1 TB run were 5-10% slower
     * off-heap than on-heap (#403).
     */
    private static byte[] heapNulls(ColumnVector cv, int numRows) {
        if (cv instanceof OnHeapColumnVector) {
            return (byte[]) get(ONHEAP_NULLS, cv);
        }
        if (cv instanceof OffHeapColumnVector) {
            MemorySegment nativeNulls = nativeSegment(OFFHEAP_NULLS, cv, numRows);
            if (nativeNulls == null) {
                return null;
            }
            byte[] nulls = new byte[numRows];
            MemorySegment.copy(nativeNulls, ValueLayout.JAVA_BYTE, 0, nulls, 0, numRows);
            return nulls;
        }
        return null;
    }

    /**
     * The dictionary ids as a heap {@code int[]}: the on-heap array, or the
     * off-heap ints copied out once.
     */
    private static int[] heapIds(WritableColumnVector ids, int numRows) {
        if (ids instanceof OnHeapColumnVector) {
            return (int[]) get(ONHEAP_INTS, ids);
        }
        if (ids instanceof OffHeapColumnVector) {
            MemorySegment nativeIds = nativeSegment(OFFHEAP_DATA, ids, 4L * numRows);
            if (nativeIds == null) {
                return null;
            }
            int[] idArray = new int[numRows];
            MemorySegment.copy(nativeIds, ValueLayout.JAVA_INT_UNALIGNED,
                    0, idArray, 0, numRows);
            return idArray;
        }
        return null;
    }

    private static Dictionary dictionaryOf(WritableColumnVector cv) {
        return (Dictionary) get(DICTIONARY_FIELD, cv);
    }
}
