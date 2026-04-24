package brrr

// Two-pass fast encoder for an input fragment, independent of input history.
// In the first pass, backward matches and literal bytes are saved into
// buffers. In the second pass, they are emitted into the bitstream using
// prefix codes built from actual command and literal histograms.

import "math/bits"

const twoPassBlockSize = 1 << 17

// sampleRate is the byte sampling interval used by shouldCompress to
// estimate entropy without scanning every byte.
const sampleRate = 43

// numExtraBits maps each command code (0-127) to the number of extra bits
// that follow it in the bitstream.
var numExtraBits = [128]uint{
	0, 0, 0, 0, 0, 0, 1, 1, 2, 2, 3, 3, 4, 4, 5, 5,
	6, 7, 8, 9, 10, 12, 14, 24, 0, 0, 0, 0, 0, 0, 0, 0,
	1, 1, 2, 2, 3, 3, 4, 4, 0, 0, 0, 0, 0, 0, 0, 0,
	1, 1, 2, 2, 3, 3, 4, 4, 5, 5, 6, 7, 8, 9, 10, 24,
	0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0,
	1, 1, 2, 2, 3, 3, 4, 4, 5, 5, 6, 6, 7, 7, 8, 8,
	9, 9, 10, 10, 11, 11, 12, 12, 13, 13, 14, 14, 15, 15, 16, 16,
	17, 17, 18, 18, 19, 19, 20, 20, 21, 21, 22, 22, 23, 23, 24, 24,
}

// insertOffset maps each insert length code (0-23) to the base insert length.
var insertOffset = [24]uint{
	0, 1, 2, 3, 4, 5, 6, 8, 10, 14, 18, 26,
	34, 50, 66, 98, 130, 194, 322, 578, 1090, 2114, 6210, 22594,
}

type twoPassCompressor struct {
	arena      *twoPassArena
	b          *bitWriter
	input      []byte
	table      []uint32
	commandBuf []uint32
	literalBuf []byte
	tableBits  uint
	minMatch   int
	isLast     bool
}

func (c *twoPassCompressor) compress() {
	c.tableBits = uint(bits.Len(uint(len(c.table)))) - 1
	if c.tableBits <= 15 {
		c.minMatch = 4
	} else {
		c.minMatch = 6
	}
	initialBitOffset := c.b.bitOffset

	input := c.input
	pos := 0

	inputSize := len(input)
	for inputSize > 0 {
		blockSize := min(inputSize, twoPassBlockSize)
		commands := c.commandBuf
		literals := c.literalBuf

		numCommands, numLiterals := c.createCommands(
			input, pos, blockSize, inputSize, commands, literals)

		if c.shouldCompress(input[pos:pos+blockSize], numLiterals) {
			c.b.writeMetaBlockHeader(blockSize, false, false)
			// No block splits, no contexts.
			c.b.writeBits(13, 0)
			c.writeCommands(literals[:numLiterals], commands[:numCommands])
		} else {
			// Since we did not find many backward references and the entropy of
			// the data is close to 8 bits, we can simply emit an uncompressed
			// block. This makes compression of uncompressible data about 3x
			// faster.
			c.b.writeUncompressedMetaBlock(input[pos : pos+blockSize])
		}
		pos += blockSize
		inputSize -= blockSize
	}

	// If output is larger than a single uncompressed block, rewrite it.
	if c.b.bitOffset-initialBitOffset > 31+uint(len(input))*8 {
		c.b.rewindTo(initialBitOffset)
		c.b.writeUncompressedMetaBlock(input)
	}

	if c.isLast {
		c.b.writeBits(1, 1) // islast
		c.b.writeBits(1, 1) // isempty
		c.b.byteAlign()
	}
}

