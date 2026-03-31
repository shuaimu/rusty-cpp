# Rust-to-C++ Transpilation: Feasibility Analysis

## Core Principle: Forward Correctness Guarantee

**If valid Rust compiles, the transpiled C++ must compile and produce the same result.** This is the fundamental guarantee of the transpiler. If a Rust program passes `rustc` (type checking, borrow checking, lifetime checking), then the generated C++ code is guaranteed to compile and behave identically at runtime.

**The reverse is explicitly not guaranteed.** If transpiled C++ happens to compile and run, that does not imply the original Rust source was valid. C++ is more permissive than Rust — it accepts programs that Rust would reject (use-after-move, data races, dangling references, etc.). The transpiler is a one-way correctness bridge: Rust's safety guarantees flow forward into the C++ output, but C++'s permissiveness does not flow backward to validate Rust source.

In other words: Rust is the source of truth for correctness. The transpiler preserves semantics, not the other way around.

---

## Executive Summary

C++ is *almost* a superset of Rust in terms of expressible semantics — both are systems languages with value semantics, deterministic destruction, zero-cost abstractions, and compile-time generics. This makes Rust-to-C++ transpilation broadly feasible, with most language constructs having direct or near-direct mappings. The hard parts are the **trait system** (Rust's core abstraction), **enums with data** (algebraic data types), **pattern matching**, and **lifetime annotations** (which have no C++ equivalent but can be erased in the output). This document maps every major Rust construct to its C++ equivalent, flags the non-obvious cases, and proposes solutions.

---

## 1. Direct Mappings (Straightforward)

These Rust constructs map 1:1 or nearly 1:1 to C++.

### 1.1 Primitive Types

| Rust | C++ |
|------|-----|
| `i8, i16, i32, i64, i128` | `int8_t, int16_t, int32_t, int64_t, __int128` |
| `u8, u16, u32, u64, u128` | `uint8_t, uint16_t, uint32_t, uint64_t, unsigned __int128` |
| `f32, f64` | `float, double` |
| `bool` | `bool` |
| `char` (Unicode scalar) | `char32_t` (note: Rust `char` is 4 bytes, not 1) |
| `usize, isize` | `size_t, ptrdiff_t` |
| `()` (unit) | `void` (return) / empty struct (value context) |
| `!` (never) | `[[noreturn]]` (on functions) |

### 1.2 Variables and Mutability

```rust
let x = 5;           // immutable binding
let mut y = 10;      // mutable binding
const Z: i32 = 42;   // compile-time constant
static S: i32 = 99;  // static variable
```

```cpp
const auto x = 5;         // const by default
auto y = 10;               // mutable
constexpr int32_t Z = 42;  // compile-time constant
static int32_t S = 99;     // static variable (note: not thread-safe init in general)
```

**Key insight**: Rust defaults to immutable, C++ defaults to mutable. The transpiler should emit `const` for all non-`mut` bindings.

### 1.3 Functions

```rust
fn add(a: i32, b: i32) -> i32 {
    a + b   // implicit return
}
```

```cpp
int32_t add(int32_t a, int32_t b) {
    return a + b;  // explicit return needed
}
```

**Note**: Rust's expression-based returns (`a + b` without semicolon) need to be converted to explicit `return` statements. This is a straightforward AST transformation — identify the tail expression of each block.

### 1.4 Control Flow

| Rust | C++ |
|------|-----|
| `if / else if / else` | `if / else if / else` |
| `loop { }` | `while (true) { }` |
| `while cond { }` | `while (cond) { }` |
| `for x in iter` | `for (auto& x : iter)` (range-based) |
| `break` / `continue` | `break` / `continue` |
| `break value` (from loop) | Requires variable + break (see §3.5) |
| `return` | `return` |

### 1.5 References and Borrowing

```rust
fn read(x: &i32) -> i32 { *x }
fn write(x: &mut i32) { *x = 42; }
```

```cpp
int32_t read(const int32_t& x) { return x; }  // no deref needed
void write(int32_t& x) { x = 42; }
```

#### The Rebinding Problem

C++ references **cannot be rebound** — this is a critical semantic mismatch. Rust references behave more like non-null pointers:

```rust
let x = 5;
let y = 10;
let mut r = &x;  // r refers to x
r = &y;           // r now refers to y — REBINDING
```

```cpp
// WRONG — C++ reference version:
int& r = x;
r = y;   // assigns y's value into x, does NOT rebind r!

// CORRECT — use pointer:
const int* r = &x;
r = &y;  // rebinds r to point at y
```

#### Transpilation Strategy: Static Analysis of Rebinding

The transpiler should analyze whether a reference binding is ever reassigned. If not, it can safely emit a C++ reference (more idiomatic, zero overhead). If rebinding occurs, it must fall back to a pointer.

**Step 1**: For each `let mut r: &T` binding, scan all subsequent assignments to `r` in the same scope.

**Step 2**: Choose output based on the result:

```rust
// Case 1: No rebinding — emit C++ reference
let mut r = &x;
println!("{}", r);  // r is never reassigned
```
```cpp
const int& r = x;            // safe: never rebound
std::println("{}", r);
```

```rust
// Case 2: Rebinding detected — emit pointer
let mut r = &x;
r = &y;              // rebinding!
println!("{}", *r);
```
```cpp
const int* r = &x;           // must use pointer
r = &y;                       // rebinding works
std::println("{}", *r);
```

**Decision table**:

| Rust | Rebound? | C++ output |
|------|----------|------------|
| `let r: &T = ...` | N/A (immutable binding) | `const T& r = ...` |
| `let r: &mut T = ...` | N/A (immutable binding) | `T& r = ...` |
| `let mut r: &T = ...` | No | `const T& r = ...` |
| `let mut r: &T = ...` | Yes | `const T* r = &...` |
| `let mut r: &mut T = ...` | No | `T& r = ...` |
| `let mut r: &mut T = ...` | Yes | `T* r = &...` |
| `&T` (function param) | No (typical) | `const T&` |
| `&mut T` (function param) | No (typical) | `T&` |
| `*const T` | — | `const T*` |
| `*mut T` | — | `T*` |

This produces the most idiomatic C++ output — references when possible, pointers only when necessary. The analysis is trivial since Rust's scoping rules make it a simple scan of assignments within the binding's scope.

**Key insight**: Rust's `&T` is a shared (immutable) reference and `&mut T` is an exclusive (mutable) reference. The borrow checker rules are erased in the C++ output (they were enforced at the Rust level). Auto-deref (`*r` in Rust when using pointers) also needs adjustment: C++ references auto-deref, C++ pointers need explicit `*` or `->`.

### 1.6 Structs

```rust
struct Point {
    x: f64,
    y: f64,
}

impl Point {
    fn new(x: f64, y: f64) -> Self { Point { x, y } }
    fn distance(&self, other: &Point) -> f64 {
        ((self.x - other.x).powi(2) + (self.y - other.y).powi(2)).sqrt()
    }
}
```

```cpp
struct Point {
    double x;
    double y;

    static Point new_(double x, double y) { return Point{x, y}; }
    double distance(const Point& other) const {
        return std::sqrt(std::pow(x - other.x, 2) + std::pow(y - other.y, 2));
    }
};
```

| Rust method receiver | C++ equivalent |
|----------------------|----------------|
| `&self` | `const` method |
| `&mut self` | non-const method |
| `self` (by value) | method taking `*this` by value (C++23 explicit object) or free function |
| `Self` (associated fn) | `static` method |

### 1.7 Ownership and Move Semantics

```rust
let a = String::from("hello");
let b = a;   // a is moved, no longer usable
```

```cpp
auto a = std::string("hello");
auto b = std::move(a);  // explicit std::move needed
// a is in valid-but-unspecified state
```

**Key difference**: Rust moves are implicit and destructive (source becomes inaccessible). C++ moves are explicit (`std::move`) and the source remains in a valid-but-unspecified state. The transpiler should insert `std::move` wherever Rust does a move, and the borrow-checker guarantees (enforced on the Rust side) ensure the moved-from value is never accessed.

### 1.8 Smart Pointers

The transpiler maps directly to rusty-cpp wrappers (in `include/rusty/`), which mirror Rust's API surface and are analyzable by the rusty-cpp checker. This closes the loop: Rust → transpile → C++ → verify with rusty-cpp.

| Rust | C++ |
|------|-----|
| `Box<T>` | `rusty::Box<T>` |
| `Rc<T>` | `rusty::Rc<T>` |
| `Arc<T>` | `rusty::Arc<T>` |
| `Weak<T>` (from Rc/Arc) | `rusty::Weak<T>` |
| `Cell<T>` | `rusty::Cell<T>` |
| `RefCell<T>` | `rusty::RefCell<T>` |
| `UnsafeCell<T>` | `rusty::UnsafeCell<T>` |
| `MaybeUninit<T>` | `rusty::MaybeUninit<T>` |

### 1.9 Strings

| Rust | C++ |
|------|-----|
| `String` | `rusty::String` |
| `&str` | `rusty::str` / `std::string_view` |

### 1.10 Collections

| Rust | C++ |
|------|-----|
| `Vec<T>` | `rusty::Vec<T>` |
| `HashMap<K,V>` | `rusty::HashMap<K,V>` |
| `BTreeMap<K,V>` | `rusty::BTreeMap<K,V>` |
| `HashSet<T>` | `rusty::HashSet<T>` |
| `BTreeSet<T>` | `rusty::BTreeSet<T>` |
| `VecDeque<T>` | `rusty::VecDeque<T>` |

### 1.11 Error Handling

| Rust | C++ |
|------|-----|
| `Option<T>` | `rusty::Option<T>` |
| `Result<T, E>` | `rusty::Result<T, E>` |
| `panic!()` | `std::abort()` or `throw` (configurable) |
| `unwrap()` | `.unwrap()` |
| `?` operator | See §3.4 |

### 1.12 Concurrency Primitives

| Rust | C++ |
|------|-----|
| `Mutex<T>` | `rusty::Mutex<T>` |
| `RwLock<T>` | `rusty::RwLock<T>` |
| `Condvar` | `rusty::Condvar` |
| `Barrier` | `rusty::Barrier` |
| `Once` | `rusty::Once` |
| `thread::spawn` | `rusty::thread::spawn` |

### 1.13 Function Pointers

| Rust | C++ |
|------|-----|
| `fn(A) -> B` | `rusty::SafeFn<B(A)>` |
| `unsafe fn(A) -> B` | `rusty::UnsafeFn<B(A)>` |
| `Fn(A) -> B` | `std::function<B(A)>` |
| `FnMut(A) -> B` | `std::function<B(A)>` |
| `FnOnce(A) -> B` | `std::move_only_function<B(A)>` (C++23) |

---

## 2. Near-Direct Mappings (Minor Adjustments)

### 2.1 Closures / Lambdas

```rust
let add = |a: i32, b: i32| -> i32 { a + b };
let capture_ref = |x: &i32| *x + 1;    // borrows
let capture_move = move || println!("{}", name);  // moves name in
```

```cpp
auto add = [](int32_t a, int32_t b) -> int32_t { return a + b; };
auto capture_ref = [&x](const int32_t& x) { return x + 1; };  // captures by ref
auto capture_move = [name = std::move(name)]() { std::println("{}", name); };
```

**Mapping rules**:
- Default Rust closures (borrow environment) → `[&]` capture
- `move` closures → `[var = std::move(var), ...]` capture
- `Fn` trait bound → `const` lambda (or `std::function<Sig>`)
- `FnMut` trait bound → mutable lambda
- `FnOnce` trait bound → movable lambda (C++23 `std::move_only_function`)

### 2.2 Tuples

```rust
let pair: (i32, String) = (42, String::from("hello"));
let (a, b) = pair;  // destructuring
```

```cpp
auto pair = std::tuple<int32_t, std::string>(42, std::string("hello"));
auto [a, b] = std::move(pair);  // structured bindings (C++17)
```

### 2.3 Arrays and Slices

| Rust | C++ |
|------|-----|
| `[T; N]` (array) | `std::array<T, N>` |
| `&[T]` (slice) | `std::span<const T>` (C++20) |
| `&mut [T]` | `std::span<T>` |

### 2.4 Type Aliases

```rust
type Result<T> = std::result::Result<T, MyError>;
```

```cpp
template<typename T>
using Result = std::expected<T, MyError>;
```

### 2.5 Modules → C++20 Modules (Recommended) or Namespaces

#### The Header/Source Problem

Traditional C++ requires splitting code into headers (`.h` — declarations) and source files (`.cpp` — definitions). This creates complexity that doesn't exist in Rust:

- Every public type/function needs a declaration in a header and a definition in a source file
- Include guards (`#pragma once` / `#ifndef`) needed to prevent double inclusion
- Circular dependencies between headers require forward declarations
- Templates must be defined in headers (not source files)
- ODR (One Definition Rule) violations are easy to introduce
- Build times suffer from repeated header parsing

Transpiling Rust's single-file modules into header/source pairs would be a significant source of complexity.

#### Solution: C++20 Modules

C++20 modules bypass the header/source split entirely and map almost 1:1 to Rust's module system:

```rust
// src/graphics/mod.rs
pub mod shapes;           // public submodule
mod internal;             // private submodule

pub fn draw() { }
pub(crate) fn helper() { }
fn private_fn() { }
```

```cpp
// graphics.cppm (C++20 module interface unit)
export module graphics;
export import graphics.shapes;   // public submodule re-export
import graphics.internal;        // private submodule (not exported)

export void draw() { }           // pub → export
void helper() { }                // pub(crate) → module-visible, not exported
static void private_fn() { }     // private → static or in anonymous namespace
```

**Mapping table**:

| Rust | C++20 Modules |
|------|---------------|
| `mod foo;` | `import foo;` |
| `pub mod foo;` | `export import foo;` |
| `use crate::foo::Bar;` | `import foo;` (then use `foo::Bar`) |
| `pub fn` | `export void fn()` |
| `fn` (private) | `void fn()` (not exported) |
| `pub(crate) fn` | `void fn()` (module-visible, not exported) |
| `pub(super)` | No direct equivalent (not exported, parent imports) |
| `pub struct` | `export struct` |
| `pub use foo::Bar;` | `export using foo::Bar;` or `export import foo;` |

**Why C++20 modules are ideal for transpilation**:

1. **No header/source split** — one `.cppm` file per Rust module, definitions and declarations together
2. **`export` = `pub`** — direct visibility mapping
3. **No include guards** — modules are imported, not textually included
4. **No circular dependency issues** — module imports are not textual
5. **No ODR problems** — each entity has exactly one owning module
6. **Templates work** — template definitions live in the module interface, no header needed
7. **Faster builds** — modules are compiled once, not re-parsed per translation unit

**Crate → module mapping**:

```
my_crate/                    →  my_crate.cppm (primary module interface)
├── src/lib.rs               →  export module my_crate;
├── src/foo.rs               →  my_crate.foo.cppm
├── src/bar/mod.rs           →  my_crate.bar.cppm
└── src/bar/baz.rs           →  my_crate.bar.baz.cppm
```

**Compiler support (as of 2026)**: GCC 14+, Clang 17+, and MSVC 19.34+ all support C++20 modules. CMake 3.28+ has `import std` support. Module support is production-ready for new projects.

### 2.6 Impl Blocks

Rust splits methods across multiple `impl` blocks. In C++, all methods must be declared in the class body. The transpiler must **merge all `impl` blocks** for a type into a single class definition.

```rust
struct Foo { x: i32 }
impl Foo {
    fn new(x: i32) -> Self { Foo { x } }
}
impl Foo {  // second impl block
    fn get(&self) -> i32 { self.x }
}
```

```cpp
struct Foo {
    int32_t x;
    static Foo new_(int32_t x) { return Foo{x}; }
    int32_t get() const { return x; }
};
```

---

## 3. Non-Trivial Mappings (Require Design Decisions)

### 3.1 Enums with Data (Algebraic Data Types) ⚠️

Rust enums are tagged unions with pattern matching. They map to `std::variant` + `std::visit`.

```rust
enum Shape {
    Circle(f64),                    // radius
    Rectangle { w: f64, h: f64 },  // named fields
    None,                           // unit variant
}
```

```cpp
struct Circle { double radius; };
struct Rectangle { double w; double h; };
struct None_ {};

using Shape = std::variant<Circle, Rectangle, None_>;
```

Each variant becomes its own struct, and the enum becomes a `using` alias for `std::variant<...>`. This is type-safe, zero-overhead, and preserves value semantics. For recursive enums (like linked lists or ASTs), use `rusty::Box<T>` for the recursive case.

### 3.2 Traits → Microsoft Proxy ⚠️⚠️

Rust traits map to [Proxy](https://github.com/ngcpp/proxy) facades. Proxy provides non-invasive, value-semantic type erasure — the closest C++ equivalent to Rust's trait system. Types just need the right methods; no inheritance required.

| Rust trait usage | C++ (Proxy) mapping |
|------------------|---------------------|
| `trait Foo { fn bar(&self); }` | `PRO_DEF_MEM_DISPATCH` + `pro::facade_builder` |
| `dyn Trait` | `pro::proxy<Facade>` |
| `Box<dyn Trait>` | `pro::proxy<Facade>` (owns the value) |
| `&dyn Trait` | `pro::proxy_view<Facade>` (non-owning) |
| `impl Trait for Type` | Just add the methods to the struct |
| `T: Trait` (generic bound) | `pro::proxy<Facade>` or concept constraint |
| `T: A + B` (multiple bounds) | Combine conventions in one facade |
| Associated types (`type Item`) | Template type alias in facade |
| Supertraits (`trait B: A`) | Facade inheriting conventions from another facade |
| Operator traits (`Add`, `Index`) | C++ operator overloading (direct) |
| Marker traits (`Send`, `Sync`) | `static_assert` or concept constraints |

#### 3.2.1 Trait Definition and Dynamic Dispatch

```rust
trait Animal {
    fn speak(&self) -> String;
}

fn make_noise(animal: &dyn Animal) {
    println!("{}", animal.speak());
}
```

```cpp
#include <proxy/proxy.h>

// Trait definition → facade
PRO_DEF_MEM_DISPATCH(MemSpeak, speak);

struct AnimalFacade : pro::facade_builder
    ::add_convention<MemSpeak, std::string() const>
    ::build {};

// &dyn Animal → pro::proxy_view
void make_noise(pro::proxy_view<AnimalFacade> animal) {
    std::println("{}", animal.invoke<MemSpeak>());
}

// Any type with speak() satisfies the trait — no inheritance!
struct Dog {
    std::string speak() const { return "Woof"; }
};

void example() {
    Dog dog;
    make_noise(pro::make_proxy_view<AnimalFacade>(dog));  // &dyn Animal

    auto boxed = pro::make_proxy<AnimalFacade>(Dog{});    // Box<dyn Animal>
    make_noise(boxed);
}
```

**Why Proxy is the right choice**:
- **Non-invasive**: Types don't need to inherit anything — just have the right methods (exactly like Rust traits)
- **Value semantics**: `pro::proxy` owns the value, like `Box<dyn Trait>`
- **Small buffer optimization**: Avoids heap allocation for small types
- **No vtable inheritance**: Dispatch tables are per-facade, not per-type
- **C++20 compatible**: Works with standard compilers (GCC 14+, Clang 17+, MSVC 19.34+)

#### 3.2.2 Trait Implementation

```rust
impl Animal for Dog {
    fn speak(&self) -> String { "Woof".to_string() }
}
impl Animal for Cat {
    fn speak(&self) -> String { "Meow".to_string() }
}
```

```cpp
// Just define the methods — Proxy resolves them automatically
struct Dog {
    std::string speak() const { return "Woof"; }
};
struct Cat {
    std::string speak() const { return "Meow"; }
};
// Both Dog and Cat automatically satisfy AnimalFacade
```

#### 3.2.3 Multiple Trait Bounds

```rust
fn process(item: &(dyn Display + Debug)) { ... }
```

```cpp
PRO_DEF_MEM_DISPATCH(MemDisplay, display);
PRO_DEF_MEM_DISPATCH(MemDebug, debug);

struct DisplayDebugFacade : pro::facade_builder
    ::add_convention<MemDisplay, std::string() const>
    ::add_convention<MemDebug, std::string() const>
    ::build {};

void process(pro::proxy_view<DisplayDebugFacade> item) { ... }
```

#### 3.2.4 Default Trait Methods

```rust
trait Greet {
    fn name(&self) -> String;
    fn greet(&self) -> String {
        format!("Hello, {}!", self.name())
    }
}
```

```cpp
PRO_DEF_MEM_DISPATCH(MemName, name);

struct GreetFacade : pro::facade_builder
    ::add_convention<MemName, std::string() const>
    ::build {};

// Default method as free function
std::string greet(pro::proxy_view<GreetFacade> self) {
    return std::format("Hello, {}!", self.invoke<MemName>());
}
```

#### 3.2.5 Operator Traits

Rust's operator traits (`Add`, `Sub`, `Index`, `Deref`, etc.) map directly to C++ operator overloading — no Proxy needed:

```rust
impl Add for Point {
    type Output = Point;
    fn add(self, other: Point) -> Point {
        Point { x: self.x + other.x, y: self.y + other.y }
    }
}
```

```cpp
Point operator+(Point lhs, const Point& rhs) {
    return Point{ lhs.x + rhs.x, lhs.y + rhs.y };
}
```

### 3.3 Pattern Matching ⚠️

```rust
match shape {
    Shape::Circle(r) => println!("Circle with radius {}", r),
    Shape::Rectangle { w, h } => println!("Rect {}x{}", w, h),
    Shape::None => println!("Nothing"),
}
```

#### Using `std::visit`:

```cpp
std::visit(overloaded{
    [](const Circle& c) { std::println("Circle with radius {}", c.radius); },
    [](const Rectangle& r) { std::println("Rect {}x{}", r.w, r.h); },
    [](const None_&) { std::println("Nothing"); },
}, shape);
```

Where `overloaded` is the standard helper:
```cpp
template<class... Ts> struct overloaded : Ts... { using Ts::operator()...; };
```

#### Pattern matching on other types:

| Rust pattern | C++ equivalent |
|-------------|----------------|
| `match x { 1 => ..., 2 => ... }` | `switch (x) { case 1: ...; case 2: ...; }` |
| `if let Some(v) = opt` | `if (opt.has_value()) { auto v = *opt; ... }` |
| `let (a, b) = tuple` | `auto [a, b] = tuple;` |
| `let Point { x, y } = p` | `auto [x, y] = p;` (needs structured bindings) |
| Guard: `x if x > 0` | if-else chain |

**Note**: C++26 proposes `inspect` for proper pattern matching (P2688). If targeting future standards, this becomes much cleaner.

### 3.4 The `?` Operator ⚠️

```rust
fn read_file(path: &str) -> Result<String, io::Error> {
    let content = std::fs::read_to_string(path)?;
    Ok(content.to_uppercase())
}
```

No direct C++ equivalent. Options:

#### Option A: Macro-based (Recommended)

```cpp
#define TRY(expr) \
    ({ auto _r = (expr); \
       if (!_r.has_value()) return std::unexpected(_r.error()); \
       std::move(_r.value()); })

// Usage:
std::expected<std::string, std::io::Error> read_file(std::string_view path) {
    auto content = TRY(fs::read_to_string(path));
    return to_uppercase(content);
}
```

Note: This uses GCC/Clang statement expressions. For portable code, use a different pattern.

#### Option B: Monadic chaining (C++23)

```cpp
std::expected<std::string, Error> read_file(std::string_view path) {
    return fs::read_to_string(path)
        .transform([](auto& s) { return to_uppercase(s); });
}
```

#### Option C: Exceptions (if panic strategy = exceptions)

Map `Result` to exceptions: `Err(e)` throws, `Ok(v)` returns `v`. The `?` operator is implicit. This is the simplest transpilation but changes error handling semantics.

### 3.5 `break` with Value from `loop`

```rust
let result = loop {
    if condition {
        break 42;
    }
};
```

```cpp
auto result = [&]() -> int32_t {
    while (true) {
        if (condition) {
            return 42;
        }
    }
}();
```

Wrap the loop in an immediately-invoked lambda that uses `return` instead of `break value`.

### 3.6 Lifetimes

Rust lifetimes have **no runtime representation** — they are purely compile-time constraints. In the C++ output, lifetimes are simply erased. The safety guarantees were already enforced by the Rust compiler.

```rust
fn longest<'a>(x: &'a str, y: &'a str) -> &'a str {
    if x.len() > y.len() { x } else { y }
}
```

```cpp
// Lifetimes erased — the Rust compiler already verified correctness
std::string_view longest(std::string_view x, std::string_view y) {
    return x.size() > y.size() ? x : y;
}
```

If the transpiled C++ is then fed back into rusty-cpp for analysis, lifetime annotations can be emitted as comments:
```cpp
// @lifetime: (&'a, &'a) -> &'a
std::string_view longest(std::string_view x, std::string_view y);
```

### 3.7 Unsafe Code → rusty-cpp @unsafe Annotations

Rust's `unsafe` marks code regions where the programmer takes responsibility for safety invariants. In the transpiled C++, we preserve these boundaries using rusty-cpp's `@unsafe` annotation system, closing the loop for analyzer verification.

#### Unsafe Blocks

```rust
fn safe_wrapper() {
    let x = 42;
    unsafe {
        let ptr = &x as *const i32;
        let val = *ptr;
    }
}
```

```cpp
void safe_wrapper() {
    const auto x = 42;
    // @unsafe
    {
        const auto ptr = static_cast<const int32_t*>(&x);
        const auto val = *ptr;
    }
}
```

The `unsafe { }` block becomes a `// @unsafe` annotated block. The rusty-cpp analyzer will skip safety checks inside `@unsafe` blocks, matching Rust's semantics.

#### Unsafe Functions

```rust
unsafe fn dangerous(ptr: *mut i32) {
    *ptr = 42;
}
```

```cpp
// @unsafe
void dangerous(int32_t* ptr) {
    *ptr = 42;
}
```

`unsafe fn` becomes a `// @unsafe` annotated function. In rusty-cpp's two-state model, calling this function from `@safe` code requires an `@unsafe { }` block.

#### Raw Pointers

Raw pointer operations pass through naturally — C++ pointers are inherently unsafe:

| Rust | C++ |
|------|-----|
| `*const T` | `const T*` |
| `*mut T` | `T*` |
| `ptr as *const T` | `static_cast<const T*>(ptr)` |
| `*ptr` (deref) | `*ptr` |
| `&x as *const T` | `static_cast<const T*>(&x)` |

#### Design Decision

The transpiler emits `// @unsafe` (not just `// unsafe`) so that the rusty-cpp analyzer can enforce safety boundaries on the transpiled output. This means:

1. Transpiled safe code is checked by the analyzer (borrow rules, pointer safety)
2. Transpiled unsafe blocks are skipped by the analyzer (programmer responsibility)
3. The safety boundary is preserved across the transpilation — Rust's `unsafe` maps exactly to rusty-cpp's `@unsafe`

This is consistent with the forward correctness guarantee: if Rust's borrow checker approved the safe code, the transpiled C++ should also pass the rusty-cpp analyzer's checks.

### 3.8 Async/Await → Pollable State Machine on C++20 Coroutines

Rust's async model is a lazy, poll-based state machine. C++20 coroutines provide the state machine generation, but default to eager execution. The transpiler builds Rust's poll model on top of C++20 coroutines by customizing the `promise_type`.

#### Core Types

```cpp
#include <coroutine>
#include <functional>

// Poll<T> — Rust's Poll enum
template<typename T>
struct Poll {
    rusty::Option<T> value;  // None = Pending, Some = Ready

    static Poll ready(T v) { return Poll{rusty::Option<T>::some(std::move(v))}; }
    static Poll pending()  { return Poll{rusty::Option<T>::none()}; }
    bool is_ready() const  { return value.is_some(); }
};

// Waker — notification callback for IO readiness
struct Waker {
    std::function<void()> wake_fn;
    void wake() { if (wake_fn) wake_fn(); }
};

struct Context {
    Waker* waker;
};
```

#### Task<T> — The Lazy Coroutine Future

```cpp
template<typename T>
class Task {
public:
    struct promise_type {
        rusty::Option<T> result;
        Context* current_ctx = nullptr;

        Task get_return_object() {
            return Task{std::coroutine_handle<promise_type>::from_promise(*this)};
        }

        // KEY: suspend_always makes it LAZY — nothing runs until poll()
        std::suspend_always initial_suspend() { return {}; }
        std::suspend_always final_suspend() noexcept { return {}; }

        void return_value(T value) {
            result = rusty::Option<T>::some(std::move(value));
        }
        void unhandled_exception() { std::terminate(); }
    };

    // poll() — drives the state machine one step (like Rust's Future::poll)
    Poll<T> poll(Context& cx) {
        if (handle_.done()) {
            return Poll<T>::ready(std::move(*handle_.promise().result));
        }
        handle_.promise().current_ctx = &cx;
        handle_.resume();  // runs until next co_await or co_return
        if (handle_.done()) {
            return Poll<T>::ready(std::move(*handle_.promise().result));
        }
        return Poll<T>::pending();
    }

    ~Task() { if (handle_) handle_.destroy(); }
    Task(Task&& o) : handle_(std::exchange(o.handle_, nullptr)) {}

private:
    Task(std::coroutine_handle<promise_type> h) : handle_(h) {}
    std::coroutine_handle<promise_type> handle_;
};
```

#### Executor — The Event Loop (like tokio)

```cpp
class Executor {
    std::vector<std::function<Poll<void>(Context&)>> tasks;
    std::queue<size_t> ready_queue;

public:
    void spawn(Task<void> task) {
        tasks.push_back([t = std::move(task)](Context& cx) mutable {
            return t.poll(cx);
        });
        ready_queue.push(tasks.size() - 1);
    }

    void run() {
        while (!ready_queue.empty()) {
            auto idx = ready_queue.front();
            ready_queue.pop();

            Waker waker{[this, idx]() { ready_queue.push(idx); }};
            Context cx{&waker};

            auto result = tasks[idx](cx);
            // Pending → waker will re-enqueue when IO fires
            // Ready → task is done
        }
    }
};
```

#### Transpilation Example

```rust
async fn fetch(url: &str) -> Result<String, Error> {
    let response = client.get(url).send().await?;
    let body = response.text().await?;
    Ok(body)
}
```

```cpp
Task<rusty::Result<rusty::String, Error>> fetch(std::string_view url) {
    auto response = co_await client.get(url).send();
    if (response.is_err()) co_return rusty::Result<rusty::String, Error>::err(response.unwrap_err());
    auto body = co_await response.unwrap().text();
    if (body.is_err()) co_return rusty::Result<rusty::String, Error>::err(body.unwrap_err());
    co_return rusty::Result<rusty::String, Error>::ok(body.unwrap());
}
```

#### How It Works

```
┌──────────────────────────────────────────────────┐
│  Executor                                        │
│                                                  │
│  loop:                                           │
│    pick task from ready_queue                    │
│    call task.poll(context)                       │
│      │                                           │
│      ├─ Ready(T) → task done                     │
│      │                                           │
│      └─ Pending → waker will re-enqueue          │
│           │        when IO/timer fires           │
│           ▼                                      │
│    ┌─────────────────┐                           │
│    │ C++20 coroutine │ (compiler-generated        │
│    │                 │  state machine)            │
│    │ co_await inner  │──► inner.poll(cx)          │
│    │   Pending?      │   suspend, return Pending  │
│    │   Ready?        │   continue to next state   │
│    │                 │                           │
│    │ co_return val   │──► return Ready(val)        │
│    └─────────────────┘                           │
└──────────────────────────────────────────────────┘
```

**Key design decisions**:
- **`initial_suspend()` → `suspend_always`** — makes coroutines lazy, matching Rust semantics
- **`poll()` wraps `handle_.resume()`** — one step of the state machine per call
- **`Waker`** — callback mechanism so IO subsystems can notify the executor
- **C++20 generates the state machine** — `co_await`/`co_return` map directly to Rust's `.await`
- **Executor is a library, not language** — same as Rust (tokio is a library too)

### 3.8 Derive Macros

```rust
#[derive(Debug, Clone, PartialEq, Hash)]
struct Point { x: f64, y: f64 }
```

| Derive | C++ equivalent |
|--------|---------------|
| `Debug` | `operator<<` or `std::format` specialization |
| `Clone` | Copy constructor (+ explicit `.clone()` method) |
| `Copy` | Trivially copyable (default for POD types) |
| `PartialEq` / `Eq` | `operator==` (C++20: `= default`) |
| `PartialOrd` / `Ord` | `operator<=>` (C++20: `= default`) |
| `Hash` | `std::hash<T>` specialization |
| `Default` | Default constructor |
| `Serialize` / `Deserialize` | External lib (nlohmann/json, etc.) |

```cpp
struct Point {
    double x;
    double y;

    auto operator<=>(const Point&) const = default;  // gives ==, <, >, etc.
    // Debug: implement format or operator<<
    friend std::ostream& operator<<(std::ostream& os, const Point& p) {
        return os << "Point { x: " << p.x << ", y: " << p.y << " }";
    }
};

template<>
struct std::hash<Point> {
    size_t operator()(const Point& p) const {
        return std::hash<double>{}(p.x) ^ (std::hash<double>{}(p.y) << 1);
    }
};
```

### 3.9 Procedural / Declarative Macros

Rust macros operate on token trees and are Turing-complete. There is no general C++ equivalent.

| Macro type | Strategy |
|-----------|----------|
| Simple `macro_rules!` (text substitution) | C preprocessor macros |
| Complex `macro_rules!` (pattern matching) | Expand at transpile time |
| Procedural macros (derive, attribute) | Generate code at transpile time |
| `println!`, `format!` | `std::println`, `std::format` (C++23) |
| `vec![1, 2, 3]` | `std::vector<int>{1, 2, 3}` (initializer list) |

**Recommendation**: Expand all macros before transpilation (using `rustc`'s macro expansion output or `cargo expand`), then transpile the expanded code.

### 3.10 Generics / Templates

```rust
fn max<T: Ord>(a: T, b: T) -> T {
    if a > b { a } else { b }
}
```

```cpp
template<std::totally_ordered T>
T max(T a, T b) {
    return a > b ? std::move(a) : std::move(b);
}
```

| Rust | C++ |
|------|-----|
| `<T>` | `template<typename T>` |
| `T: Bound` | `Concept T` or `requires` clause |
| `T: A + B` | `requires (A<T> && B<T>)` |
| `where T: Bound` | `requires` clause |
| `impl<T> Struct<T>` | Template class method definitions |
| `T: 'static` | No equivalent (lifetime erased) |
| Monomorphization | Same — C++ templates are monomorphized |

---

## 4. Semantic Gaps and Challenges

### 4.1 Exhaustiveness Checking

Rust's `match` is exhaustive — the compiler ensures all variants are handled. `std::visit` on `std::variant` provides this at compile time. `switch` on integers does not. The transpiler should prefer `std::visit` for enum matches.

### 4.2 Move Semantics Differences

| Aspect | Rust | C++ |
|--------|------|-----|
| Default | Move | Copy |
| After move | Inaccessible (compile error) | Valid-but-unspecified |
| Implicit move | Yes (last use) | No (need `std::move`) |
| Destructive move | Yes | No (destructor still runs) |

The transpiler must:
1. Insert `std::move()` at every Rust move point
2. Trust that Rust's borrow checker has verified no use-after-move
3. Optionally use `[[clang::trivial_abi]]` for destructive move optimization

### 4.3 Visibility / Access Control

| Rust | C++ |
|------|-----|
| Private (default) | Private (default in class), Public (default in struct) |
| `pub` | `public:` |
| `pub(crate)` | No equivalent (internal linkage? `friend`? anonymous namespace?) |
| `pub(super)` | No equivalent |

**Strategy**: Use `public`/`private` in structs/classes. For module-level visibility, rely on separate compilation units and header organization. `pub(crate)` can be approximated with comments or `[[deprecated("internal")]]`.

### 4.4 Orphan Rule / Coherence

Rust prevents implementing external traits for external types (orphan rule). C++ has no such restriction — you can specialize templates and overload operators for any type. The transpiler doesn't need to enforce this; it's a Rust-side concern.

### 4.5 No Null

Rust has no null — `Option<T>` is used instead. The transpiler maps all `Option` usage to `rusty::Option<T>`, which preserves Rust's semantics (no implicit null, explicit `Some`/`None`, `.unwrap()`, `.map()`, etc.).

### 4.6 Iterators

Rust iterators are lazy, composable, and zero-cost. C++ ranges (C++20) provide similar functionality.

```rust
let sum: i32 = vec.iter()
    .filter(|x| **x > 0)
    .map(|x| x * 2)
    .sum();
```

```cpp
auto sum = vec
    | std::views::filter([](int x) { return x > 0; })
    | std::views::transform([](int x) { return x * 2; })
    | std::ranges::fold_left(0, std::plus{});  // C++23
```

### 4.7 Trait Objects with Multiple Traits

```rust
fn process(item: &(dyn Display + Debug)) { ... }
```

Proxy handles this naturally by combining conventions in a single facade (see §3.2.3):

```cpp
struct DisplayDebugFacade : pro::facade_builder
    ::add_convention<MemDisplay, std::string() const>
    ::add_convention<MemDebug, std::string() const>
    ::build {};
```

### 4.8 `impl Trait` in Return Position (Existential Types)

```rust
fn make_iter() -> impl Iterator<Item = i32> {
    (0..10).filter(|x| x % 2 == 0)
}
```

Both `impl Trait` and `dyn Trait` returns map uniformly to `pro::proxy<Facade>`. This trades static dispatch for a simpler, uniform transpilation rule — one mapping for all trait-typed returns.

```cpp
PRO_DEF_MEM_DISPATCH(MemNext, next);

struct IteratorFacade : pro::facade_builder
    ::add_convention<MemNext, rusty::Option<int32_t>()>
    ::build {};

pro::proxy<IteratorFacade> make_iter() {
    return pro::make_proxy<IteratorFacade>(/* ... */);
}
```

| Rust | C++ |
|------|-----|
| `-> impl Trait` | `-> pro::proxy<Facade>` |
| `-> Box<dyn Trait>` | `-> pro::proxy<Facade>` |
| `-> &dyn Trait` | `-> pro::proxy_view<Facade>` |

---

## 5. Complete Feature Matrix

| Rust Feature | C++ Mapping (rusty-cpp preferred) | Difficulty | Notes |
|-------------|-----------------------------------|------------|-------|
| Primitive types | Fixed-width integers | Easy | Direct mapping |
| `let` / `let mut` | `const auto` / `auto` | Easy | Flip default mutability |
| Functions | Functions | Easy | Add explicit `return` |
| Structs | Structs/classes | Easy | Merge impl blocks |
| Enums (C-like) | `enum class` | Easy | Direct |
| Enums (with data) | `std::variant` | Medium | See §3.1 |
| Traits | Microsoft Proxy facades | Medium | See §3.2 |
| Pattern matching | `std::visit` / switch | Medium | See §3.3 |
| `?` operator | Macro / monadic | Medium | See §3.4 |
| Closures | Lambdas | Easy | Capture mode mapping |
| Generics | Templates + concepts | Medium | Bounds → concepts |
| Lifetimes | Erased | Easy | No runtime effect |
| Ownership/moves | `rusty::move` / `std::move` | Medium | Insert at move points |
| `Box<T>` | `rusty::Box<T>` | Easy | Direct API match |
| `Rc<T>` / `Arc<T>` | `rusty::Rc<T>` / `rusty::Arc<T>` | Easy | Direct API match |
| `Vec<T>` | `rusty::Vec<T>` | Easy | Direct API match |
| `HashMap` / `HashSet` | `rusty::HashMap` / `rusty::HashSet` | Easy | Direct API match |
| `Option<T>` | `rusty::Option<T>` | Easy | Direct API match |
| `Result<T,E>` | `rusty::Result<T,E>` | Easy | Direct API match |
| `String` / `&str` | `rusty::String` / `std::string_view` | Easy | Direct API match |
| `Mutex<T>` / `RwLock<T>` | `rusty::Mutex<T>` / `rusty::RwLock<T>` | Easy | Data-protecting model |
| `Cell<T>` / `RefCell<T>` | `rusty::Cell<T>` / `rusty::RefCell<T>` | Easy | Runtime borrow checks |
| `fn()` / `unsafe fn()` | `rusty::SafeFn` / `rusty::UnsafeFn` | Easy | Safety-typed wrappers |
| `async`/`await` | Coroutines | Hard | No standard executor |
| Macros | Expand before transpile | Medium | Use `cargo expand` |
| Modules | C++20 modules (`.cppm`) | Easy | `pub` → `export`, see §2.5 |
| Derive macros | Code generation | Medium | Per-derive mapping |
| Unsafe blocks | Raw code | Easy | Just emit the code |
| FFI (`extern "C"`) | `extern "C"` | Easy | Direct mapping |

---

## 6. Proposed Architecture

```
                    ┌─────────────────┐
                    │   Rust Source    │
                    │   (.rs files)   │
                    └────────┬────────┘
                             │
                    ┌────────▼────────┐
                    │  cargo expand   │
                    │ (macro expand)  │
                    └────────┬────────┘
                             │
                    ┌────────▼────────┐
                    │   syn / rustc   │
                    │  (parse AST)    │
                    └────────┬────────┘
                             │
              ┌──────────────┼──────────────┐
              │              │              │
     ┌────────▼───────┐ ┌───▼────┐ ┌───────▼──────┐
     │ Type Resolution│ │ Trait  │ │  Lifetime    │
     │ & Inference    │ │ Mapper │ │  Erasure     │
     └────────┬───────┘ └───┬────┘ └───────┬──────┘
              │              │              │
              └──────────────┼──────────────┘
                             │
                    ┌────────▼────────┐
                    │  C++ Code Gen   │
                    │  (emit .hpp/.cpp│
                    └────────┬────────┘
                             │
                    ┌────────▼────────┐
                    │  C++20 Output   │
                    │  (.hpp/.cpp)    │
                    └─────────────────┘
```

### Key Components:

1. **Macro Expander**: Use `cargo expand` to flatten all macros before processing
2. **AST Parser**: Use `syn` crate to parse Rust into a typed AST
3. **Type Resolution**: Resolve all types, infer where needed, map Rust types → C++ types
4. **Trait Mapper**: Convert trait definitions to Proxy facades (`PRO_DEF_MEM_DISPATCH` + `pro::facade_builder`)
5. **Lifetime Eraser**: Strip all lifetime annotations (they have no runtime effect)
6. **Code Generator**: Emit idiomatic C++20 code

---

## 7. Existing Work and Related Projects

| Project | Approach | Status |
|---------|----------|--------|
| **C2Rust** | C → Rust transpiler (inverse direction) | Mature, Mozilla-backed |
| **Crubit** | Google's C++/Rust interop tool | Active, focused on FFI bindings |
| **cxx** | Rust/C++ safe interop bridge | Mature, bidirectional FFI |
| **autocxx** | Automated C++ binding generation | Active |
| **cbindgen** | Rust → C/C++ header generation | Mature, for FFI headers only |

No production-quality **Rust→C++** transpiler exists today. The closest conceptual work is **C2Rust** (which goes the other direction) and academic papers on transpilation between systems languages.

---

## 8. Recommended Strategy

### Phase 1: Core Language (MVP)
- Primitive types, functions, structs, basic enums
- `let`/`let mut` → `const auto`/`auto`
- References → `const T&` / `T&`
- `Vec`, `String`, `HashMap` → STL equivalents
- Simple `match` → `switch` or `std::visit`
- Lifetime erasure

### Phase 2: Traits and Generics
- Trait definitions → C++20 concepts
- All trait usages → Microsoft Proxy facades
- Generic functions → constrained templates
- Derive macros → generated operator overloads

### Phase 3: Advanced Features
- Async/await → C++20 coroutines
- Complex pattern matching → `std::visit` with guards
- Macro expansion via `cargo expand`
- Module system → C++20 modules

### Phase 4: Ecosystem Integration
- Standard library mapping (full `std::` equivalents)
- Build system integration (Cargo.toml → CMakeLists.txt)
- Test transpilation (`#[test]` → Google Test or Catch2)
- Documentation comments (`///` → Doxygen `///`)

---

## 9. Conclusion

Rust-to-C++ transpilation is **feasible** for the vast majority of Rust code. The language constructs map well because both languages share the same computational model (value semantics, deterministic destruction, zero-cost abstractions, monomorphized generics).

The **three hardest problems** are:
1. **Traits → C++**: Mapped uniformly to Microsoft Proxy facades (non-invasive, value-semantic)
2. **Enums with data → `std::variant`**: Works but pattern matching is verbose
3. **The `?` operator**: Requires a macro or monadic chaining

The **easiest wins** are:
- All primitive types, functions, structs, and control flow map directly
- Lifetimes simply disappear (they have no runtime semantics)
- Move semantics map to `std::move` (with the borrow checker guaranteeing safety on the Rust side)
- Smart pointers and collections map directly to rusty-cpp counterparts (`Box`→`rusty::Box`, `Vec`→`rusty::Vec`, etc.)
- Modules map to C++20 modules (`pub` → `export`, `mod` → `import`)

This approach effectively lets Rust serve as a **safe DSL for C++** — write in Rust with full safety guarantees, transpile to C++ for deployment in C++ codebases. The generated C++ can then be analyzed by rusty-cpp to verify that the safety properties are maintained.

---

## 10. Whole-Crate Transpilation: Using Rust Crates in C++

### 10.1 The Goal

A C++ project should be able to use a Rust crate as easily as any other C++ dependency:

```cmake
# CMakeLists.txt
find_package(my_rust_crate REQUIRED)
target_link_libraries(my_app PRIVATE my_rust_crate)
```

```cpp
// main.cpp
import my_rust_crate;
import my_rust_crate.utils;

int main() {
    auto result = my_rust_crate::process(42);
}
```

### 10.2 Approach: Full Transpilation (Rust Source → C++ Source)

Convert the entire Rust crate into C++ source files that compile natively with a C++ compiler.

```
my_rust_crate/                     my_rust_crate_cpp/
├── Cargo.toml                     ├── CMakeLists.txt
├── src/                    →      ├── my_rust_crate.cppm
│   ├── lib.rs                     ├── my_rust_crate.utils.cppm
│   ├── utils.rs                   ├── my_rust_crate.types.cppm
│   └── types.rs                   └── my_rust_crate.internal.cppm
```

**Workflow:**
```bash
# One command transpiles the entire crate
rusty-cpp-transpiler --crate Cargo.toml --output-dir build/

# This produces:
#   build/my_crate.cppm              (from src/lib.rs)
#   build/my_crate.utils.cppm        (from src/utils.rs)
#   build/my_crate.types.cppm        (from src/types.rs)
#   build/CMakeLists.txt             (generated build system)
```

**Pros:**
- No Rust toolchain needed at build time — pure C++ output
- Full integration with C++ build systems (CMake, Bazel, etc.)
- C++ IDE support (autocomplete, debugging, refactoring)
- Can be checked by rusty-cpp analyzer after transpilation
- Zero runtime FFI overhead — everything is native C++

**Cons:**
- Not all Rust code can be transpiled (unsafe blocks, proc macros, complex trait impls)
- External crate dependencies require recursive transpilation or manual bindings
- Generated C++ may be less idiomatic than hand-written C++
- Transpilation must be re-run when Rust source changes

**Current status:** Single-file transpilation works (243 tests). Missing: crate-level orchestration.

### 10.3 Implementation Plan for Whole-Crate Transpilation

#### Step 1: `--crate` Mode (Orchestration Layer)

Add a `--crate <Cargo.toml>` flag that transpiles an entire Rust crate in one command.

**1a: Crate Discovery**
```
Input:  Cargo.toml path
Output: List of (rs_path, module_name, cppm_path) tuples
```
- Parse Cargo.toml for crate name and targets
- Walk `src/` to find all `.rs` files
- Use existing `cmake::map_rs_to_cppm()` for file→module mapping
- Build module dependency graph from `mod` and `use` statements

**1b: Per-File Transpilation**
```
For each .rs file in topological order:
  1. Read source (or cargo expand)
  2. Call transpile(source, module_name)
  3. Write .cppm to output directory
```
- Reuse existing `transpile()` function — no changes needed
- Each file gets its own `CodeGen` instance with correct module name
- Output directory mirrors the flat module naming: `crate.module.submodule.cppm`

**1c: Build System Generation**
```
Output: CMakeLists.txt in output directory
```
- Reuse existing `cmake::generate_cmake()` — already handles multi-file mapping
- Add `find_package(rusty-cpp)` for rusty:: headers
- Add C++20 module support flags

**1d: Verification (Optional)**
```
If --verify: run rusty-cpp-checker on each .cppm file
```
- Reuse existing `--verify` infrastructure

**Estimated effort:** ~200 LOC in `main.rs` (new `transpile_crate()` function).

#### Step 2: External Crate Handling

When the crate depends on external crates (`[dependencies]` in Cargo.toml):

| Dependency Type | Strategy |
|----------------|----------|
| Rust std lib (`std::`, `core::`) | Mapped to `rusty::` types (already done) |
| Crates with `rusty::` equivalents | Map types via extended `types.rs` |
| Crates that can be transpiled | Recursively transpile |
| `serde`, `tokio`, etc. (complex) | Require manual type mapping files |

For MVP, external crates should emit a `// TODO: external crate` comment and continue. Users can provide manual type mappings for specific crates via a configuration file.

#### Step 3: Recursive Dependency Transpilation

For crates that depend on other transpilable crates:

1. Parse `[dependencies]` from Cargo.toml
2. Check if each dependency has a local path (workspace member or path dependency)
3. Recursively transpile dependencies first
4. Generate CMake `add_subdirectory()` or `FetchContent` for each dependency

### 10.4 End-to-End Example

**Rust crate** (`my_math/`):
```rust
// src/lib.rs
pub mod vector;

pub fn add(a: i32, b: i32) -> i32 { a + b }

// src/vector.rs
pub struct Vec2 { pub x: f64, pub y: f64 }

impl Vec2 {
    pub fn new(x: f64, y: f64) -> Self { Vec2 { x, y } }
    pub fn length(&self) -> f64 { (self.x * self.x + self.y * self.y).sqrt() }
}

impl std::ops::Add for Vec2 {
    type Output = Vec2;
    fn add(self, other: Vec2) -> Vec2 {
        Vec2 { x: self.x + other.x, y: self.y + other.y }
    }
}
```

**Transpile:**
```bash
rusty-cpp-transpiler --crate my_math/Cargo.toml --output-dir build/
```

**Generated C++ output:**

`build/my_math.cppm`:
```cpp
export module my_math;

export import my_math.vector;

export int32_t add(int32_t a, int32_t b) {
    return a + b;
}
```

`build/my_math.vector.cppm`:
```cpp
export module my_math.vector;

export struct Vec2 {
    double x;
    double y;

    static Vec2 new_(double x, double y) {
        return Vec2{.x = x, .y = y};
    }
    double length() const {
        return std::sqrt(x * x + y * y);
    }
    Vec2 operator+(Vec2 other) {
        return Vec2{.x = x + other.x, .y = y + other.y};
    }
};
```

`build/CMakeLists.txt`:
```cmake
cmake_minimum_required(VERSION 3.28)
project(my_math VERSION 0.1.0 LANGUAGES CXX)
set(CMAKE_CXX_STANDARD 20)

add_library(my_math
    my_math.cppm
    my_math.vector.cppm
)
target_sources(my_math PUBLIC FILE_SET CXX_MODULES FILES
    my_math.cppm
    my_math.vector.cppm
)
```

**Use from C++:**
```cpp
import my_math;
import my_math.vector;

int main() {
    auto v1 = Vec2::new_(1.0, 2.0);
    auto v2 = Vec2::new_(3.0, 4.0);
    auto v3 = v1 + v2;
    auto len = v3.length();
    auto sum = my_math::add(1, 2);
}
```

### 10.5 Current State and Gaps

| Component | Status | Notes |
|-----------|--------|-------|
| Single-file transpilation | Done ✅ | 243 tests, all language features |
| Type mapping (rusty::) | Done ✅ | All std lib types covered |
| C++20 module declarations | Done ✅ | export/import/pub handling |
| File-to-module mapping | Done ✅ | `cmake::map_rs_to_cppm()` |
| CMakeLists.txt generation | Done ✅ | Binary and library targets |
| `cargo expand` integration | Done ✅ | `--expand` flag |
| Analyzer verification | Done ✅ | `--verify` flag |
| **`--crate` mode** | **Not done** | Orchestration layer (~200 LOC) |
| **External crate handling** | **Not done** | Dependency resolution |
| **Recursive transpilation** | **Not done** | For dependency crates |

### 10.6 Priority Order

1. **`--crate` mode** — highest impact, ~200 LOC, enables whole-crate transpilation
2. **External crate detection** — graceful handling when dependencies can't be mapped
3. **Recursive dependency transpilation** — full dependency graph resolution

---

## 10.7 Real-World Transpilation Gaps (from `either` crate testing)

Testing the transpiler against real crates reveals systematic gaps. These are categorized by root cause and proposed fix.

### Gap 1: Generic Enums/Structs Lose Type Parameters — FIXED ✅

**Problem:** `enum Either<L, R> { Left(L), Right(R) }` transpiled to variant structs using bare `L` and `R` as types, without template declarations.

**Fix:** `emit_enum` now extracts type parameters from `ItemEnum.generics`, emits `template<typename ...>` prefix on each variant struct, and appends template args to the variant alias. Recursive generic enums get a template forward declaration.

**Output after fix:**
```cpp
template<typename L, typename R>
struct Either_Left { L _0; };
template<typename L, typename R>
struct Either_Right { R _0; };
template<typename L, typename R>
using Either = std::variant<Either_Left<L, R>, Either_Right<L, R>>;
```

**Fix:** In `emit_enum`, propagate the enum's generic parameters to each variant struct and to the variant alias. Reuse the existing `emit_template_prefix` logic.

**Estimated effort:** ~50 LOC in `codegen.rs::emit_enum`.

### Gap 2: `core::` Path Not Mapped

**Problem:** `use core::convert::AsRef` emits `using core::convert::AsRef` but `core::` is not a valid C++ namespace. In Rust, `core` is the no-std version of `std`.

**Fix:** Map `core::` to the same handling as `std::` in `emit_use_tree`. Both should pass through as `std::` or be recognized as internal Rust paths that don't need mapping.

**Estimated effort:** ~5 LOC in `emit_use_tree`.

### Gap 3: Group Use Imports Emit Invalid C++

**Problem:** `use std::io::{Read, Write, Seek}` emits `using std::io::{Read, Write, Seek}` but C++ doesn't support brace group imports.

**Current output (wrong):**
```cpp
using std::io::{Read, Write, Seek};
```

**Expected output:**
```cpp
using std::io::Read;
using std::io::Write;
using std::io::Seek;
```

**Fix:** In `emit_use`, when the use tree contains a `UseTree::Group`, expand it into multiple separate `using` declarations.

**Estimated effort:** ~30 LOC in `emit_use`.

### Gap 4: Unhandled `syn::Item` Kinds

**Problem:** Several item kinds emit `// TODO: unhandled item kind`:
- `Item::ExternCrate` — `extern crate foo;`
- `Item::Macro` (top-level macro invocations like `macro_rules!`)
- `Item::Verbatim` (unparsed items)

**Fix:**
- `Item::ExternCrate` → skip or emit `import`
- `Item::Macro` (top-level) → expand or emit comment with macro name
- Handle `macro_rules!` definitions — either skip (they're compile-time only) or emit a comment

**Estimated effort:** ~20 LOC in `emit_item`.

### Gap 5: `Self` in Trait Method Signatures

**Problem:** In trait method signatures, `Self` appears as a return type or parameter type but there's no current struct context to resolve it.

**Current output:** `Either<Self, Self>` (wrong — `Self` is unresolved)

**Expected output:** In a trait context, `Self` should remain as a template parameter or be mapped to the proxy's value type.

**Fix:** In trait method signatures, leave `Self` as-is (it's the implementor's type — Proxy handles this). Or replace with `auto` for return types.

**Estimated effort:** ~10 LOC.

### Gap 6: Slice/Range Syntax Not Fully Handled

**Problem:** Rust slice syntax `&mockdata[..]`, `&buf[..len]` and range syntax `0..10` in non-for contexts don't fully transpile.

**Current output:** `mockdata[rusty::range(, )]` (empty args), `/* TODO: expr */`

**Fix:** Handle `Expr::Range` with missing start/end (open ranges), and `Expr::Index` with range arguments. Map `..` to appropriate C++ span/range operations.

**Estimated effort:** ~30 LOC in `emit_expr_to_string`.

### Gap 7: Array/Vec Literal Initialization

**Problem:** `[0x00; 256]` (repeat initializer) and `b"\xff"` (byte string literals) aren't handled.

**Fix:** `[val; N]` → `std::array<T, N>` filled with val. Byte string literals → `uint8_t[]` or `std::span<const uint8_t>`.

**Estimated effort:** ~20 LOC.

### Gap 8: Nested Function Definitions

**Problem:** Rust allows defining functions inside other functions. The transpiler emits them as nested C++ functions, which is invalid (C++ doesn't allow nested function definitions).

**Current output (wrong):**
```cpp
TEST_CASE("macros") {
    Either<uint32_t, uint32_t> a() { ... }  // nested fn — invalid C++
}
```

**Fix:** Either hoist nested functions to module scope (with a unique name), or convert them to lambdas.

**Estimated effort:** ~40 LOC.

### Priority Order for Fixes

| Priority | Gap | Impact | Effort |
|----------|-----|--------|--------|
| 1 | Gap 1: Generic enums | ~~Blocks most real crates~~ **FIXED** | ~50 LOC |
| 2 | Gap 3: Group use imports | Invalid C++ syntax | ~30 LOC |
| 3 | Gap 2: `core::` mapping | Missing path | ~5 LOC |
| 4 | Gap 4: Unhandled item kinds | Missing code | ~20 LOC |
| 5 | Gap 8: Nested functions | Invalid C++ | ~40 LOC |
| 6 | Gap 6: Slice/range syntax | Missing expressions | ~30 LOC |
| 7 | Gap 7: Array literals | Missing expressions | ~20 LOC |
| 8 | Gap 5: Self in traits | Cosmetic | ~10 LOC |

Total estimated: ~205 LOC to fix all gaps.

---

## 11. Wrong Approaches (Rejected)

This section documents approaches that were considered and rejected, to avoid revisiting them.

### 11.1 FFI Binding Instead of Transpilation

**Rejected approach:** Compile Rust as a native library (`.a`/`.so`) and generate C++ headers for the FFI boundary using tools like `cbindgen` or `cxx`.

**Why it was rejected:**
- **Violates the core principle.** Our guarantee is: if Rust compiles, the transpiled C++ compiles and behaves identically. FFI binding doesn't transpile — it wraps. The C++ code doesn't mirror the Rust logic; it calls into an opaque binary.
- **Limited type mapping.** FFI can only expose `extern "C"` compatible types. No generics, no traits, no `Option<T>`, no `Result<T,E>`, no closures. The rich Rust type system is lost at the FFI boundary.
- **Requires Rust toolchain at C++ build time.** The whole point of transpilation is that the output is self-contained C++ — no Rust compiler needed to build the C++ project.
- **No inlining across boundary.** The C++ compiler can't optimize across the FFI boundary. With transpilation, everything is native C++ and fully optimizable.
- **Debugging across FFI is painful.** Stack traces cross language boundaries, breakpoints need both debuggers, and variable inspection is limited.
- **Duplicates existing tools.** `cbindgen` and `cxx` already do this well. We don't need to reimplement them. Our value is in transpilation, not wrapping.

**When FFI is actually appropriate (outside this project):** When you have a large existing Rust library that you can't or won't transpile, and you only need a narrow API surface exposed to C++. Use `cxx` or `cbindgen` directly for that — don't use the rusty-cpp transpiler.

### 11.2 Using C++ Headers Instead of C++20 Modules

**Rejected approach:** Transpile each Rust module into a `.hpp`/`.cpp` pair instead of a `.cppm` module interface unit.

**Why it was rejected:**
- Forces splitting declarations and definitions across two files per module
- Requires include guards, forward declarations, and careful include ordering
- Template definitions must go in headers (not source files)
- Circular dependencies require manual forward declarations
- Build times suffer from repeated header parsing
- C++20 modules solve all of these problems and map 1:1 to Rust modules

See §2.5 for the full rationale.

### 11.3 Multiple Trait Object Implementations (Virtual + CRTP + Type Erasure)

**Rejected approach:** Use a hybrid of virtual interfaces, CRTP, and manual type erasure to map Rust traits, choosing the approach based on usage analysis.

**Why it was rejected:**
- Complexity explosion: the transpiler must analyze whether each trait is used statically, dynamically, or both, and choose different implementations
- Three different trait representations means three different calling conventions
- Microsoft Proxy provides a single, uniform solution that handles all cases
- Proxy is non-invasive (like Rust traits), has value semantics, and supports SBO

We use Microsoft Proxy exclusively for all trait mappings. See §3.2.
