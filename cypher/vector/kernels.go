package vector

import "math"

// float32 kernels for the exhaustive vector search. They are written with eight
// independent accumulators: a single running sum makes every addition wait for
// the previous one, and splitting it lets the CPU overlap them. Measured on a
// 100,000 x 384 scan this is 3.3x faster than the naive loop, in plain Go with
// no assembly. The sums are accumulated in a different order from a sequential
// loop, so results differ from it by normal float rounding.
//
// vector_distance() and vector.similarity.* keep their float64 arithmetic; these
// kernels serve the search, where only the ranking matters.

// Dot32 returns the dot product of a and b, which must have equal length.
func Dot32(a, b []float32) float32 {
	b = b[:len(a)]
	var s0, s1, s2, s3, s4, s5, s6, s7 float32
	n := len(a) &^ 7
	i := 0
	for ; i < n; i += 8 {
		s0 += a[i] * b[i]
		s1 += a[i+1] * b[i+1]
		s2 += a[i+2] * b[i+2]
		s3 += a[i+3] * b[i+3]
		s4 += a[i+4] * b[i+4]
		s5 += a[i+5] * b[i+5]
		s6 += a[i+6] * b[i+6]
		s7 += a[i+7] * b[i+7]
	}
	for ; i < len(a); i++ {
		s0 += a[i] * b[i]
	}
	return (s0 + s1) + (s2 + s3) + ((s4 + s5) + (s6 + s7))
}

// SquaredL2 returns the squared Euclidean distance between a and b.
func SquaredL2(a, b []float32) float32 {
	b = b[:len(a)]
	var s0, s1, s2, s3, s4, s5, s6, s7 float32
	n := len(a) &^ 7
	i := 0
	for ; i < n; i += 8 {
		d0 := a[i] - b[i]
		d1 := a[i+1] - b[i+1]
		d2 := a[i+2] - b[i+2]
		d3 := a[i+3] - b[i+3]
		d4 := a[i+4] - b[i+4]
		d5 := a[i+5] - b[i+5]
		d6 := a[i+6] - b[i+6]
		d7 := a[i+7] - b[i+7]
		s0 += d0 * d0
		s1 += d1 * d1
		s2 += d2 * d2
		s3 += d3 * d3
		s4 += d4 * d4
		s5 += d5 * d5
		s6 += d6 * d6
		s7 += d7 * d7
	}
	for ; i < len(a); i++ {
		d := a[i] - b[i]
		s0 += d * d
	}
	return (s0 + s1) + (s2 + s3) + ((s4 + s5) + (s6 + s7))
}

// Norm32 returns the Euclidean norm of a.
func Norm32(a []float32) float32 { return float32(math.Sqrt(float64(Dot32(a, a)))) }

// Normalize32 scales a to unit length in place and reports whether it could
// (a zero vector cannot be normalised and is left as it is).
func Normalize32(a []float32) bool {
	n := Norm32(a)
	if n == 0 {
		return false
	}
	inv := 1 / n
	for i := range a {
		a[i] *= inv
	}
	return true
}

// Cosine32 returns the cosine similarity of a and b, or ok=false if either is a
// zero vector.
func Cosine32(a, b []float32) (cos float32, ok bool) {
	na, nb := Norm32(a), Norm32(b)
	if na == 0 || nb == 0 {
		return 0, false
	}
	return Dot32(a, b) / (na * nb), true
}