// createCommands performs the first pass: scan input for backward matches and
// write insert/copy/distance commands into commandBuf and literal bytes into
// literalBuf. Returns the number of commands and literals produced.
//
// input is the full input buffer; pos is the start of the current block.
// blockSize is the size of the current block; inputSize is the remaining
// input size from pos onward.
func (c *twoPassCompressor) createCommands(
	input []byte, pos, blockSize, inputSize int,
	commands []uint32, literals []byte,
) (numCommands, numLiterals int) {
	if c.minMatch == 6 {
		return c.createCommandsMinMatch6(input, pos, blockSize, inputSize, commands, literals)
	}

	ip := pos
	shift := 64 - c.tableBits
	ipEnd := pos + blockSize
	nextEmit := pos
	lastDistance := -1
	table := c.table
	minMatch := c.minMatch
	cmdPos := 0
	litPos := 0
	var nextHash uint32

	if blockSize < inputMarginBytes {
		goto encodeRemainder
	}

	{
		// For the last block, keep a 16-byte margin so all distances are at
		// most window size - 16. For other blocks, keep a margin of minMatch
		// bytes so we don't go past the block size with a copy.
		lenLimit := min(blockSize-minMatch, inputSize-inputMarginBytes)
		ipLimit := pos + lenLimit

		ip++
		nextHash = hashTwoPass(input[ip:], shift, minMatch)

		for {
			// Step 1: Scan forward looking for a match. Skip bytes
			// heuristically when no matches are found recently.
			skip := uint32(32)
			nextIP := ip
			var candidate int

			for {
				hash := nextHash
				bytesBetweenHashLookups := skip >> 5
				skip++
				ip = nextIP
				nextIP = ip + int(bytesBetweenHashLookups)
				if nextIP > ipLimit {
					goto encodeRemainder
				}
				nextHash = hashTwoPass(input[nextIP:], shift, minMatch)

				candidate = ip - lastDistance
				if candidate >= 0 && candidate < ip &&
					isMatchTwoPass(input[ip:], input[candidate:], minMatch) {
					table[hash] = uint32(ip)
					if ip-candidate <= maxDistance {
						break
					}
					continue
				}

				candidate = int(table[hash])
				table[hash] = uint32(ip)
				if isMatchTwoPass(input[ip:], input[candidate:], minMatch) {
					if ip-candidate <= maxDistance {
						break
					}
					continue
				}
			}

			// Step 2: Emit the found match together with the literal bytes from
			// nextEmit, and then see if we can find a next match immediately
			// afterwards.
			{
				base := ip
				matched := minMatch + matchLen(
					input[candidate+minMatch:], input[ip+minMatch:], ipEnd-ip-minMatch)
				distance := base - candidate
				insert := base - nextEmit
				ip += matched

				cmdPos += encodeInsertLen(commands[cmdPos:], uint(insert))
				copy(literals[litPos:], input[nextEmit:nextEmit+insert])
				litPos += insert
				if distance == lastDistance {
					commands[cmdPos] = 64
					cmdPos++
				} else {
					cmdPos += encodeDistance(commands[cmdPos:], uint(distance))
					lastDistance = distance
				}
				cmdPos += encodeCopyLenLastDistance(commands[cmdPos:], uint(matched))

				nextEmit = ip
				if ip >= ipLimit {
					goto encodeRemainder
				}

				candidate = c.updateHashTableTwoPass(input, table, ip, shift, minMatch, 0)
			}

			// Try to find another match immediately.
			for ip-candidate <= maxDistance &&
				isMatchTwoPass(input[ip:], input[candidate:], minMatch) {
				base := ip
				matched := minMatch + matchLen(
					input[candidate+minMatch:], input[ip+minMatch:], ipEnd-ip-minMatch)
				ip += matched
				lastDistance = base - candidate
				cmdPos += encodeCopyLen(commands[cmdPos:], uint(matched))
				cmdPos += encodeDistance(commands[cmdPos:], uint(lastDistance))

				nextEmit = ip
				if ip >= ipLimit {
					goto encodeRemainder
				}

				candidate = c.updateHashTableTwoPass(input, table, ip, shift, minMatch, 2)
			}

			ip++
			nextHash = hashTwoPass(input[ip:], shift, minMatch)
		}
	} // close block scope for ipLimit, lenLimit

encodeRemainder:
	// Emit the remaining bytes as literals.
	if nextEmit < ipEnd {
		insert := ipEnd - nextEmit
		cmdPos += encodeInsertLen(commands[cmdPos:], uint(insert))
		copy(literals[litPos:], input[nextEmit:ipEnd])
		litPos += insert
	}
	return cmdPos, litPos
}

