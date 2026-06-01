# DBN decoding functionality

"""
    read_null_terminated_string(io, n::Int) -> String

Optimized reading of null-terminated fixed-length string from IO.
Finds the first null byte and creates string from valid data only.
9x faster than String(strip(String(bytes), '\\0')).
"""
@inline function read_null_terminated_string(io, n::Int)
    bytes = read(io, n)
    # Find first null byte
    null_pos = findfirst(==(0x00), bytes)
    len = null_pos === nothing ? n : null_pos - 1
    return len == 0 ? "" : String(bytes[1:len])
end

"""
    unsafe_action(raw_val::UInt8) -> Action.T

Fast enum conversion without safety checks. 1000x+ faster than safe_action.
Only use when you know the data is well-formed (e.g., reading from trusted DBN files).
"""
@inline function unsafe_action(raw_val::UInt8)
    return raw_val == 0x00 ? Action.NONE : Action.T(raw_val)
end

"""
    unsafe_side(raw_val::UInt8) -> Side.T

Fast enum conversion without safety checks. 1000x+ faster than safe_side.
Only use when you know the data is well-formed (e.g., reading from trusted DBN files).
"""
@inline function unsafe_side(raw_val::UInt8)
    return raw_val == 0x00 ? Side.NONE : Side.T(raw_val)
end

"""
    DBNDecoder

Decoder for reading DBN (Databento Binary Encoding) files with support for compression.

# Fields
- `io::IO`: Current IO stream (may be wrapped with compression)
- `base_io::IO`: Original IO stream before any compression wrapper
- `header::Union{DBNHeader,Nothing}`: Parsed DBN header information
- `metadata::Union{Metadata,Nothing}`: Parsed metadata information
- `upgrade_policy::UInt8`: Version upgrade policy
"""
mutable struct DBNDecoder{IO_T <: IO}
    io::IO_T     # Parametric type for type-stable operations
    base_io::IO  # Original IO before compression wrapper (can be abstract)
    header::Union{DBNHeader,Nothing}
    metadata::Union{Metadata,Nothing}
    upgrade_policy::UInt8
    string_cache::Dict{UInt64, String}  # String interning cache for symbols, exchanges, etc.
end

"""
    DBNDecoder(io::IO)

Construct a DBNDecoder from an existing IO stream.

# Arguments
- `io::IO`: Input stream to read from

# Returns
- `DBNDecoder{typeof(io)}`: Decoder instance ready for reading with concrete IO type

# Details
The decoder is parametrized on the IO type for maximum performance. Julia will
specialize all operations on the concrete IO type, eliminating runtime dispatch.
"""
DBNDecoder(io::IO_T) where {IO_T <: IO} = DBNDecoder{IO_T}(io, io, nothing, nothing, 0, Dict{UInt64, String}())

"""
    DBNDecoder(filename::String)

Construct a DBNDecoder from a file, automatically detecting and handling compression.

# Arguments
- `filename::String`: Path to the DBN file (can be compressed with .zst extension)

# Returns
- `DBNDecoder`: Decoder instance with header already parsed

# Details
Automatically detects Zstd compression by checking magic bytes and file extension.
Reads and parses the DBN header during construction.
"""
function DBNDecoder(filename::String)
    base_io = open(filename, "r")
    
    # Check if the file is compressed by looking at magic bytes
    # Zstd magic number is 0xFD2FB528 (little-endian)
    mark_pos = position(base_io)
    magic_bytes = read(base_io, 4)
    seek(base_io, mark_pos)  # Reset to beginning
    
    is_zstd = false
    if length(magic_bytes) == 4
        # Check for Zstd magic number (0x28B52FFD in little-endian)
        is_zstd = magic_bytes == UInt8[0x28, 0xB5, 0x2F, 0xFD]
    end
    
    # Create appropriate IO stream
    if is_zstd || endswith(filename, ".zst")
        # Create a streaming decompressor
        io = TranscodingStream(ZstdDecompressor(), base_io)
    else
        io = base_io
    end

    # Wrap in BufferedReader for 30-50% performance improvement
    # BufferedReader reduces system calls by reading in large chunks (64KB default)
    buffered_io = BufferedReader(io)

    # Use the parametric constructor - Julia will infer the concrete IO type
    decoder = DBNDecoder{typeof(buffered_io)}(buffered_io, base_io, nothing, nothing, 0, Dict{UInt64, String}())
    read_header!(decoder)
    return decoder
end

"""
    intern_string(decoder::DBNDecoder, bytes::Vector{UInt8})

Intern a string to reduce memory allocations for repeated values.

Uses a hash-based cache to reuse string objects for symbols, exchanges,
and other frequently repeated string fields.

Note: String(bytes) takes ownership of the byte array, so we must
compute the hash BEFORE calling String().
"""
@inline function intern_string(decoder::DBNDecoder, bytes::Vector{UInt8})
    # IMPORTANT: Compute hash BEFORE calling String(), which empties the array
    h = hash(bytes)

    # Strip null bytes and convert to string
    stripped = strip(String(bytes), '\0')

    # Empty strings are common - handle without hashing
    if isempty(stripped)
        return ""
    end

    # Check cache and return existing string if found
    get!(decoder.string_cache, h) do
        stripped
    end
end

"""
    read_header!(decoder::DBNDecoder)

Read and parse the DBN file header, populating the decoder's metadata.

# Arguments
- `decoder::DBNDecoder`: Decoder instance to populate

# Details
Reads the magic bytes, version, and metadata section of a DBN file.
Populates the decoder's `metadata` field with parsed information including:
- Dataset identifier
- Schema type
- Time range
- Symbol information
- Mappings

# Throws
- `ErrorException`: If magic bytes are invalid or version is unsupported
"""
function read_header!(decoder::DBNDecoder)
    # Read magic bytes "DBN"
    magic = read(decoder.io, 3)
    if magic != b"DBN"
        error("Invalid DBN file: wrong magic bytes")
    end
    
    # Read version
    version = read(decoder.io, UInt8)
    if version > DBN_VERSION
        error("Unsupported DBN version: $version (decoder supports up to $DBN_VERSION)")
    end
    
    # Read metadata length (4 bytes)
    metadata_length = read(decoder.io, UInt32)
    
    # Read the entire metadata block
    metadata_start_pos = position(decoder.io)
    metadata_bytes = read(decoder.io, metadata_length)
    metadata_io = IOBuffer(metadata_bytes)
    
    # Parse metadata fields from the buffer
    pos = 1
    
    # Dataset (16 bytes fixed-length C string)
    dataset_bytes = metadata_bytes[pos:pos+15]
    pos += 16
    # Remove null terminator bytes
    dataset = String(dataset_bytes[1:findfirst(==(0), dataset_bytes)-1])
    
    # Schema (2 bytes)
    schema_val = ltoh(reinterpret(UInt16, metadata_bytes[pos:pos+1])[1])
    pos += 2
    schema = schema_val == 0xFFFF ? Schema.MIX : Schema.T(schema_val)
    
    # Start timestamp (8 bytes)
    start_ts_raw = ltoh(reinterpret(UInt64, metadata_bytes[pos:pos+7])[1])
    pos += 8
    start_ts = start_ts_raw <= typemax(Int64) ? Int64(start_ts_raw) : 0
    
    # End timestamp (8 bytes) 
    end_ts_raw = ltoh(reinterpret(UInt64, metadata_bytes[pos:pos+7])[1])
    pos += 8
    end_ts = if end_ts_raw == 0 || end_ts_raw == 0xffffffffffffffff
        nothing
    else
        # Safe conversion - check if it fits in Int64
        end_ts_raw <= typemax(Int64) ? Int64(end_ts_raw) : nothing
    end
    
    # Limit (8 bytes)
    limit_raw = ltoh(reinterpret(UInt64, metadata_bytes[pos:pos+7])[1])
    pos += 8
    limit = limit_raw == 0 ? nothing : limit_raw
    
    # For version 1, skip record_count (8 bytes)
    if version == 1
        pos += 8
    end
    
    # SType in (1 byte)
    stype_in_val = metadata_bytes[pos]
    pos += 1
    stype_in = stype_in_val == 0xFF ? nothing : SType.T(stype_in_val)
    
    # SType out (1 byte)
    stype_out = SType.T(metadata_bytes[pos])
    pos += 1
    
    # TS out (1 byte boolean)
    ts_out = metadata_bytes[pos] != 0
    pos += 1
    
    # Symbol string length (2 bytes, only for version > 1)
    symbol_cstr_len = if version == 1
        22  # v1::SYMBOL_CSTR_LEN
    else
        len = ltoh(reinterpret(UInt16, metadata_bytes[pos:pos+1])[1])
        pos += 2
        len
    end
    
    # Skip reserved padding. Per the official DBN spec
    # (databento/dbn rust crate, src/compat.rs):
    #   v1: METADATA_RESERVED_LEN_V1 = 47
    #   v2+: METADATA_RESERVED_LEN    = 53
    reserved_len = if version == 1
        47
    else
        53
    end
    pos += reserved_len
    
    # Schema definition length (4 bytes) - always 0 for now
    schema_def_len = ltoh(reinterpret(UInt32, metadata_bytes[pos:pos+3])[1])
    pos += 4
    if schema_def_len != 0
        error("Schema definitions not supported yet")
    end
    
    # Read variable-length sections
    
    # Symbols
    symbols_count = ltoh(reinterpret(UInt32, metadata_bytes[pos:pos+3])[1])
    pos += 4
    symbols = String[]
    for _ in 1:symbols_count
        symbol_bytes = metadata_bytes[pos:pos+symbol_cstr_len-1]
        pos += symbol_cstr_len
        # Remove null terminator
        null_pos = findfirst(==(0), symbol_bytes)
        if null_pos !== nothing
            symbol = String(symbol_bytes[1:null_pos-1])
        else
            symbol = String(symbol_bytes)
        end
        push!(symbols, symbol)
    end
    
    # Partial symbols
    partial_count = ltoh(reinterpret(UInt32, metadata_bytes[pos:pos+3])[1])
    pos += 4
    partial = String[]
    for _ in 1:partial_count
        symbol_bytes = metadata_bytes[pos:pos+symbol_cstr_len-1]
        pos += symbol_cstr_len
        null_pos = findfirst(==(0), symbol_bytes)
        if null_pos !== nothing
            symbol = String(symbol_bytes[1:null_pos-1])
        else
            symbol = String(symbol_bytes)
        end
        push!(partial, symbol)
    end
    
    # Not found symbols
    not_found_count = ltoh(reinterpret(UInt32, metadata_bytes[pos:pos+3])[1])
    pos += 4
    not_found = String[]
    for _ in 1:not_found_count
        symbol_bytes = metadata_bytes[pos:pos+symbol_cstr_len-1]
        pos += symbol_cstr_len
        null_pos = findfirst(==(0), symbol_bytes)
        if null_pos !== nothing
            symbol = String(symbol_bytes[1:null_pos-1])
        else
            symbol = String(symbol_bytes)
        end
        push!(not_found, symbol)
    end
    
    # Symbol mappings
    mappings_count = ltoh(reinterpret(UInt32, metadata_bytes[pos:pos+3])[1])
    pos += 4
    mappings = Tuple{String,String,Int64,Int64}[]
    for _ in 1:mappings_count
        # Raw symbol
        raw_symbol_bytes = metadata_bytes[pos:pos+symbol_cstr_len-1]
        pos += symbol_cstr_len
        null_pos = findfirst(==(0), raw_symbol_bytes)
        if null_pos !== nothing
            raw_symbol = String(raw_symbol_bytes[1:null_pos-1])
        else
            raw_symbol = String(raw_symbol_bytes)
        end
        
        # Intervals count
        intervals_count = ltoh(reinterpret(UInt32, metadata_bytes[pos:pos+3])[1])
        pos += 4
        
        # For now, just read the first interval (simplified)
        if intervals_count > 0
            # Start date (4 bytes)
            start_date_raw = ltoh(reinterpret(UInt32, metadata_bytes[pos:pos+3])[1])
            pos += 4
            
            # End date (4 bytes)
            end_date_raw = ltoh(reinterpret(UInt32, metadata_bytes[pos:pos+3])[1])
            pos += 4
            
            # Mapped symbol
            mapped_symbol_bytes = metadata_bytes[pos:pos+symbol_cstr_len-1]
            pos += symbol_cstr_len
            null_pos = findfirst(==(0), mapped_symbol_bytes)
            if null_pos !== nothing
                mapped_symbol = String(mapped_symbol_bytes[1:null_pos-1])
            else
                mapped_symbol = String(mapped_symbol_bytes)
            end
            
            push!(mappings, (raw_symbol, mapped_symbol, Int64(start_date_raw), Int64(end_date_raw)))
            
            # Skip remaining intervals for now
            for _ in 2:intervals_count
                pos += 4 + 4 + symbol_cstr_len  # start_date + end_date + symbol
            end
        end
    end
    
    decoder.metadata = Metadata(
        version, dataset, schema, start_ts, end_ts, limit,
        stype_in, stype_out, ts_out,
        symbols, partial, not_found, mappings
    )
    
    # Convert timestamps for DatasetCondition, handling nothing values
    condition_start_ts = start_ts
    condition_end_ts = end_ts === nothing ? 0 : end_ts
    condition_limit = limit === nothing ? 0 : limit
    
    decoder.header = DBNHeader(
        VersionUpgradePolicy(decoder.upgrade_policy),
        DatasetCondition(0, condition_start_ts, condition_end_ts, condition_limit),
        decoder.metadata
    )
    
    # For streaming compatibility, skip remaining metadata bytes instead of seeking
    # We've already read metadata_length bytes into metadata_bytes
    # No need to do anything - we're already at the right position
end

"""
    read_record_header(io::IO)

Read a record header from the IO stream.

# Arguments
- `io::IO`: Input stream positioned at the start of a record header

# Returns
- `RecordHeader`: Parsed record header, or
- `Tuple`: (nothing, raw_rtype, length) for unknown record types

# Details
Reads the standard DBN record header fields:
- Record length
- Record type
- Publisher ID
- Instrument ID  
- Event timestamp

Gracefully handles unknown record types by returning a tuple instead of throwing an error.
"""
function read_record_header(io::IO)
    record_length_units = read(io, UInt8)
    rtype_raw = read(io, UInt8)
    
    # Handle unknown record types first, before trying to read more data
    rtype = try
        RType.T(rtype_raw)
    catch ArgumentError
        # Return special marker for unknown types - don't read more data
        return nothing, rtype_raw, record_length_units
    end
    
    # Always read the standard header fields
    publisher_id = read(io, UInt16)
    instrument_id = read(io, UInt32)
    ts_event = read(io, Int64)
    
    # Store the raw length units value (not converted to bytes)
    RecordHeader(record_length_units, rtype, publisher_id, instrument_id, ts_event)
end

"""
    read_record(decoder::DBNDecoder)

Read a complete record from the DBN stream.

# Arguments
- `decoder::DBNDecoder`: Decoder instance to read from

# Returns
- Record instance (MBOMsg, TradeMsg, etc.): Parsed record, or
- `nothing`: If EOF reached or unknown record type encountered

# Details
Reads the record header and then the appropriate record body based on the record type.
Supports all DBN v3 record types including:
- Market data (MBO, MBP, Trade, OHLCV)
- Status and system messages
- Instrument definitions
- Error and mapping messages

Unknown record types are skipped gracefully.
"""
function read_record(decoder::DBNDecoder)
    if eof(decoder.io)
        return nothing
    end
    
    hd_result = read_record_header(decoder.io)
    
    # Handle unknown record types
    if hd_result isa Tuple
        _, rtype_raw, record_length = hd_result
        # record_length is in 4-byte units; we already consumed length+rtype (2 bytes).
        skip(decoder.io, Int(record_length) * LENGTH_MULTIPLIER - 2)
        return nothing
    end

    hd = hd_result

    # Type-stable dispatch - function barrier eliminates type instability
    return read_record_dispatch(decoder, hd, hd.rtype)