// createCommandsMinMatch6 is the quality-1 large-table path. Keeping the
// 6-byte minimum match as a constant removes minMatch branches from the hot
// scan and hash-table update loops used for real large inputs.
func (c *twoPassCompressor) createCommandsMinMatch6(
	input []byte, pos, blockSize, inputSize int,
	commands []uint32, literals []byte,
) (numCommands, numLiterals int) {
	const minMatch = 6

	ip := pos
	shift := 64 - c.tableBits
	ipEnd := pos + blockSize
	nextEmit := pos
	lastDistance := -1
	table := c.table
	cmdPos := 0
	litPos := 0
	var nextHash uint32

	if blockSize < inputMarginBytes {
		goto encodeRemainder
	}

	{
		// For the last block, keep a 16-byte margin so all distances are at
		// most window size - 16. For other blocks, keep a margin of minMatch
		// bytes so we don't go past the block size with a copy.
		lenLimit := min(blockSize-minMatch, inputSize-inputMarginBytes)
		ipLimit := pos + lenLimit

		ip++
		nextHash = hashTwoPass6At(input, uint(ip), shift)

		for {
			// Step 1: Scan forward looking for a match. Skip bytes
			// heuristically when no matches are found recently.
			skip := uint32(32)
			nextIP := ip
			var candidate int

			for {
				hash := nextHash
				bytesBetweenHashLookups := skip >> 5
				skip++
				ip = nextIP
				nextIP = ip + int(bytesBetweenHashLookups)
				if nextIP > ipLimit {
					goto encodeRemainder
				}
				nextHash = hashTwoPass6At(input, uint(nextIP), shift)

				candidate = ip - lastDistance
				if candidate >= 0 && candidate < ip &&
					isMatchTwoPass6At(input, uint(ip), uint(candidate)) {
					table[hash] = uint32(ip)
					if ip-candidate <= maxDistance {
						break
					}
					continue
				}

				candidate = int(table[hash])
				table[hash] = uint32(ip)
				if isMatchTwoPass6At(input, uint(ip), uint(candidate)) {
					if ip-candidate <= maxDistance {
						break
					}
					continue
				}
			}

			// Step 2: Emit the found match together with the literal bytes from
			// nextEmit, and then see if we can find a next match immediately
			// afterwards.
			{
				base := ip
				matched := minMatch + matchLenAt(
					input, uint(candidate+minMatch), uint(ip+minMatch), ipEnd-ip-minMatch)
				distance := base - candidate
				insert := base - nextEmit
				ip += matched

				cmdPos += encodeInsertLen(commands[cmdPos:], uint(insert))
				copy(literals[litPos:], input[nextEmit:nextEmit+insert])
				litPos += insert
				if distance == lastDistance {
					commands[cmdPos] = 64
					cmdPos++
				} else {
					cmdPos += encodeDistance(commands[cmdPos:], uint(distance))
					lastDistance = distance
				}
				cmdPos += encodeCopyLenLastDistance(commands[cmdPos:], uint(matched))

				nextEmit = ip
				if ip >= ipLimit {
					goto encodeRemainder
				}

				candidate = c.updateHashTableTwoPass6(input, table, ip, shift)
			}

			// Try to find another match immediately.
			for ip-candidate <= maxDistance &&
				isMatchTwoPass6At(input, uint(ip), uint(candidate)) {
				base := ip
				matched := minMatch + matchLenAt(
					input, uint(candidate+minMatch), uint(ip+minMatch), ipEnd-ip-minMatch)
				ip += matched
				lastDistance = base - candidate
				cmdPos += encodeCopyLen(commands[cmdPos:], uint(matched))
				cmdPos += encodeDistance(commands[cmdPos:], uint(lastDistance))

				nextEmit = ip
				if ip >= ipLimit {
					goto encodeRemainder
				}

				candidate = c.updateHashTableTwoPass6(input, table, ip, shift)
			}

			ip++
			nextHash = hashTwoPass6At(input, uint(ip), shift)
		}
	} // close block scope for ipLimit, lenLimit

encodeRemainder:
	// Emit the remaining bytes as literals.
	if nextEmit < ipEnd {
		insert := ipEnd - nextEmit
		cmdPos += encodeInsertLen(commands[cmdPos:], uint(insert))
		copy(literals[litPos:], input[nextEmit:ipEnd])
		litPos += insert
	}
	return cmdPos, litPos
}