end

# Dispatch to type-stable helpers - each helper has concrete types
@inline function read_record_dispatch(decoder::DBNDecoder, hd::RecordHeader, rtype::RType.T)
    if rtype == RType.MBO_MSG
        return read_mbo_msg(decoder, hd)
    elseif rtype == RType.MBP_0_MSG
        return read_trade_msg(decoder, hd)
    elseif rtype == RType.MBP_1_MSG
        return read_mbp1_msg(decoder, hd)
    elseif rtype == RType.MBP_10_MSG
        return read_mbp10_msg(decoder, hd)
    elseif rtype in (RType.OHLCV_1S_MSG, RType.OHLCV_1M_MSG, RType.OHLCV_1H_MSG, RType.OHLCV_1D_MSG)
        return read_ohlcv_msg(decoder, hd)
    elseif rtype == RType.STATUS_MSG
        return read_status_msg(decoder, hd)
    elseif rtype == RType.INSTRUMENT_DEF_MSG
        return read_instrument_def_msg(decoder, hd)
    elseif rtype == RType.IMBALANCE_MSG
        return read_imbalance_msg(decoder, hd)
    elseif rtype == RType.STAT_MSG
        return read_stat_msg(decoder, hd)
    elseif rtype == RType.ERROR_MSG
        return read_error_msg(decoder, hd)
    elseif rtype == RType.SYMBOL_MAPPING_MSG
        return read_symbol_mapping_msg(decoder, hd)
    elseif rtype == RType.SYSTEM_MSG
        return read_system_msg(decoder, hd)
    elseif rtype == RType.CMBP_1_MSG
        return read_cmbp1_msg(decoder, hd)
    elseif rtype == RType.CBBO_1S_MSG
        return read_cbbo1s_msg(decoder, hd)
    elseif rtype == RType.CBBO_1M_MSG
        return read_cbbo1m_msg(decoder, hd)
    elseif rtype == RType.TCBBO_MSG
        return read_tcbbo_msg(decoder, hd)
    elseif rtype == RType.BBO_1S_MSG
        return read_bbo1s_msg(decoder, hd)
    elseif rtype == RType.BBO_1M_MSG
        return read_bbo1m_msg(decoder, hd)
    else
        # hd.length is in 4-byte units; standard header is 16 bytes already consumed.
        skip(decoder.io, Int(hd.length) * LENGTH_MULTIPLIER - 16)
        return nothing
    end
end

@inline function read_mbo_msg(decoder::DBNDecoder, hd::RecordHeader)
    # For MBO records, we need to read exactly 56 bytes total
    # We've already read: length(1) + rtype(1) + publisher_id(2) + instrument_id(4) + ts_event(8) = 16 bytes
    # Remaining to read: 56 - 16 = 40 bytes
    
    # Based on Rust struct order and empirical evidence:
    ts_recv = read(decoder.io, Int64)      # 8 bytes (positions 16-23)
    order_id = read(decoder.io, UInt64)    # 8 bytes (positions 24-31)
    size = read(decoder.io, UInt32)        # 4 bytes (positions 32-35)
    flags = read(decoder.io, UInt8)        # 1 byte (position 36)
    channel_id = read(decoder.io, UInt8)   # 1 byte (position 37)
    action = unsafe_action(read(decoder.io, UInt8))   # 1 byte (position 38)
    side = unsafe_side(read(decoder.io, UInt8))       # 1 byte (position 39)
    price = read(decoder.io, Int64)        # 8 bytes (positions 40-47)
    ts_in_delta = read(decoder.io, Int32)  # 4 bytes (positions 48-51)
    sequence = read(decoder.io, UInt32)    # 4 bytes (positions 52-55)
    
    return MBOMsg(hd, order_id, price, size, flags, channel_id, action, side, ts_recv, ts_in_delta, sequence)
end

@inline function read_trade_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    return TradeMsg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence)
end

@inline function read_mbp1_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    
    bid_px = read(decoder.io, Int64)
    ask_px = read(decoder.io, Int64)
    bid_sz = read(decoder.io, UInt32)
    ask_sz = read(decoder.io, UInt32)
    bid_ct = read(decoder.io, UInt32)
    ask_ct = read(decoder.io, UInt32)
    levels = BidAskPair(bid_px, ask_px, bid_sz, ask_sz, bid_ct, ask_ct)
    
    return MBP1Msg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence, levels)
end

@inline function read_mbp10_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    
    levels = ntuple(10) do _
        bid_px = read(decoder.io, Int64)
        ask_px = read(decoder.io, Int64)
        bid_sz = read(decoder.io, UInt32)
        ask_sz = read(decoder.io, UInt32)
        bid_ct = read(decoder.io, UInt32)
        ask_ct = read(decoder.io, UInt32)
        BidAskPair(bid_px, ask_px, bid_sz, ask_sz, bid_ct, ask_ct)
    end
    
    return MBP10Msg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence, levels)
end

@inline function read_ohlcv_msg(decoder::DBNDecoder, hd::RecordHeader)
    open = read(decoder.io, Int64)
    high = read(decoder.io, Int64)
    low = read(decoder.io, Int64)
    close = read(decoder.io, Int64)
    volume = read(decoder.io, UInt64)
    return OHLCVMsg(hd, open, high, low, close, volume)
end

@inline function read_status_msg(decoder::DBNDecoder, hd::RecordHeader)
    ts_recv = read(decoder.io, UInt64)
    action = read(decoder.io, UInt16)
    reason = read(decoder.io, UInt16)
    trading_event = read(decoder.io, UInt16)
    is_trading = read(decoder.io, UInt8)
    is_quoting = read(decoder.io, UInt8)
    is_short_sell_restricted = read(decoder.io, UInt8)
    _ = read(decoder.io, 7)  # Reserved (was 5, now 7 to align to 40 bytes total)
    return StatusMsg(hd, ts_recv, action, reason, trading_event, is_trading, is_quoting, is_short_sell_restricted)
end

@inline function read_imbalance_msg(decoder::DBNDecoder, hd::RecordHeader)
    ts_recv = read(decoder.io, UInt64)
    ref_price = read(decoder.io, Int64)
    auction_time = read(decoder.io, UInt64)
    cont_book_clr_price = read(decoder.io, Int64)
    auct_interest_clr_price = read(decoder.io, Int64)
    ssr_filling_price = read(decoder.io, Int64)
    ind_match_price = read(decoder.io, Int64)
    upper_collar = read(decoder.io, Int64)
    lower_collar = read(decoder.io, Int64)
    paired_qty = read(decoder.io, UInt32)
    total_imbalance_qty = read(decoder.io, UInt32)
    market_imbalance_qty = read(decoder.io, UInt32)
    unpaired_qty = read(decoder.io, UInt32)
    auction_type = read(decoder.io, UInt8)
    side = unsafe_side(read(decoder.io, UInt8))
    auction_status = read(decoder.io, UInt8)
    freeze_status = read(decoder.io, UInt8)
    num_extensions = read(decoder.io, UInt8)
    unpaired_side = read(decoder.io, UInt8)
    significant_imbalance = read(decoder.io, UInt8)
    _ = read(decoder.io, 1)  # Reserved
    return ImbalanceMsg(hd, ts_recv, ref_price, auction_time, cont_book_clr_price, auct_interest_clr_price, ssr_filling_price, ind_match_price, upper_collar, lower_collar, paired_qty, total_imbalance_qty, market_imbalance_qty, unpaired_qty, auction_type, side, auction_status, freeze_status, num_extensions, unpaired_side, significant_imbalance)
end