// updateHashTableTwoPass updates the hash table with positions from the last
// copy and returns the next candidate position.
//
// thirdOffset controls the byte offset used for hashing position ip-1.
// The C reference uses offset 0 after the first match (Step 2) and offset 2
// in the consecutive-match loop.
func (c *twoPassCompressor) updateHashTableTwoPass(input []byte, table []uint32, ip int, shift uint, minMatch int, thirdOffset uint) int {
	var curHash uint32
	if minMatch == 4 {
		inputBytes := loadU64LE(input, uint(ip-3))
		curHash = hashBytesAtOffsetTwoPass(inputBytes, 3, shift, minMatch)
		prevHash := hashBytesAtOffsetTwoPass(inputBytes, 0, shift, minMatch)
		table[prevHash] = uint32(ip - 3)
		prevHash = hashBytesAtOffsetTwoPass(inputBytes, 1, shift, minMatch)
		table[prevHash] = uint32(ip - 2)
		prevHash = hashBytesAtOffsetTwoPass(inputBytes, thirdOffset, shift, minMatch)
		table[prevHash] = uint32(ip - 1)
	} else {
		inputBytes := loadU64LE(input, uint(ip-5))
		prevHash := hashBytesAtOffsetTwoPass(inputBytes, 0, shift, minMatch)
		table[prevHash] = uint32(ip - 5)
		prevHash = hashBytesAtOffsetTwoPass(inputBytes, 1, shift, minMatch)
		table[prevHash] = uint32(ip - 4)
		prevHash = hashBytesAtOffsetTwoPass(inputBytes, 2, shift, minMatch)
		table[prevHash] = uint32(ip - 3)
		inputBytes = loadU64LE(input, uint(ip-2))
		curHash = hashBytesAtOffsetTwoPass(inputBytes, 2, shift, minMatch)
		prevHash = hashBytesAtOffsetTwoPass(inputBytes, 0, shift, minMatch)
		table[prevHash] = uint32(ip - 2)
		prevHash = hashBytesAtOffsetTwoPass(inputBytes, 1, shift, minMatch)
		table[prevHash] = uint32(ip - 1)
	}

	candidate := int(table[curHash])
	table[curHash] = uint32(ip)
	return candidate
}

func (c *twoPassCompressor) updateHashTableTwoPass6(input []byte, table []uint32, ip int, shift uint) int {
	inputBytes := loadU64LE(input, uint(ip-5))
	prevHash := hashBytesAtOffsetTwoPass6(inputBytes, 0, shift)
	table[prevHash] = uint32(ip - 5)
	prevHash = hashBytesAtOffsetTwoPass6(inputBytes, 1, shift)
	table[prevHash] = uint32(ip - 4)
	prevHash = hashBytesAtOffsetTwoPass6(inputBytes, 2, shift)
	table[prevHash] = uint32(ip - 3)
	inputBytes = loadU64LE(input, uint(ip-2))
	curHash := hashBytesAtOffsetTwoPass6(inputBytes, 2, shift)
	prevHash = hashBytesAtOffsetTwoPass6(inputBytes, 0, shift)
	table[prevHash] = uint32(ip - 2)
	prevHash = hashBytesAtOffsetTwoPass6(inputBytes, 1, shift)
	table[prevHash] = uint32(ip - 1)

	candidate := int(table[curHash])
	table[curHash] = uint32(ip)
	return candidate
}