@inline function read_stat_msg(decoder::DBNDecoder, hd::RecordHeader)
    ts_recv = read(decoder.io, UInt64)
    ts_ref = read(decoder.io, UInt64) 
    price = read(decoder.io, Int64)
    # Handle UNDEF values in quantity field - read as UInt64 first
    quantity_raw = read(decoder.io, UInt64)
    quantity = if quantity_raw == 0xffffffffffffffff
        # UNDEF_STAT_QUANTITY - use a special value or convert safely
        typemax(Int64)  
    else
        # Safe conversion for normal values
        quantity_raw <= typemax(Int64) ? Int64(quantity_raw) : typemax(Int64)
    end
    sequence = read(decoder.io, UInt32)
    ts_in_delta = read(decoder.io, Int32)
    stat_type = read(decoder.io, UInt16)
    channel_id = read(decoder.io, UInt16)
    update_action = read(decoder.io, UInt8)
    stat_flags = read(decoder.io, UInt8)
    _ = read(decoder.io, 18)  # Reserved (adjusted for field size changes)
    return StatMsg(hd, ts_recv, ts_ref, price, quantity, sequence, ts_in_delta, stat_type, channel_id, update_action, stat_flags)
end

@inline function read_error_msg(decoder::DBNDecoder, hd::RecordHeader)
    # Read error message string. hd.length is in 4-byte units; subtract the 16-byte header.
    msg_bytes = Int(hd.length) * LENGTH_MULTIPLIER - 16
    if msg_bytes > 0
        err_data = read(decoder.io, msg_bytes)
        # Remove null terminator if present
        null_pos = findfirst(==(0), err_data)
        if null_pos !== nothing
            err_string = String(err_data[1:null_pos-1])
        else
            err_string = String(err_data)
        end
    else
        err_string = ""
    end
    return ErrorMsg(hd, err_string)
end

@inline function read_symbol_mapping_msg(decoder::DBNDecoder, hd::RecordHeader)
    # SymbolMappingMsg layout depends on DBN version. Per the public spec:
    #   v1: stype_in_symbol[22] | stype_out_symbol[22] | padding(4) | start_ts(8) | end_ts(8) = 64
    #       (stype_in/stype_out fields don't exist in v1)
    #   v2+: stype_in(1) | stype_in_symbol[symbol_cstr_len] | stype_out(1) |
    #        stype_out_symbol[symbol_cstr_len] | start_ts(8) | end_ts(8)
    body_size = Int(hd.length) * LENGTH_MULTIPLIER - 16
    if body_size <= 64
        return _read_symbol_mapping_v1(decoder, hd)
    else
        # symbol_cstr_len = (body_size - 1 - 1 - 8 - 8) / 2
        sym_len = (body_size - 18) ÷ 2
        return _read_symbol_mapping_v2(decoder, hd, sym_len)
    end
end

@inline function _trim_cstr(bytes::Vector{UInt8})
    nul = findfirst(==(0), bytes)
    nul === nothing ? bytes : bytes[1:nul-1]
end

@inline function _read_symbol_mapping_v1(decoder::DBNDecoder, hd::RecordHeader)
    in_bytes  = read(decoder.io, 22)
    out_bytes = read(decoder.io, 22)
    _ = read(decoder.io, 4)  # padding to 8-byte alignment for timestamps
    start_ts  = reinterpret(Int64, read(decoder.io, UInt64))
    end_ts    = reinterpret(Int64, read(decoder.io, UInt64))
    # v1 has no stype_in/stype_out bytes; use INSTRUMENT_ID as a neutral default.
    return SymbolMappingMsg(hd,
        SType.INSTRUMENT_ID,  intern_string(decoder, _trim_cstr(in_bytes)),
        SType.INSTRUMENT_ID,  intern_string(decoder, _trim_cstr(out_bytes)),
        start_ts, end_ts,
    )
end

@inline function _read_symbol_mapping_v2(decoder::DBNDecoder, hd::RecordHeader, sym_len::Int)
    stype_in_raw   = read(decoder.io, UInt8)
    in_bytes       = read(decoder.io, sym_len)
    stype_out_raw  = read(decoder.io, UInt8)
    out_bytes      = read(decoder.io, sym_len)
    start_ts       = reinterpret(Int64, read(decoder.io, UInt64))
    end_ts         = reinterpret(Int64, read(decoder.io, UInt64))
    return SymbolMappingMsg(hd,
        SType.T(stype_in_raw),  intern_string(decoder, _trim_cstr(in_bytes)),
        SType.T(stype_out_raw), intern_string(decoder, _trim_cstr(out_bytes)),
        start_ts, end_ts,
    )
end

@inline function read_system_msg(decoder::DBNDecoder, hd::RecordHeader)
    # Read system message fields. hd.length is in 4-byte units; subtract the 16-byte header.
    remaining_bytes = Int(hd.length) * LENGTH_MULTIPLIER - 16
    if remaining_bytes > 0
        # Split remaining data into msg and code (format TBD)
        # For now, read as single message string
        msg_data = read(decoder.io, remaining_bytes)
        null_pos = findfirst(==(0), msg_data)
        if null_pos !== nothing
            msg_string = String(msg_data[1:null_pos-1])
            # If there's more data after null, treat as code
            if null_pos < length(msg_data)
                code_data = msg_data[null_pos+1:end]
                code_null = findfirst(==(0), code_data)
                if code_null !== nothing
                    code_string = String(code_data[1:code_null-1])
                else
                    code_string = String(code_data)
                end
            else
                code_string = ""
            end
        else
            msg_string = String(msg_data)
            code_string = ""
        end
    else
        msg_string = ""
        code_string = ""
    end
    return SystemMsg(hd, msg_string, code_string)
end

@inline function read_cmbp1_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    
    bid_px = read(decoder.io, Int64)
    ask_px = read(decoder.io, Int64)
    bid_sz = read(decoder.io, UInt32)
    ask_sz = read(decoder.io, UInt32)
    bid_ct = read(decoder.io, UInt32)
    ask_ct = read(decoder.io, UInt32)
    levels = BidAskPair(bid_px, ask_px, bid_sz, ask_sz, bid_ct, ask_ct)
    
    return CMBP1Msg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence, levels)
end

@inline function read_cbbo1s_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    
    bid_px = read(decoder.io, Int64)
    ask_px = read(decoder.io, Int64)
    bid_sz = read(decoder.io, UInt32)
    ask_sz = read(decoder.io, UInt32)
    bid_ct = read(decoder.io, UInt32)
    ask_ct = read(decoder.io, UInt32)
    levels = BidAskPair(bid_px, ask_px, bid_sz, ask_sz, bid_ct, ask_ct)
    
    return CBBO1sMsg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence, levels)
end

@inline function read_cbbo1m_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    
    bid_px = read(decoder.io, Int64)
    ask_px = read(decoder.io, Int64)
    bid_sz = read(decoder.io, UInt32)
    ask_sz = read(decoder.io, UInt32)
    bid_ct = read(decoder.io, UInt32)
    ask_ct = read(decoder.io, UInt32)
    levels = BidAskPair(bid_px, ask_px, bid_sz, ask_sz, bid_ct, ask_ct)
    
    return CBBO1mMsg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence, levels)
end

@inline function read_tcbbo_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    
    bid_px = read(decoder.io, Int64)
    ask_px = read(decoder.io, Int64)
    bid_sz = read(decoder.io, UInt32)
    ask_sz = read(decoder.io, UInt32)
    bid_ct = read(decoder.io, UInt32)
    ask_ct = read(decoder.io, UInt32)
    levels = BidAskPair(bid_px, ask_px, bid_sz, ask_sz, bid_ct, ask_ct)
    
    return TCBBOMsg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence, levels)
end

@inline function read_bbo1s_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    
    bid_px = read(decoder.io, Int64)
    ask_px = read(decoder.io, Int64)
    bid_sz = read(decoder.io, UInt32)
    ask_sz = read(decoder.io, UInt32)
    bid_ct = read(decoder.io, UInt32)
    ask_ct = read(decoder.io, UInt32)
    levels = BidAskPair(bid_px, ask_px, bid_sz, ask_sz, bid_ct, ask_ct)
    
    return BBO1sMsg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence, levels)
end

@inline function read_bbo1m_msg(decoder::DBNDecoder, hd::RecordHeader)
    price = read(decoder.io, Int64)
    size = read(decoder.io, UInt32)
    action = unsafe_action(read(decoder.io, UInt8))
    side = unsafe_side(read(decoder.io, UInt8))
    flags = read(decoder.io, UInt8)
    depth = read(decoder.io, UInt8)
    ts_recv = read(decoder.io, Int64)
    ts_in_delta = read(decoder.io, Int32)
    sequence = read(decoder.io, UInt32)
    
    bid_px = read(decoder.io, Int64)
    ask_px = read(decoder.io, Int64)
    bid_sz = read(decoder.io, UInt32)
    ask_sz = read(decoder.io, UInt32)
    bid_ct = read(decoder.io, UInt32)
    ask_ct = read(decoder.io, UInt32)
    levels = BidAskPair(bid_px, ask_px, bid_sz, ask_sz, bid_ct, ask_ct)
    
    return BBO1mMsg(hd, price, size, action, side, flags, depth, ts_recv, ts_in_delta, sequence, levels)
end

@inline function read_instrument_def_msg(decoder::DBNDecoder, hd::RecordHeader)
    start_pos = position(decoder.io)
    record_size_bytes = hd.length * LENGTH_MULTIPLIER
    body_size = record_size_bytes - 16
    if body_size == 384
        return read_instrument_def_v2(decoder, hd)
    else
        return read_instrument_def_v3(decoder, hd)
    end
end
@inline function read_instrument_def_v2(decoder::DBNDecoder, hd::RecordHeader)
    # ===== DBN V2 InstrumentDefMsg =====
    # CRITICAL: In v2, encode_order attributes are COMPLETELY IGNORED!
    # Read ALL fields in exact Rust struct declaration order
    ts_recv = read(decoder.io, Int64)                            # offset 0
    min_price_increment = read(decoder.io, Int64)                # offset 8
    display_factor = read(decoder.io, Int64)                     # offset 16
    expiration = reinterpret(Int64, read(decoder.io, UInt64))    # offset 24
    activation = reinterpret(Int64, read(decoder.io, UInt64))    # offset 32
    high_limit_price = read(decoder.io, Int64)                   # offset 40
    low_limit_price = read(decoder.io, Int64)                    # offset 48
    max_price_variation = read(decoder.io, Int64)                # offset 56
    trading_reference_price = read(decoder.io, Int64)            # offset 64 (v2 only)
    unit_of_measure_qty = read(decoder.io, Int64)                # offset 72
    min_price_increment_amount = read(decoder.io, Int64)         # offset 80
    price_ratio = read(decoder.io, Int64)                        # offset 88
    strike_price = read(decoder.io, Int64)                       # offset 96
    # Int32/UInt32 fields (offsets 104-159)
    inst_attrib_value = read(decoder.io, Int32)                  # offset 104
    underlying_id = read(decoder.io, UInt32)                     # offset 108
    raw_instrument_id = UInt64(read(decoder.io, UInt32))         # offset 112 (u32 in v2, convert to u64)
    market_depth_implied = read(decoder.io, Int32)               # offset 116
    market_depth = read(decoder.io, Int32)                       # offset 120
    market_segment_id = read(decoder.io, UInt32)                 # offset 124
    max_trade_vol = read(decoder.io, UInt32)                     # offset 128
    min_lot_size = read(decoder.io, Int32)                       # offset 132
    min_lot_size_block = read(decoder.io, Int32)                 # offset 136
    min_lot_size_round_lot = read(decoder.io, Int32)             # offset 140
    min_trade_vol = read(decoder.io, UInt32)                     # offset 144
    contract_multiplier = read(decoder.io, Int32)                # offset 148
    decay_quantity = read(decoder.io, Int32)                     # offset 152
    original_contract_size = read(decoder.io, Int32)             # offset 156
    # Int16/UInt16 fields (offsets 160-169)
    trading_reference_date = read(decoder.io, UInt16)            # offset 160 (v2 only)
    appl_id = read(decoder.io, Int16)                            # offset 162
    maturity_year = read(decoder.io, UInt16)                     # offset 164
    decay_start_date = read(decoder.io, UInt16)                  # offset 166
    channel_id = read(decoder.io, UInt16)                        # offset 168
    # String fields in struct declaration order (offsets 170+)
    # Use string interning for repeated values (currencies, exchanges, etc.)
    currency = intern_string(decoder, read(decoder.io, 4))          # offset 170
    settl_currency = intern_string(decoder, read(decoder.io, 4))    # offset 174
    secsubtype = intern_string(decoder, read(decoder.io, 6))        # offset 178
    raw_symbol = intern_string(decoder, read(decoder.io, SYMBOL_CSTR_LEN))  # offset 184
    group = intern_string(decoder, read(decoder.io, 21))            # offset 255
    exchange = intern_string(decoder, read(decoder.io, 5))          # offset 276
    asset = intern_string(decoder, read(decoder.io, 7))             # offset 281 (7 bytes in v2!)
    cfi = intern_string(decoder, read(decoder.io, 7))               # offset 288
    security_type = intern_string(decoder, read(decoder.io, 7))     # offset 295
    unit_of_measure = intern_string(decoder, read(decoder.io, 31))  # offset 302
    underlying = intern_string(decoder, read(decoder.io, 21))       # offset 333
    strike_price_currency = intern_string(decoder, read(decoder.io, 4))  # offset 354
    # Byte fields in struct declaration order (offsets 358+)
    instrument_class_byte = read(decoder.io, UInt8)              # offset 358
    instrument_class = safe_instrument_class(instrument_class_byte)
    match_algorithm_byte = read(decoder.io, UInt8)               # offset 359
    match_algorithm = match_algorithm_byte == 0 ? '\0' : Char(match_algorithm_byte)
    md_security_trading_status = read(decoder.io, UInt8)         # offset 360 (v2 only)
    main_fraction = read(decoder.io, UInt8)                      # offset 361
    price_display_format = read(decoder.io, UInt8)               # offset 362
    settl_price_type = read(decoder.io, UInt8)                   # offset 363 (v2 only)
    sub_fraction = read(decoder.io, UInt8)                       # offset 364
    underlying_product = read(decoder.io, UInt8)                 # offset 365
    security_update_action_byte = read(decoder.io, UInt8)        # offset 366
    security_update_action = security_update_action_byte == 0 ? '\0' : Char(security_update_action_byte)
    maturity_month = read(decoder.io, UInt8)                     # offset 367
    maturity_day = read(decoder.io, UInt8)                       # offset 368
    maturity_week = read(decoder.io, UInt8)                      # offset 369
    user_defined_instrument_byte = read(decoder.io, UInt8)       # offset 370
    user_defined_instrument = user_defined_instrument_byte != 0x00 && user_defined_instrument_byte != UInt8('N')
    contract_multiplier_unit = read(decoder.io, Int8)            # offset 371
    flow_schedule_type = read(decoder.io, Int8)                  # offset 372
    tick_rule = read(decoder.io, UInt8)                          # offset 373
    # v2: remaining bytes are reserved/padding (384 - 374 = 10 bytes)
    skip(decoder.io, 10)
    # V2 has NO leg fields - set ALL to defaults
    leg_price = Int64(0)
    leg_delta = Int64(0)
    leg_count = UInt16(0)
    leg_index = UInt16(0)
    leg_instrument_id = UInt32(0)
    leg_raw_symbol = ""
    leg_instrument_class = InstrumentClass.OTHER  # Default is OTHER, not UNKNOWN_0
    leg_side = Side.NONE
    leg_ratio_price_numerator = Int32(0)
    leg_ratio_price_denominator = Int32(0)
    leg_ratio_qty_numerator = Int32(0)
    leg_ratio_qty_denominator = Int32(0)
    leg_underlying_id = UInt32(0)

    return InstrumentDefMsg(
        hd, ts_recv, min_price_increment, display_factor, expiration, activation,
        high_limit_price, low_limit_price, max_price_variation,
        trading_reference_price, unit_of_measure_qty, min_price_increment_amount,
        price_ratio, inst_attrib_value, underlying_id, raw_instrument_id,
        market_depth_implied, market_depth, market_segment_id, max_trade_vol,
        min_lot_size, min_lot_size_block, min_lot_size_round_lot, min_trade_vol,
        contract_multiplier, decay_quantity, original_contract_size,
        trading_reference_date, appl_id, maturity_year, decay_start_date, channel_id,
        currency, settl_currency, secsubtype, raw_symbol, group, exchange, asset,
        cfi, security_type, unit_of_measure, underlying, strike_price_currency,
        instrument_class, strike_price, match_algorithm, md_security_trading_status,
        main_fraction, price_display_format, settl_price_type, sub_fraction,
        underlying_product, security_update_action, maturity_month, maturity_day,
        maturity_week, user_defined_instrument, contract_multiplier_unit,
        flow_schedule_type, tick_rule, leg_count, leg_index, leg_instrument_id,
        leg_raw_symbol, leg_side, leg_underlying_id, leg_instrument_class,
        leg_ratio_qty_numerator, leg_ratio_qty_denominator, leg_ratio_price_numerator,
        leg_ratio_price_denominator, leg_price, leg_delta
    )