// writeCommands performs the second pass: build prefix codes from the actual
// histograms and write commands and literals to the bitstream.
func (c *twoPassCompressor) writeCommands(literals []byte, commands []uint32) {
	s := c.arena

	s.resetHistograms()

	// Build literal histogram and Huffman code.
	for _, lit := range literals {
		s.litHisto[lit]++
	}
	c.b.buildAndWriteHuffmanTreeFast(s.tree[:], s.litHisto[:],
		uint(len(literals)), 8, s.litDepth[:], s.litBits[:])

	// Build command histogram and Huffman code.
	for _, cmd := range commands {
		code := cmd & 0xFF
		s.cmdHisto[code]++
	}
	// Ensure some baseline counts for codes that must exist.
	s.cmdHisto[1]++
	s.cmdHisto[2]++
	s.cmdHisto[64]++
	s.cmdHisto[84]++
	s.buildAndWriteCommandPrefixCode(c.b)

	// Emit commands and interleaved literals.
	litIdx := 0
	for _, cmd := range commands {
		code := cmd & 0xFF
		extra := cmd >> 8
		cmdDepth := uint(s.cmdDepth[code])
		c.b.writeBits(cmdDepth+numExtraBits[code], uint64(s.cmdBits[code])|uint64(extra)<<cmdDepth)
		if code < 24 {
			insert := insertOffset[code] + uint(extra)
			for range insert {
				lit := literals[litIdx]
				c.b.writeBits(uint(s.litDepth[lit]), uint64(s.litBits[lit]))
				litIdx++
			}
		}
	}
}

// shouldCompress decides whether to use compressed or uncompressed mode
// for the given block.
func (c *twoPassCompressor) shouldCompress(input []byte, numLiterals int) bool {
	corpusSize := float64(len(input))
	if float64(numLiterals) < 0.98*corpusSize {
		return true
	}
	maxTotalBitCost := corpusSize * 8 * 0.98 / sampleRate
	s := c.arena
	s.litHisto = [256]uint32{}
	for i := 0; i < len(input); i += sampleRate {
		s.litHisto[input[i]]++
	}
	return bitsEntropy(s.litHisto[:]) < maxTotalBitCost
}

// TODO: take *encoder instead of *bitWriter
// compressFragmentTwoPass compresses the input as one or more complete
// meta-blocks using two-pass processing and writes them to the bitstream.
// If isLast is true, an additional empty last meta-block is emitted.
//
// The arena s is used for scratch space.
//
// commandBuf and literalBuf must each have capacity for at least
// twoPassBlockSize elements. table must be zeroed on the first call.
// Its length must be a power of two.
func compressFragmentTwoPass(
	s *twoPassArena,
	input []byte,
	isLast bool,
	commandBuf []uint32,
	literalBuf []byte,
	table []uint32,
	b *bitWriter,
) {
	c := &twoPassCompressor{
		arena:      s,
		b:          b,
		input:      input,
		table:      table,
		commandBuf: commandBuf,
		literalBuf: literalBuf,
		isLast:     isLast,
	}
	c.compress()
}

// hashTwoPass computes a hash of minMatch bytes starting at p,
// shifted right by shift bits (64 - tableBits).
func hashTwoPass(p []byte, shift uint, minMatch int) uint32 {
	h := (loadU64LE(p, 0) << uint(((8 - minMatch) * 8))) * hashMul32
	return uint32(h >> shift)
}

// hashTwoPass6At computes a 6-byte hash of input[i:], shifted right by
// shift bits (64 - tableBits). Taking the raw byte slice and index avoids
// the sub-slice bounds check at the call site in the inner scan loop.
func hashTwoPass6At(input []byte, i, shift uint) uint32 {
	h := (loadU64LE(input, i) << 16) * hashMul32
	return uint32(h >> shift)
}

// hashBytesAtOffsetTwoPass computes a hash of minMatch bytes within a
// 64-bit value, starting at the given byte offset.
func hashBytesAtOffsetTwoPass(v uint64, offset, shift uint, minMatch int) uint32 {
	h := ((v >> (8 * offset)) << uint((8-minMatch)*8)) * hashMul32
	return uint32(h >> shift)
}

func hashBytesAtOffsetTwoPass6(v uint64, offset, shift uint) uint32 {
	h := ((v >> (8 * offset)) << 16) * hashMul32
	return uint32(h >> shift)
}

// isMatchTwoPass returns true if the first minMatch bytes of a and b are equal.
func isMatchTwoPass(a, b []byte, minMatch int) bool {
	if loadU32LE(a, 0) != loadU32LE(b, 0) {
		return false
	}
	if minMatch == 4 {
		return true
	}
	return a[4] == b[4] && a[5] == b[5]
}

// isMatchTwoPass6At compares 6 bytes of input at positions a and b. Taking
// the raw byte slice and indices avoids the sub-slice bounds check at the
// call site in the inner scan loop.
func isMatchTwoPass6At(input []byte, a, b uint) bool {
	return (loadU64LE(input, a)^loadU64LE(input, b))<<16 == 0
}

// encodeInsertLen encodes an insert length command into commands and returns
// the number of command slots used (always 1).
func encodeInsertLen(commands []uint32, insertLen uint) int {
	switch {
	case insertLen < 6:
		commands[0] = uint32(insertLen)
	case insertLen < 130:
		tail := insertLen - 2
		nbits := uint(bits.Len(tail)) - 2
		prefix := tail >> nbits
		inscode := (nbits << 1) + prefix + 2
		extra := tail - (prefix << nbits)
		commands[0] = uint32(inscode) | uint32(extra)<<8
	case insertLen < 2114:
		tail := insertLen - 66
		nbits := uint(bits.Len(tail)) - 1
		code := nbits + 10
		extra := tail - (1 << nbits)
		commands[0] = uint32(code) | uint32(extra)<<8
	case insertLen < 6210:
		extra := insertLen - 2114
		commands[0] = 21 | uint32(extra)<<8
	case insertLen < 22594:
		extra := insertLen - 6210
		commands[0] = 22 | uint32(extra)<<8
	default:
		extra := insertLen - 22594
		commands[0] = 23 | uint32(extra)<<8
	}
	return 1
}

// encodeCopyLen encodes a copy length command into commands and returns
// the number of command slots used (always 1).
func encodeCopyLen(commands []uint32, copyLen uint) int {
	switch {
	case copyLen < 10:
		commands[0] = uint32(copyLen + 38)
	case copyLen < 134:
		tail := copyLen - 6
		nbits := uint(bits.Len(tail)) - 2
		prefix := tail >> nbits
		code := (nbits << 1) + prefix + 44
		extra := tail - (prefix << nbits)
		commands[0] = uint32(code) | uint32(extra)<<8
	case copyLen < 2118:
		tail := copyLen - 70
		nbits := uint(bits.Len(tail)) - 1
		code := nbits + 52
		extra := tail - (1 << nbits)
		commands[0] = uint32(code) | uint32(extra)<<8
	default:
		extra := copyLen - 2118
		commands[0] = 63 | uint32(extra)<<8
	}
	return 1
}

// encodeCopyLenLastDistance encodes a copy-with-last-distance command into
// commands and returns the number of command slots used (1 or 2).
func encodeCopyLenLastDistance(commands []uint32, copyLen uint) int {
	switch {
	case copyLen < 12:
		commands[0] = uint32(copyLen + 20)
		return 1
	case copyLen < 72:
		tail := copyLen - 8
		nbits := uint(bits.Len(tail)) - 2
		prefix := tail >> nbits
		code := (nbits << 1) + prefix + 28
		extra := tail - (prefix << nbits)
		commands[0] = uint32(code) | uint32(extra)<<8
		return 1
	case copyLen < 136:
		tail := copyLen - 8
		code := (tail >> 5) + 54
		extra := tail & 31
		commands[0] = uint32(code) | uint32(extra)<<8
		commands[1] = 64
		return 2
	case copyLen < 2120:
		tail := copyLen - 72
		nbits := uint(bits.Len(tail)) - 1
		code := nbits + 52
		extra := tail - (1 << nbits)
		commands[0] = uint32(code) | uint32(extra)<<8
		commands[1] = 64
		return 2
	default:
		extra := copyLen - 2120
		commands[0] = 63 | uint32(extra)<<8
		commands[1] = 64
		return 2
	}
}

// encodeDistance encodes a distance command into commands and returns
// the number of command slots used (always 1).
func encodeDistance(commands []uint32, distance uint) int {
	d := distance + 3
	nbits := uint(bits.Len(d)) - 2
	prefix := (d >> nbits) & 1
	offset := (2 + prefix) << nbits
	distcode := 2*(nbits-1) + prefix + 80
	extra := d - offset
	commands[0] = uint32(distcode) | uint32(extra)<<8
	return 1
}