end

@inline function read_instrument_def_v3(decoder::DBNDecoder, hd::RecordHeader)
    # ===== DBN V3 InstrumentDefMsg =====
    # DBN binary records are encoded in the fixed binary field layout.
    # `encode_order` controls text/field ordering, not the binary layout.
    ts_recv = read(decoder.io, Int64)
    min_price_increment = read(decoder.io, Int64)
    display_factor = read(decoder.io, Int64)
    expiration = read(decoder.io, Int64)
    activation = read(decoder.io, Int64)
    high_limit_price = read(decoder.io, Int64)
    low_limit_price = read(decoder.io, Int64)
    max_price_variation = read(decoder.io, Int64)
    unit_of_measure_qty = read(decoder.io, Int64)
    min_price_increment_amount = read(decoder.io, Int64)
    price_ratio = read(decoder.io, Int64)
    strike_price = read(decoder.io, Int64)
    raw_instrument_id = read(decoder.io, UInt64)
    leg_price = read(decoder.io, Int64)
    leg_delta = read(decoder.io, Int64)
    inst_attrib_value = read(decoder.io, Int32)
    underlying_id = read(decoder.io, UInt32)
    market_depth_implied = read(decoder.io, Int32)
    market_depth = read(decoder.io, Int32)
    market_segment_id = read(decoder.io, UInt32)
    max_trade_vol = read(decoder.io, UInt32)
    min_lot_size = read(decoder.io, Int32)
    min_lot_size_block = read(decoder.io, Int32)
    min_lot_size_round_lot = read(decoder.io, Int32)
    min_trade_vol = read(decoder.io, UInt32)
    contract_multiplier = read(decoder.io, Int32)
    decay_quantity = read(decoder.io, Int32)
    original_contract_size = read(decoder.io, Int32)
    leg_instrument_id = read(decoder.io, UInt32)
    leg_ratio_price_numerator = read(decoder.io, Int32)
    leg_ratio_price_denominator = read(decoder.io, Int32)
    leg_ratio_qty_numerator = read(decoder.io, Int32)
    leg_ratio_qty_denominator = read(decoder.io, Int32)
    leg_underlying_id = read(decoder.io, UInt32)
    appl_id = read(decoder.io, Int16)
    maturity_year = read(decoder.io, UInt16)
    decay_start_date = read(decoder.io, UInt16)
    channel_id = read(decoder.io, UInt16)
    leg_count = read(decoder.io, UInt16)
    leg_index = read(decoder.io, UInt16)

    # String fields in struct declaration order.
    currency = intern_string(decoder, read(decoder.io, 4))
    settl_currency = intern_string(decoder, read(decoder.io, 4))
    secsubtype = intern_string(decoder, read(decoder.io, 6))
    raw_symbol = intern_string(decoder, read(decoder.io, SYMBOL_CSTR_LEN))
    group = intern_string(decoder, read(decoder.io, 21))
    exchange = intern_string(decoder, read(decoder.io, 5))
    asset = intern_string(decoder, read(decoder.io, 11))  # 11 bytes in v3!
    cfi = intern_string(decoder, read(decoder.io, 7))
    security_type = intern_string(decoder, read(decoder.io, 7))
    unit_of_measure = intern_string(decoder, read(decoder.io, 31))
    underlying = intern_string(decoder, read(decoder.io, 21))
    strike_price_currency = intern_string(decoder, read(decoder.io, 4))
    leg_raw_symbol = intern_string(decoder, read(decoder.io, SYMBOL_CSTR_LEN))

    # Single-byte fields without encode_order
    instrument_class_byte = read(decoder.io, UInt8)
    instrument_class = safe_instrument_class(instrument_class_byte)
    match_algorithm_byte = read(decoder.io, UInt8)
    match_algorithm = match_algorithm_byte == 0 ? '\0' : Char(match_algorithm_byte)
    main_fraction = read(decoder.io, UInt8)
    price_display_format = read(decoder.io, UInt8)
    sub_fraction = read(decoder.io, UInt8)
    underlying_product = read(decoder.io, UInt8)
    security_update_action_byte = read(decoder.io, UInt8)
    security_update_action = security_update_action_byte == 0 ? '\0' : Char(security_update_action_byte)
    maturity_month = read(decoder.io, UInt8)
    maturity_day = read(decoder.io, UInt8)
    maturity_week = read(decoder.io, UInt8)
    user_defined_instrument_byte = read(decoder.io, UInt8)
    user_defined_instrument = user_defined_instrument_byte != 0x00 && user_defined_instrument_byte != UInt8('N')
    contract_multiplier_unit = read(decoder.io, Int8)
    flow_schedule_type = read(decoder.io, Int8)
    tick_rule = read(decoder.io, UInt8)
    leg_instrument_class_byte = read(decoder.io, UInt8)
    leg_instrument_class = safe_instrument_class(leg_instrument_class_byte)
    leg_side_byte = read(decoder.io, UInt8)
    leg_side = unsafe_side(leg_side_byte)

    # v3: 17 bytes _reserved
    skip(decoder.io, 17)
    # V3 has NO v2-only fields - set to defaults
    trading_reference_price = Int64(0)
    trading_reference_date = UInt16(0)
    md_security_trading_status = UInt8(0)
    settl_price_type = UInt8(0)

    return InstrumentDefMsg(
        hd, ts_recv, min_price_increment, display_factor, expiration, activation,
        high_limit_price, low_limit_price, max_price_variation,
        trading_reference_price, unit_of_measure_qty, min_price_increment_amount,
        price_ratio, inst_attrib_value, underlying_id, raw_instrument_id,
        market_depth_implied, market_depth, market_segment_id, max_trade_vol,
        min_lot_size, min_lot_size_block, min_lot_size_round_lot, min_trade_vol,
        contract_multiplier, decay_quantity, original_contract_size,
        trading_reference_date, appl_id, maturity_year, decay_start_date, channel_id,
        currency, settl_currency, secsubtype, raw_symbol, group, exchange, asset,
        cfi, security_type, unit_of_measure, underlying, strike_price_currency,
        instrument_class, strike_price, match_algorithm, md_security_trading_status,
        main_fraction, price_display_format, settl_price_type, sub_fraction,
        underlying_product, security_update_action, maturity_month, maturity_day,
        maturity_week, user_defined_instrument, contract_multiplier_unit,
        flow_schedule_type, tick_rule, leg_count, leg_index, leg_instrument_id,
        leg_raw_symbol, leg_side, leg_underlying_id, leg_instrument_class,
        leg_ratio_qty_numerator, leg_ratio_qty_denominator, leg_ratio_price_numerator,
        leg_ratio_price_denominator, leg_price, leg_delta
    )
end



# Convenience function
"""
    read_dbn(filename::String)

Convenience function to read all records from a DBN file.

# Arguments
- `filename::String`: Path to the DBN file (compressed or uncompressed)

# Returns
- `Vector`: Array containing all records from the file

# Details
Reads the entire DBN file into memory, automatically handling:
- Compression detection and decompression
- Resource cleanup
- Error recovery for unknown record types

For large files, consider using `DBNStream` for memory-efficient streaming.
For metadata access, use `read_dbn_with_metadata()`.

# Example
```julia
records = read_dbn("data.dbn")
for record in records
    println(typeof(record))
end
```
"""
function read_dbn(filename::String)
    decoder = DBNDecoder(filename)  # This now handles compression automatically

    # Schema-aware fast path: when the metadata's schema maps to a single
    # concrete record type and DBN.jl has a typed reader for it, dispatch
    # to `read_dbn_typed` instead. The typed path returns `Vector{T}` (still
    # a subtype of Vector{<:DBNRecord} for callers that iterate generically)
    # and avoids the per-push Union allocation that dominates GC time on
    # the generic path.
    #
    # If the file's records don't actually match the declared schema (mixed
    # files, files containing only control records like ErrorMsg/SystemMsg
    # under a data-schema label), `read_dbn_typed` raises an
    # `ErrorException`; fall back to the generic loop in that case so
    # `read_dbn`'s historical permissive semantics are preserved.
    T = record_type_for_dbn_schema(decoder.metadata.schema)
    if T !== nothing
        if decoder.io !== decoder.base_io
            close(decoder.io)
        end
        if isa(decoder.base_io, IOStream)
            close(decoder.base_io)
        end
        try
            return read_dbn_typed(filename, T)
        catch e
            isa(e, ErrorException) || rethrow()
            # rtype mismatch — reopen and fall through to generic.
            decoder = DBNDecoder(filename)
        end
    end

    # Pre-allocate records vector
    # Two strategies: exact pre-allocation if limit known, or dynamic with sizehint
    has_exact_limit = decoder.metadata.limit !== nothing && decoder.metadata.limit > 0

    if has_exact_limit
        # EXACT PRE-ALLOCATION: Eliminate all vector growth overhead
        # When limit is known, pre-allocate exact size and use direct indexing
        limit = Int(decoder.metadata.limit)
        records = Vector{DBNRecord}(undef, limit)
        idx = 1

        try
            while idx <= limit && !eof(decoder.io)
                record = read_record(decoder)
                if record !== nothing
                    records[idx] = record
                    idx += 1
                else
                    # Handle case where we hit unknown record types
                    # This is rare but possible
                end
            end

            # Trim if we read fewer records than expected (very rare)
            if idx <= limit
                resize!(records, idx - 1)
            end
        catch e
            # On error, trim to what we successfully read
            resize!(records, idx - 1)
            rethrow(e)
        end
    else
        # DYNAMIC ALLOCATION: Use sizehint! for estimated capacity
        # Estimate based on file size when limit is unknown
        file_size = filesize(filename)
        estimated_count = max(100, div(file_size, 50))

        # Use type-stable union instead of Vector{Any} to eliminate boxing overhead
        records = Vector{DBNRecord}(undef, 0)
        sizehint!(records, estimated_count)

        while !eof(decoder.io)
            record = read_record(decoder)
            if record !== nothing
                push!(records, record)
            end
        end
    end

    # Clean up resources - always close files even if there was an error
    try
        return records
    finally
        if decoder.io !== decoder.base_io
            # Close the TranscodingStream first
            close(decoder.io)
        end
        # Always close the base IO
        if isa(decoder.base_io, IOStream)
            close(decoder.base_io)
        end
        # Force garbage collection to ensure file handles are released on Windows
        # Windows may not immediately release file locks even after close()
        GC.gc()
    end
end

"""
    read_dbn_with_metadata(filename::String)

Read a DBN file and return both metadata and records.

# Arguments
- `filename::String`: Path to the DBN file (compressed or uncompressed)

# Returns
- `Tuple{Metadata, Vector}`: A tuple containing the file metadata and array of all records

# Details
Similar to `read_dbn()` but also returns the file metadata containing dataset information,
schema, timestamp ranges, symbol mappings, and other file properties.

# Example
```julia
metadata, records = read_dbn_with_metadata("data.dbn")
println("Dataset: \$(metadata.dataset)")
println("Schema: \$(metadata.schema)")
println("Records: \$(length(records))")
```
"""
function read_dbn_with_metadata(filename::String)
    decoder = DBNDecoder(filename)  # This now handles compression automatically

    # Schema-aware fast path (same rationale as `read_dbn`): when the metadata
    # schema is type-pure, capture metadata first and then delegate to the
    # typed reader, returning (metadata, Vector{T}) where T is concrete.
    # Falls back to the generic loop on rtype-mismatch (mixed files, etc.).
    T = record_type_for_dbn_schema(decoder.metadata.schema)
    if T !== nothing
        metadata = decoder.metadata
        if decoder.io !== decoder.base_io
            close(decoder.io)
        end
        if isa(decoder.base_io, IOStream)
            close(decoder.base_io)
        end
        try
            return metadata, read_dbn_typed(filename, T)
        catch e
            isa(e, ErrorException) || rethrow()
            decoder = DBNDecoder(filename)
        end
    end

    # Pre-allocate records vector with size hint
    estimated_count = if decoder.metadata.limit !== nothing && decoder.metadata.limit > 0
        Int(decoder.metadata.limit)
    else
        file_size = filesize(filename)
        max(100, div(file_size, 50))
    end

    # Use type-stable union instead of Vector{Any} to eliminate boxing overhead
    records = Vector{DBNRecord}(undef, 0)
    sizehint!(records, estimated_count)

    try
        while !eof(decoder.io)
            record = read_record(decoder)
            if record !== nothing
                push!(records, record)
            end
        end
    finally
        # Clean up resources
        if decoder.io !== decoder.base_io
            # Close the TranscodingStream first
            close(decoder.io)
        end
        # Always close the base IO
        if isa(decoder.base_io, IOStream)
            close(decoder.base_io)
        end
        # Force garbage collection to ensure file handles are released on Windows
        # Windows may not immediately release file locks even after close()
        GC.gc()
    end

    return decoder.metadata, records
end

"""
    read_dbn_typed(filename::String, ::Type{T}) where T -> Vector{T}

Read a DBN file into a type-specific vector, avoiding Union overhead.

# Implementation
This function is now built on top of the optimized `foreach_record` callback API,
which provides near-zero allocation streaming. The eager read pre-allocates the
exact vector size and streams records directly into it.

# Performance
This function provides 5-6x better performance than `read_dbn()` by eliminating
Union type overhead and GC pressure. Use this when you know all records will be
of a single type (e.g., all TradeMsg).

# Arguments
- `filename::String`: Path to DBN file
- `::Type{T}`: Expected record type (e.g., `TradeMsg`, `MBOMsg`)

# Returns
- `Vector{T}`: Type-specific vector of records

# Performance Comparison
- `read_dbn()`: ~3 M rec/s (flexible, supports mixed types)
- `read_dbn_typed()`: ~17 M rec/s (fast, single type only)

# Example
```julia
# 5-6x faster than read_dbn() when schema is known
trades = read_dbn_typed("trades.dbn", TradeMsg)
mbos = read_dbn_typed("mbo.dbn", MBOMsg)
```

# Warning
If the file contains records of different types, this will error.
For mixed-type files, use `read_dbn()` instead.
"""
function read_dbn_typed(filename::String, ::Type{T}) where T
    # Open decoder once and use it for both metadata and streaming
    decoder = DBNDecoder(filename)
    metadata = decoder.metadata
    expected_rtype = _type_to_rtype_stream(T)

    # Pre-allocate exact size if known
    has_exact_limit = metadata.limit !== nothing && metadata.limit > 0

    if has_exact_limit
        # EXACT PRE-ALLOCATION: Best performance path
        # Pre-allocate exact size and use direct indexing
        limit = Int(metadata.limit)
        records = Vector{T}(undef, limit)
        idx = 1

        try
            while idx <= limit && !eof(decoder.io)
                # Read header
                hd_result = read_record_header(decoder.io)

                # Handle unknown record types
                if hd_result isa Tuple
                    _, rtype_raw, record_length = hd_result
                    # record_length is in 4-byte units; we already consumed 2 bytes.
                    skip(decoder.io, Int(record_length) * LENGTH_MULTIPLIER - 2)
                    continue
                end

                hd = hd_result

                # Verify type matches expected
                if hd.rtype != expected_rtype
                    # Special handling for OHLCV variants
                    if T === OHLCVMsg && hd.rtype in (RType.OHLCV_1S_MSG, RType.OHLCV_1M_MSG, RType.OHLCV_1H_MSG, RType.OHLCV_1D_MSG)
                        # OK, continue
                    else
                        error("Expected $(T) (rtype=$(expected_rtype)) but got rtype=$(hd.rtype)")
                    end
                end

                # Read record directly - uses same helpers as streaming
                @inbounds records[idx] = _read_typed_record_stream(decoder, T, hd)
                idx += 1
            end

            # Trim if we read fewer than expected
            if idx <= limit
                resize!(records, idx - 1)
            end
        finally
            # Clean up
            if decoder.io !== decoder.base_io
                close(decoder.io)
            end
            if isa(decoder.base_io, IOStream)
                close(decoder.base_io)
            end
        end
    else
        # DYNAMIC ALLOCATION: Use sizehint for efficiency
        records = Vector{T}()
        file_size = filesize(filename)
        estimated_count = max(100, div(file_size, 50))
        sizehint!(records, estimated_count)

        try
            while !eof(decoder.io)
                hd_result = read_record_header(decoder.io)

                if hd_result isa Tuple
                    _, rtype_raw, record_length = hd_result
                    # record_length is in 4-byte units; we already consumed 2 bytes.
                    skip(decoder.io, Int(record_length) * LENGTH_MULTIPLIER - 2)
                    continue
                end

                hd = hd_result

                if hd.rtype != expected_rtype
                    if T === OHLCVMsg && hd.rtype in (RType.OHLCV_1S_MSG, RType.OHLCV_1M_MSG, RType.OHLCV_1H_MSG, RType.OHLCV_1D_MSG)
                        # OK
                    else
                        error("Expected $(T) (rtype=$(expected_rtype)) but got rtype=$(hd.rtype)")
                    end
                end

                push!(records, _read_typed_record_stream(decoder, T, hd))
            end
        finally
            if decoder.io !== decoder.base_io
                close(decoder.io)
            end
            if isa(decoder.base_io, IOStream)
                close(decoder.base_io)
            end
        end
    end

    return records
end

# Helper: Map Julia type to RType (used for validation)
function _type_to_rtype(::Type{MBOMsg})
    return RType.MBO_MSG
end

function _type_to_rtype(::Type{TradeMsg})
    return RType.MBP_0_MSG  # Trades use MBP-0
end

function _type_to_rtype(::Type{MBP1Msg})
    return RType.MBP_1_MSG
end

function _type_to_rtype(::Type{MBP10Msg})
    return RType.MBP_10_MSG
end

function _type_to_rtype(::Type{OHLCVMsg})
    return RType.OHLCV_MSG
end

function _type_to_rtype(::Type{StatusMsg})
    return RType.STATUS_MSG
end

function _type_to_rtype(::Type{InstrumentDefMsg})
    return RType.INSTRUMENT_DEF_MSG
end

function _type_to_rtype(::Type{ImbalanceMsg})
    return RType.IMBALANCE_MSG
end

function _type_to_rtype(::Type{ErrorMsg})
    return RType.ERROR_MSG
end

function _type_to_rtype(::Type{SymbolMappingMsg})
    return RType.SYMBOL_MAPPING_MSG
end

function _type_to_rtype(::Type{SystemMsg})
    return RType.SYSTEM_MSG
end

function _type_to_rtype(::Type{StatMsg})
    return RType.STATISTICS_MSG
end

# Convenience functions for common schemas
"""
    read_trades(filename::String) -> Vector{TradeMsg}

Fast reader for trade data files. 5-6x faster than `read_dbn()`.
"""
read_trades(filename::String) = read_dbn_typed(filename, TradeMsg)

"""
    read_mbo(filename::String) -> Vector{MBOMsg}

Fast reader for MBO (Market By Order) data files. 5-6x faster than `read_dbn()`.
"""
read_mbo(filename::String) = read_dbn_typed(filename, MBOMsg)

"""
    read_mbp1(filename::String) -> Vector{MBP1Msg}

Fast reader for MBP-1 (top-of-book) data files. 5-6x faster than `read_dbn()`.
"""
read_mbp1(filename::String) = read_dbn_typed(filename, MBP1Msg)

"""
    read_mbp10(filename::String) -> Vector{MBP10Msg}

Fast reader for MBP-10 (10-level depth) data files. 5-6x faster than `read_dbn()`.
"""
read_mbp10(filename::String) = read_dbn_typed(filename, MBP10Msg)

"""
    read_tbbo(filename::String) -> Vector{MBP1Msg}

Fast reader for TBBO (Trade BBO) data files. Uses MBP-1 records. 5-6x faster than `read_dbn()`.
"""
read_tbbo(filename::String) = read_dbn_typed(filename, MBP1Msg)

"""
    read_ohlcv(filename::String) -> Vector{OHLCVMsg}

Fast reader for OHLCV (candlestick) data files. 5-6x faster than `read_dbn()`.
"""
read_ohlcv(filename::String) = read_dbn_typed(filename, OHLCVMsg)

"""
    read_ohlcv_1s(filename::String) -> Vector{OHLCVMsg}

Fast reader for 1-second OHLCV data files. 5-6x faster than `read_dbn()`.
"""
read_ohlcv_1s(filename::String) = read_dbn_typed(filename, OHLCVMsg)

"""
    read_ohlcv_1m(filename::String) -> Vector{OHLCVMsg}

Fast reader for 1-minute OHLCV data files. 5-6x faster than `read_dbn()`.
"""
read_ohlcv_1m(filename::String) = read_dbn_typed(filename, OHLCVMsg)

"""
    read_ohlcv_1h(filename::String) -> Vector{OHLCVMsg}

Fast reader for 1-hour OHLCV data files. 5-6x faster than `read_dbn()`.
"""
read_ohlcv_1h(filename::String) = read_dbn_typed(filename, OHLCVMsg)

"""
    read_ohlcv_1d(filename::String) -> Vector{OHLCVMsg}

Fast reader for 1-day OHLCV data files. 5-6x faster than `read_dbn()`.
"""
read_ohlcv_1d(filename::String) = read_dbn_typed(filename, OHLCVMsg)

# Consolidated/BBO message readers
"""
    read_cmbp1(filename::String) -> Vector{CMBP1Msg}

Fast reader for Consolidated MBP-1 data files. 5-6x faster than `read_dbn()`.
"""
read_cmbp1(filename::String) = read_dbn_typed(filename, CMBP1Msg)

"""
    read_cbbo1s(filename::String) -> Vector{CBBO1sMsg}

Fast reader for Consolidated BBO 1-second data files. 5-6x faster than `read_dbn()`.
"""
read_cbbo1s(filename::String) = read_dbn_typed(filename, CBBO1sMsg)

"""
    read_cbbo1m(filename::String) -> Vector{CBBO1mMsg}

Fast reader for Consolidated BBO 1-minute data files. 5-6x faster than `read_dbn()`.
"""
read_cbbo1m(filename::String) = read_dbn_typed(filename, CBBO1mMsg)

"""
    read_tcbbo(filename::String) -> Vector{TCBBOMsg}

Fast reader for Top Consolidated BBO data files. 5-6x faster than `read_dbn()`.
"""
read_tcbbo(filename::String) = read_dbn_typed(filename, TCBBOMsg)

"""
    read_bbo1s(filename::String) -> Vector{BBO1sMsg}

Fast reader for BBO 1-second data files. 5-6x faster than `read_dbn()`.
"""
read_bbo1s(filename::String) = read_dbn_typed(filename, BBO1sMsg)

"""
    read_bbo1m(filename::String) -> Vector{BBO1mMsg}

Fast reader for BBO 1-minute data files. 5-6x faster than `read_dbn()`.
"""
read_bbo1m(filename::String) = read_dbn_typed(filename, BBO1mMsg)
